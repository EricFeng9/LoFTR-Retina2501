"""
域随机化增强模块 (Domain Randomization Enhancement)

目的: 打破生成数据中不同模态之间的纹理相关性
     迫使模型学习真正的跨模态不变性特征 (几何结构) 而非表面纹理

参考: "Synthetic data in generalizable, learning-based neuroimaging"
增强策略:
  1. Intensity Bias Field (空间渐变亮度不均, 模拟光照不均匀)
  2. Speckle Noise (斑点噪声, OCT/超声成像常见)
  3. Poisson Noise (泊松噪声, 低光条件)
  4. Random Downsampling (小概率随机降采样, 模拟低质量扫描)
  5. Gamma/Contrast/Brightness (传统颜色空间变换)
  6. Gaussian Blur (高斯模糊)
  7. Gaussian Noise (高斯噪声)

来源: train_multimodal_v3_3.py (lines 56-210)
"""

import torch
import torch.nn.functional as F
import numpy as np
import cv2
import random

def generate_intensity_bias_field_numpy(H, W, num_control_points=4, strength_range=(0.85, 1.15)):
    """
    Numpy version of bias field generation
    """
    # Create low-res random field
    low_res = np.random.uniform(strength_range[0], strength_range[1], (num_control_points, num_control_points))
    # Resize to high-res
    bias_field = cv2.resize(low_res, (W, H), interpolation=cv2.INTER_CUBIC)
    return bias_field

def apply_speckle_noise_numpy(img, intensity_range=(0.0, 0.15)):
    intensity = random.uniform(*intensity_range)
    if intensity > 0:
        noise = np.random.randn(*img.shape) * intensity
        img = img + img * noise
    return img

def apply_poisson_noise_numpy(img, scale_range=(50, 200)):
    scale = random.uniform(*scale_range)
    img_scaled = img * scale
    noisy = np.random.poisson(img_scaled.clip(0, None)).astype(np.float32)
    return noisy / scale

def apply_random_downsample_numpy(img, factor_range=(2, 4)):
    factor = random.randint(*factor_range)
    H, W = img.shape[:2]
    # Downsample
    low_res = cv2.resize(img, (W // factor, H // factor), interpolation=cv2.INTER_LINEAR)
    # Upsample
    restored = cv2.resize(low_res, (W, H), interpolation=cv2.INTER_LINEAR)
    # If channel dim was lost (for single channel), add it back? cv2.resize normally keeps it if 3, drops if 1?
    # Actually cv2.resize on (H, W) -> (H', W'). If input was (H, W), output is (H', W').
    return restored

def apply_signal_dropout_numpy(img, num_regions_range=(1, 3), region_size_range=(0.1, 0.3)):
    H, W = img.shape[:2]
    num_regions = random.randint(*num_regions_range)
    mask = np.ones((H, W), dtype=np.float32)
    
    y_grid, x_grid = np.meshgrid(np.arange(H), np.arange(W), indexing='ij')
    
    for _ in range(num_regions):
        cx = random.randint(0, W)
        cy = random.randint(0, H)
        h_ratio = random.uniform(*region_size_range)
        w_ratio = random.uniform(*region_size_range)
        h_radius = int(H * h_ratio) // 2
        w_radius = int(W * w_ratio) // 2
        
        dist_sq = ((x_grid - cx) / (w_radius + 1e-6)) ** 2 + ((y_grid - cy) / (h_radius + 1e-6)) ** 2
        dropout_region = 1.0 / (1.0 + np.exp(-10 * (dist_sq - 1.0)))
        mask *= dropout_region

    if img.ndim == 3:
        mask = mask[..., None]
        
    return img * mask

def apply_domain_randomization_numpy(img, 
                                   gamma_range=(0.85, 1.25), 
                                   contrast_range=(0.85, 1.15),
                                   brightness_range=(-0.05, 0.05),
                                   noise_std_range=(0.0, 0.02),
                                   blur_prob=0.1, blur_kernel_range=(3, 7),
                                   bias_field_prob=0.2,
                                   speckle_prob=0.1,
                                   poisson_prob=0.1,
                                   downsample_prob=0.01,
                                   dropout_prob=0.1):
    """
    Apply domain randomization to a single numpy image.
    Args:
        img: np.array, [H, W] or [H, W, C], values in [0, 1]
    Returns:
        augmented: np.array, same shape, values clipped to [0, 1]
    """
    augmented = img.copy().astype(np.float32)
    H, W = augmented.shape[:2]

    # 0. Intensity Bias Field
    if random.random() < bias_field_prob:
        bias_field = generate_intensity_bias_field_numpy(H, W)
        if augmented.ndim == 3: bias_field = bias_field[..., None]
        augmented = augmented * bias_field

    # Dropout
    if random.random() < dropout_prob:
        augmented = apply_signal_dropout_numpy(augmented)

    # 1. Gamma
    gamma = random.uniform(*gamma_range)
    augmented = np.power(np.maximum(augmented, 1e-8), gamma)

    # 2. Contrast
    contrast = random.uniform(*contrast_range)
    mean_val = np.mean(augmented)
    augmented = (augmented - mean_val) * contrast + mean_val

    # 3. Brightness
    brightness = random.uniform(*brightness_range)
    augmented = augmented + brightness

    # 4. Gaussian Noise
    noise_std = random.uniform(*noise_std_range)
    if noise_std > 0:
        noise = np.random.randn(*augmented.shape) * noise_std
        augmented = augmented + noise

    # 5. Speckle Noise
    if random.random() < speckle_prob:
        augmented = apply_speckle_noise_numpy(augmented)

    # 6. Poisson Noise
    if random.random() < poisson_prob:
        augmented = apply_poisson_noise_numpy(augmented)

    # 7. Gaussian Blur
    if random.random() < blur_prob:
        k = random.choice(range(blur_kernel_range[0], blur_kernel_range[1] + 1, 2))
        augmented = cv2.GaussianBlur(augmented, (k, k), 0)
        if img.ndim == 3 and augmented.ndim == 2:
            augmented = augmented[..., None]

    # 8. Downsample
    if random.random() < downsample_prob:
        augmented = apply_random_downsample_numpy(augmented)
        if img.ndim == 3 and augmented.ndim == 2:
            augmented = augmented[..., None]

    return np.clip(augmented, 0.0, 1.0)



def generate_intensity_bias_field(H, W, device, num_control_points=4, strength_range=(0.85, 1.15)):
    """
    生成随机 Intensity Bias Field (空间渐变亮度场)
    模拟真实眼底成像中的光照不均匀性 (如边缘比中心暗)
    
    Args:
        H, W: 图像尺寸
        device: torch 设备
        num_control_points: 控制点数量 (越少越平滑)
        strength_range: 亮度乘数范围
    
    Returns:
        bias_field: [1, 1, H, W] 亮度乘法场
    """
    # 生成低分辨率随机场
    low_res = torch.rand(1, 1, num_control_points, num_control_points, device=device)
    # 缩放到 strength_range
    low_res = low_res * (strength_range[1] - strength_range[0]) + strength_range[0]
    # 上采样到原始分辨率 (双三次插值产生平滑渐变)
    bias_field = F.interpolate(low_res, size=(H, W), mode='bicubic', align_corners=False)
    return bias_field


def apply_speckle_noise(img, intensity_range=(0.0, 0.15)):
    """
    添加斑点噪声 (Speckle Noise)
    常见于 OCT、超声等相干成像系统
    
    公式: out = img + img * noise
    即噪声强度与局部亮度成正比
    """
    intensity = random.uniform(*intensity_range)
    if intensity > 0:
        noise = torch.randn_like(img) * intensity
        img = img + img * noise
    return img


def apply_poisson_noise(img, scale_range=(50, 200)):
    """
    添加泊松噪声 (Shot Noise)
    模拟低光条件下光子计数噪声
    
    Args:
        scale_range: 缩放因子范围, 越小噪声越强
    """
    scale = random.uniform(*scale_range)
    # 转换到 numpy 处理
    img_np = img.cpu().numpy()
    # 缩放到 [0, scale] 范围
    img_scaled = img_np * scale
    # 应用泊松噪声
    noisy = np.random.poisson(img_scaled.clip(0, None)).astype(np.float32)
    # 缩放回 [0, 1]
    noisy = noisy / scale
    return torch.from_numpy(noisy).to(img.device)


def apply_random_downsample(img, factor_range=(2, 4)):
    """
    随机降采样后再上采样回原尺寸
    模拟低分辨率或老旧设备产生的模糊图像
    """
    _, _, H, W = img.shape
    factor = random.randint(*factor_range)
    # 降采样
    low_res = F.interpolate(img, size=(H // factor, W // factor), mode='bilinear', align_corners=False)
    # 上采样回原尺寸
    restored = F.interpolate(low_res, size=(H, W), mode='bilinear', align_corners=False)
    return restored


def apply_domain_randomization(img_tensor, gamma_range=(0.7, 1.5), 
                                contrast_range=(0.7, 1.3),
                                brightness_range=(-0.15, 0.15),
                                noise_std_range=(0.0, 0.05),
                                blur_prob=0.3, blur_kernel_range=(3, 7),
                                bias_field_prob=0.5,
                                speckle_prob=0.3,
                                poisson_prob=0.2,
                                downsample_prob=0.03):
    """
    对输入图像张量应用域随机化增强 (增强版)
    
    Args:
        img_tensor: [B, 1, H, W] 形状的图像张量，值域 [0, 1]
        gamma_range: Gamma 变换范围
        contrast_range: 对比度调整范围
        brightness_range: 亮度偏移范围
        noise_std_range: 高斯噪声标准差范围
        blur_prob: 应用模糊的概率
        blur_kernel_range: 模糊核大小范围 (奇数)
        bias_field_prob: 应用 Intensity Bias Field 的概率
        speckle_prob: 应用斑点噪声的概率
        poisson_prob: 应用泊松噪声的概率
        downsample_prob: 应用随机降采样的概率 (默认3%)
    
    Returns:
        增强后的图像张量 [B, 1, H, W]
    """
def apply_signal_dropout(img, num_regions_range=(1, 3), region_size_range=(0.1, 0.3)):
    """
    模拟生理性或成像缺陷导致的信号丢失 (Signal Dropout)
    例如：无灌注区 (Capillary Non-perfusion) 或 严重的阴影遮挡
    这不仅仅是变暗，而是结构信息的彻底丢失（变为纯黑或极低值）
    
    Args:
        img: [1, 1, H, W]
        num_regions_range: 丢失区域数量范围
        region_size_range: 丢失区域相对于图像尺寸的比例范围
    """
    _, _, H, W = img.shape
    num_regions = random.randint(*num_regions_range)
    
    # 创建一个全1的掩码
    mask = torch.ones_like(img)
    
    for _ in range(num_regions):
        # 随机中心
        cx = random.randint(0, W)
        cy = random.randint(0, H)
        
        # 随机大小 (椭圆)
        h_ratio = random.uniform(*region_size_range)
        w_ratio = random.uniform(*region_size_range)
        h_radius = int(H * h_ratio) // 2
        w_radius = int(W * w_ratio) // 2
        
        #更加自然的形状：生成一个高斯衰减的掩码，而不是硬裁剪
        y_grid, x_grid = torch.meshgrid(torch.arange(H, device=img.device), torch.arange(W, device=img.device))
        
        # 计算到中心的归一化距离
        dist_sq = ((x_grid - cx) / (w_radius + 1e-6)) ** 2 + ((y_grid - cy) / (h_radius + 1e-6)) ** 2
        
        # 距离 < 1 的区域受到影响
        # 使用 sigmoid 生成平滑边缘，避免产生非自然的人工边缘（LoFTR可能会误认为那是特征）
        # 1 / (1 + exp(-k * (dist - 1))) -> 当 dist < 1 时接近 0 (丢失)，当 dist > 1 时接近 1 (保留)
        dropout_region = 1 / (1 + torch.exp(-10 * (dist_sq - 1.0)))
        
        # 叠加掩码 (取交集)
        mask = mask * dropout_region.unsqueeze(0).unsqueeze(0)
        
    return img * mask

def apply_domain_randomization(img_tensor, gamma_range=(0.85, 1.25), 
                                contrast_range=(0.85, 1.15),
                                brightness_range=(-0.05, 0.05),
                                noise_std_range=(0.0, 0.02),
                                blur_prob=0.1, blur_kernel_range=(3, 7),
                                bias_field_prob=0.2,
                                speckle_prob=0.1,
                                poisson_prob=0.1,
                                downsample_prob=0.01,
                                dropout_prob=0.1): # 新增 dropout_prob
    """
    对输入图像张量应用域随机化增强 (增强版)
    """
    B, _, H, W = img_tensor.shape
    device = img_tensor.device
    augmented = img_tensor.clone()
    
    for b in range(B):
        img = augmented[b:b+1]  # [1, 1, H, W]
        
        # 0. Intensity Bias Field (空间渐变亮度不均)
        if random.random() < bias_field_prob:
            bias_field = generate_intensity_bias_field(H, W, device)
            img = img * bias_field
            
        # [新增] 模拟生理性信号丢失 (Signal Dropout)
        # 这对于模拟 FA/OCTA 中的无灌注区非常重要
        if random.random() < dropout_prob:
            img = apply_signal_dropout(img)
        
        # 1. Gamma 变换 (模拟不同曝光条件)
        gamma = random.uniform(*gamma_range)
        img = torch.pow(img.clamp(min=1e-8), gamma)
        
        # 2. 对比度调整 (围绕均值缩放)
        contrast = random.uniform(*contrast_range)
        mean_val = img.mean()
        img = (img - mean_val) * contrast + mean_val
        
        # 3. 亮度偏移
        brightness = random.uniform(*brightness_range)
        img = img + brightness
        
        # 4. 高斯噪声
        noise_std = random.uniform(*noise_std_range)
        if noise_std > 0:
            noise = torch.randn_like(img) * noise_std
            img = img + noise
        
        # 5. 斑点噪声 (Speckle Noise)
        if random.random() < speckle_prob:
            img = apply_speckle_noise(img)
        
        # 6. 泊松噪声 (Shot Noise)
        if random.random() < poisson_prob:
            img = apply_poisson_noise(img)
        
        # 7. 高斯模糊 (随机应用)
        if random.random() < blur_prob:
            kernel_size = random.choice(range(blur_kernel_range[0], blur_kernel_range[1] + 1, 2))  # 只选奇数
            # 使用 OpenCV 进行模糊 (更高效)
            img_np = img[0, 0].cpu().numpy()
            img_np = cv2.GaussianBlur(img_np, (kernel_size, kernel_size), 0)
            img = torch.from_numpy(img_np).unsqueeze(0).unsqueeze(0).to(device)
        
        # 8. 随机降采样+上采样 (模拟低分辨率扫描, 小概率)
        if random.random() < downsample_prob:
            img = apply_random_downsample(img)
        
        # 裁剪到有效范围
        augmented[b:b+1] = img.clamp(0, 1)
    
    return augmented


def save_batch_visualization(img0_orig, img1_orig, img0_aug, img1_aug, 
                              save_dir, epoch, step, batch_size, vessel_mask=None):
    """
    保存一个 batch 的可视化结果,用于检查域随机化效果
    
    Args:
        img0_orig: 原始 fix 图像 [B, 1, H, W]
        img1_orig: 原始 moving 图像 [B, 1, H, W]
        img0_aug: 增强后 fix 图像 [B, 1, H, W]
        img1_aug: 增强后 moving 图像 [B, 1, H, W]
        save_dir: 保存目录
        epoch: 当前 epoch
        step: 当前 step (batch index)
        batch_size: batch 大小
        vessel_mask: 可选，血管掩码 [B, 1, H, W]
    """
    import os
    
    vis_dir = os.path.join(save_dir, f'epoch{epoch}_visualization')
    os.makedirs(vis_dir, exist_ok=True)
    
    for b in range(min(batch_size, img0_orig.shape[0])):
        sample_dir = os.path.join(vis_dir, f'step{step}_sample{b}')
        os.makedirs(sample_dir, exist_ok=True)
        
        # 转换为 numpy 并保存
        fix_orig = (img0_orig[b, 0].cpu().numpy() * 255).astype(np.uint8)
        mov_orig = (img1_orig[b, 0].cpu().numpy() * 255).astype(np.uint8)
        fix_aug = (img0_aug[b, 0].cpu().numpy() * 255).astype(np.uint8)
        mov_aug = (img1_aug[b, 0].cpu().numpy() * 255).astype(np.uint8)
        
        cv2.imwrite(os.path.join(sample_dir, 'fix_original.png'), fix_orig)
        cv2.imwrite(os.path.join(sample_dir, 'moving_original.png'), mov_orig)
        cv2.imwrite(os.path.join(sample_dir, 'fix_augmented.png'), fix_aug)
        cv2.imwrite(os.path.join(sample_dir, 'moving_augmented.png'), mov_aug)
        
        if vessel_mask is not None:
            vessel = (vessel_mask[b, 0].cpu().numpy() * 255).astype(np.uint8)
            cv2.imwrite(os.path.join(sample_dir, 'vessel_mask.png'), vessel)
        
        # 创建对比图: 左边原始,右边增强
        comparison_fix = np.hstack([fix_orig, fix_aug])
        comparison_mov = np.hstack([mov_orig, mov_aug])
        cv2.imwrite(os.path.join(sample_dir, 'comparison_fix_orig_vs_aug.png'), comparison_fix)
        cv2.imwrite(os.path.join(sample_dir, 'comparison_moving_orig_vs_aug.png'), comparison_mov)
