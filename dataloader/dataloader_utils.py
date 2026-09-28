# -*- coding: utf-8 -*-
"""
@author: QgZhan
@contact: zhanqg@foxmail.com
@file: dataloader_utils.py
@time: 2022/4/19 11:27

集成NDA_SNN的数据增强方法:
- DVS数据增强: roll, rotate, shear (随机选择)
- CutMix数据增强
- Cutout数据增强
"""

import torch
import math
import random
import numpy as np
from torch.utils.data import DataLoader
from PIL import Image, ImageEnhance, ImageOps
from prefetch_generator import BackgroundGenerator
from collections.abc import Iterable
import torchvision.transforms.functional as F
from torchvision.transforms.transforms import ToPILImage, ToTensor
import torchvision.transforms as transforms


def split_to_train_test_set(train_ratio: float, origin_dataset: torch.utils.data.Dataset, num_classes: int,
                            random_split: bool = False):
    """
    :param train_ratio: split the ratio of the origin dataset as the train set
    :type train_ratio: float
    :param origin_dataset: the origin dataset
    :type origin_dataset: torch.utils.data.Dataset
    :param num_classes: total classes number, e.g., ``10`` for the MNIST dataset
    :type num_classes: int
    :param random_split: If ``False``, the front ratio of samples in each classes will
            be included in train set, while the reset will be included in test set.
            If ``True``, this function will split samples in each classes randomly. The randomness is controlled by
            ``numpy.randon.seed``
    :type random_split: int
    :return: a tuple ``(train_set, test_set)``
    :rtype: tuple
    """
    label_idx = []
    for i in range(num_classes):
        label_idx.append([])

    for i, item in enumerate(origin_dataset):
        y = item[1]
        if isinstance(y, np.ndarray) or isinstance(y, torch.Tensor):
            y = y.item()
        label_idx[y].append(i)
    train_idx = []
    test_idx = []
    if random_split:
        for i in range(num_classes):
            np.random.shuffle(label_idx[i])

    for i in range(num_classes):
        pos = math.ceil(label_idx[i].__len__() * train_ratio)
        train_idx.extend(label_idx[i][0: pos])
        test_idx.extend(label_idx[i][pos: label_idx[i].__len__()])

    return torch.utils.data.Subset(origin_dataset, train_idx), torch.utils.data.Subset(origin_dataset, test_idx)


class DataLoaderX(torch.utils.data.DataLoader):
    def __iter__(self):
        return BackgroundGenerator(super().__iter__())

    def get_len(self):
        try:
            return self.dataset.get_len()
        except:
            return self.dataset.__len__()


# code from https://github.com/uoguelph-mlrg/Cutout/blob/master/util/cutout.py
# Improved Regularization of Convolutional Neural Networks with Cutout.
class Cutout(object):
    """Randomly mask out one or more patches from an image.
    Args:
        n_holes (int): Number of patches to cut out of each image.
        length (int): The length (in pixels) of each square patch.
    """
    def __init__(self, n_holes, length):
        self.n_holes = n_holes
        self.length = length

    def __call__(self, img):
        """
        Args:
            img (Tensor): Tensor image of size (C, H, W).
        Returns:
            Tensor: Image with n_holes of dimension length x length cut out of it.
        """
        h = img.size(1)
        w = img.size(2)

        mask = np.ones((h, w), np.float32)

        for n in range(self.n_holes):
            y = np.random.randint(h)
            x = np.random.randint(w)

            y1 = np.clip(y - self.length // 2, 0, h)
            y2 = np.clip(y + self.length // 2, 0, h)
            x1 = np.clip(x - self.length // 2, 0, w)
            x2 = np.clip(x + self.length // 2, 0, w)

            mask[y1: y2, x1: x2] = 0.

        mask = torch.from_numpy(mask)
        mask = mask.expand_as(img)
        img = img * mask
        return img


class SubPolicy(object):
    def __init__(self, p1, operation1, magnitude_idx1, p2, operation2, magnitude_idx2, fillcolor=(128, 128, 128)):
        self.p1 = p1
        self.op1 = operation1
        self.magnitude_idx1 = magnitude_idx1
        self.p2 = p2
        self.op2 = operation2
        self.magnitude_idx2 = magnitude_idx2
        self.fillcolor = fillcolor
        self.init = 0

    def gen(self, operation1, magnitude_idx1, operation2, magnitude_idx2, fillcolor):
        ranges = {
            "shearX": np.linspace(0, 0.3, 10),
            "shearY": np.linspace(0, 0.3, 10),
            "translateX": np.linspace(0, 150 / 331, 10),
            "translateY": np.linspace(0, 150 / 331, 10),
            "rotate": np.linspace(0, 30, 10),
            "color": np.linspace(0.0, 0.9, 10),
            "posterize": np.round(np.linspace(8, 4, 10), 0).astype(int),
            "solarize": np.linspace(256, 0, 10),
            "contrast": np.linspace(0.0, 0.9, 10),
            "sharpness": np.linspace(0.0, 0.9, 10),
            "brightness": np.linspace(0.0, 0.9, 10),
            "autocontrast": [0] * 10,
            "equalize": [0] * 10,
            "invert": [0] * 10
        }

        def rotate_with_fill(img, magnitude):
            rot = img.convert("RGBA").rotate(magnitude)
            return Image.composite(rot, Image.new("RGBA", rot.size, (128,) * 4), rot).convert(img.mode)

        func = {
            "shearX": lambda img, magnitude: img.transform(
                img.size, Image.AFFINE, (1, magnitude *
                                         random.choice([-1, 1]), 0, 0, 1, 0),
                Image.BICUBIC, fillcolor=fillcolor),
            "shearY": lambda img, magnitude: img.transform(
                img.size, Image.AFFINE, (1, 0, 0, magnitude *
                                         random.choice([-1, 1]), 1, 0),
                Image.BICUBIC, fillcolor=fillcolor),
            "translateX": lambda img, magnitude: img.transform(
                img.size, Image.AFFINE, (1, 0, magnitude *
                                         img.size[0] * random.choice([-1, 1]), 0, 1, 0),
                fillcolor=fillcolor),
            "translateY": lambda img, magnitude: img.transform(
                img.size, Image.AFFINE, (1, 0, 0, 0, 1, magnitude *
                                         img.size[1] * random.choice([-1, 1])),
                fillcolor=fillcolor),
            "rotate": lambda img, magnitude: rotate_with_fill(img, magnitude),
            # "rotate": lambda img, magnitude: img.rotate(magnitude * random.choice([-1, 1])),
            "color": lambda img, magnitude: ImageEnhance.Color(img).enhance(1 + magnitude * random.choice([-1, 1])),
            "posterize": lambda img, magnitude: ImageOps.posterize(img, magnitude),
            "solarize": lambda img, magnitude: ImageOps.solarize(img, magnitude),
            "contrast": lambda img, magnitude: ImageEnhance.Contrast(img).enhance(
                1 + magnitude * random.choice([-1, 1])),
            "sharpness": lambda img, magnitude: ImageEnhance.Sharpness(img).enhance(
                1 + magnitude * random.choice([-1, 1])),
            "brightness": lambda img, magnitude: ImageEnhance.Brightness(img).enhance(
                1 + magnitude * random.choice([-1, 1])),
            "autocontrast": lambda img, magnitude: ImageOps.autocontrast(img),
            "equalize": lambda img, magnitude: ImageOps.equalize(img),
            "invert": lambda img, magnitude: ImageOps.invert(img)
        }

        self.operation1 = func[operation1]
        self.magnitude1 = ranges[operation1][magnitude_idx1]
        self.operation2 = func[operation2]
        self.magnitude2 = ranges[operation2][magnitude_idx2]

    def __call__(self, img):
        if self.init == 0:
            self.gen(self.op1, self.magnitude_idx1, self.op2, self.magnitude_idx2, self.fillcolor)
            self.init = 1
        if random.random() < self.p1:
            img = self.operation1(img, self.magnitude1)
        if random.random() < self.p2:
            img = self.operation2(img, self.magnitude2)
        return img


class ImageNetPolicy(object):
    """ Randomly choose one of the best 24 Sub-policies on ImageNet.
        Example:
        >>> policy = ImageNetPolicy()
        >>> transformed = policy(image)
        Example as a PyTorch Transform:
        >>> transform=transforms.Compose([
        >>>     transforms.Resize(256),
        >>>     ImageNetPolicy(),
        >>>     transforms.ToTensor()])
    """

    def __init__(self, fillcolor=(128, 128, 128)):
        self.policies = [
            SubPolicy(0.4, "posterize", 8, 0.6, "rotate", 9, fillcolor),
            SubPolicy(0.6, "solarize", 5, 0.6, "autocontrast", 5, fillcolor),
            SubPolicy(0.8, "equalize", 8, 0.6, "equalize", 3, fillcolor),
            SubPolicy(0.6, "posterize", 7, 0.6, "posterize", 6, fillcolor),
            SubPolicy(0.4, "equalize", 7, 0.2, "solarize", 4, fillcolor),

            SubPolicy(0.4, "equalize", 4, 0.8, "rotate", 8, fillcolor),
            SubPolicy(0.6, "solarize", 3, 0.6, "equalize", 7, fillcolor),
            SubPolicy(0.8, "posterize", 5, 1.0, "equalize", 2, fillcolor),
            SubPolicy(0.2, "rotate", 3, 0.6, "solarize", 8, fillcolor),
            SubPolicy(0.6, "equalize", 8, 0.4, "posterize", 6, fillcolor),

            SubPolicy(0.8, "rotate", 8, 0.4, "color", 0, fillcolor),
            SubPolicy(0.4, "rotate", 9, 0.6, "equalize", 2, fillcolor),
            SubPolicy(0.0, "equalize", 7, 0.8, "equalize", 8, fillcolor),
            SubPolicy(0.6, "invert", 4, 1.0, "equalize", 8, fillcolor),
            SubPolicy(0.6, "color", 4, 1.0, "contrast", 8, fillcolor),

            SubPolicy(0.8, "rotate", 8, 1.0, "color", 2, fillcolor),
            SubPolicy(0.8, "color", 8, 0.8, "solarize", 7, fillcolor),
            SubPolicy(0.4, "sharpness", 7, 0.6, "invert", 8, fillcolor),
            SubPolicy(0.6, "shearX", 5, 1.0, "equalize", 9, fillcolor),
            SubPolicy(0.4, "color", 0, 0.6, "equalize", 3, fillcolor),

            SubPolicy(0.4, "equalize", 7, 0.2, "solarize", 4, fillcolor),
            SubPolicy(0.6, "solarize", 5, 0.6, "autocontrast", 5, fillcolor),
            SubPolicy(0.6, "invert", 4, 1.0, "equalize", 8, fillcolor),
            SubPolicy(0.6, "color", 4, 1.0, "contrast", 8, fillcolor)
        ]

    def __call__(self, img):
        policy_idx = random.randint(0, len(self.policies) - 1)
        return self.policies[policy_idx](img)

    def __repr__(self):
        return "AutoAugment ImageNet Policy"


class CIFAR10Policy(object):
    """ Randomly choose one of the best 25 Sub-policies on CIFAR10.

        Example:
        >>> policy = CIFAR10Policy()
        >>> transformed = policy(image)

        Example as a PyTorch Transform:
        >>> transform=transforms.Compose([
        >>>     transforms.Resize(256),
        >>>     CIFAR10Policy(),
        >>>     transforms.ToTensor()])
    """

    def __init__(self, fillcolor=(128, 128, 128)):
        self.policies = [
            SubPolicy(0.1, "invert", 7, 0.2, "contrast", 6, fillcolor),
            SubPolicy(0.7, "rotate", 2, 0.3, "translateX", 9, fillcolor),
            SubPolicy(0.8, "sharpness", 1, 0.9, "sharpness", 3, fillcolor),
            SubPolicy(0.5, "shearY", 8, 0.7, "translateY", 9, fillcolor),
            SubPolicy(0.5, "autocontrast", 8, 0.9, "equalize", 2, fillcolor),

            SubPolicy(0.2, "shearY", 7, 0.3, "posterize", 7, fillcolor),
            SubPolicy(0.4, "color", 3, 0.6, "brightness", 7, fillcolor),
            SubPolicy(0.3, "sharpness", 9, 0.7, "brightness", 9, fillcolor),
            SubPolicy(0.6, "equalize", 5, 0.5, "equalize", 1, fillcolor),
            SubPolicy(0.6, "contrast", 7, 0.6, "sharpness", 5, fillcolor),

            SubPolicy(0.7, "color", 7, 0.5, "translateX", 8, fillcolor),
            SubPolicy(0.3, "equalize", 7, 0.4, "autocontrast", 8, fillcolor),
            SubPolicy(0.4, "translateY", 3, 0.2, "sharpness", 6, fillcolor),
            SubPolicy(0.9, "brightness", 6, 0.2, "color", 8, fillcolor),
            SubPolicy(0.5, "solarize", 2, 0.0, "invert", 3, fillcolor),

            SubPolicy(0.2, "equalize", 0, 0.6, "autocontrast", 0, fillcolor),
            SubPolicy(0.2, "equalize", 8, 0.8, "equalize", 4, fillcolor),
            SubPolicy(0.9, "color", 9, 0.6, "equalize", 6, fillcolor),
            SubPolicy(0.8, "autocontrast", 4, 0.2, "solarize", 8, fillcolor),
            SubPolicy(0.1, "brightness", 3, 0.7, "color", 0, fillcolor),

            SubPolicy(0.4, "solarize", 5, 0.9, "autocontrast", 3, fillcolor),
            SubPolicy(0.9, "translateY", 9, 0.7, "translateY", 9, fillcolor),
            SubPolicy(0.9, "autocontrast", 2, 0.8, "solarize", 3, fillcolor),
            SubPolicy(0.8, "equalize", 8, 0.1, "invert", 3, fillcolor),
            SubPolicy(0.7, "translateY", 9, 0.9, "autocontrast", 1, fillcolor)
        ]

    def __call__(self, img):
        policy_idx = random.randint(0, len(self.policies) - 1)
        return self.policies[policy_idx](img)

    def __repr__(self):
        return "AutoAugment CIFAR10 Policy"


class RGBToGrayscale3Channel(object):
    """将RGB图像转换为灰度图，但保持三通道格式
    
    这个变换将RGB图像转换为灰度图像，但保持三个通道，每个通道都包含相同的灰度值。
    这样可以测试RGB到DVS的迁移学习是否基于结构信息而非色彩信息。
    """
    
    def __call__(self, img):
        """
        Args:
            img (PIL Image): RGB图像
            
        Returns:
            PIL Image: 灰度图像但保持三通道格式
        """
        # 转换为灰度图
        grayscale = img.convert('L')
        # 转换回RGB格式（三个通道都是相同的灰度值）
        rgb_grayscale = Image.merge('RGB', (grayscale, grayscale, grayscale))
        return rgb_grayscale
    
    def __repr__(self):
        return self.__class__.__name__ + '()'


class DVSResize(object):
    """Resize the input PIL Image to the given size.

    Args:
        size (sequence or int): Desired output size. If size is a sequence like
            (h, w), output size will be matched to this. If size is an int,
            smaller edge of the image will be matched to this number.
            i.e, if height > width, then image will be rescaled to
            (size * height / width, size)
        interpolation (int, optional): Desired interpolation. Default is
            ``PIL.Image.BILINEAR``
    """

    def __init__(self, size, T, interpolation=Image.BILINEAR):
        assert isinstance(size, int) or (isinstance(size, Iterable) and len(size) == 2)
        self.size = size
        self.T = T
        self.interpolation = interpolation

        self._pil_interpolation_to_str = {Image.NEAREST: 'PIL.Image.NEAREST',
                                          Image.BILINEAR: 'PIL.Image.BILINEAR',
                                          Image.BICUBIC: 'PIL.Image.BICUBIC',
                                          Image.LANCZOS: 'PIL.Image.LANCZOS',
                                          Image.HAMMING: 'PIL.Image.HAMMING',
                                          Image.BOX: 'PIL.Image.BOX',
                                          }
        self.img = ToPILImage()
        self.to_tensor = ToTensor()

    def __call__(self, dvs_data):
        """
        Args:
            dvs_data (DVS data): DVS data to be scaled, which shape should be (T, C, H, W).

        Returns:
            Scaled DVS data tensor: Rescaled DVS data tensor, which shape should be (T, C, size, size).
        """
        dvs_data = torch.tensor(dvs_data, dtype=torch.float32)
        out = []
        for t in range(self.T):
            out.append(self.to_tensor(F.resize(self.img(dvs_data[t]), self.size, self.interpolation)))
        return torch.stack(out, dim=0)

    def __repr__(self):
        interpolate_str = self._pil_interpolation_to_str[self.interpolation]
        return self.__class__.__name__ + '(size={0}, interpolation={1})'.format(self.size, interpolate_str)


# ============================================================================
# NDA_SNN数据增强方法集成 (Neuromorphic Data Augmentation)
# ============================================================================

class DVSAugment(object):
    """
    DVS数据增强类 - 集成自NDA_SNN
    随机选择roll、rotate或shear中的一种进行数据增强
    默认包含水平翻转（概率0.5）
    
    Args:
        roll_range (tuple): roll操作的范围，默认(-5, 5)
        rotate_degrees (float): 旋转角度范围，默认15度
        shear_range (tuple): shear操作的范围，默认(-15, 15)
        apply_prob (float): 应用增强的概率，默认1.0
        flip_prob (float): 水平翻转概率，默认0.5
    """
    
    def __init__(self, roll_range=(-5, 5), rotate_degrees=15, shear_range=(-15, 15), 
                 apply_prob=1.0, flip_prob=0.5):
        self.roll_range = roll_range
        self.rotate_degrees = rotate_degrees
        self.shear_range = shear_range
        self.apply_prob = apply_prob
        self.flip_prob = flip_prob
        
        # 初始化transform
        self.rotate_transform = transforms.RandomRotation(degrees=rotate_degrees)
        self.shear_transform = transforms.RandomAffine(degrees=0, shear=shear_range)
    
    def __call__(self, dvs_data):
        """
        Args:
            dvs_data (Tensor): DVS数据，形状为 (T, C, H, W)
        
        Returns:
            Tensor: 增强后的DVS数据
        """
        # 水平翻转（概率0.5）
        if random.random() < self.flip_prob:
            dvs_data = torch.flip(dvs_data, dims=(3,))
        
        if random.random() > self.apply_prob:
            return dvs_data
        
        # 随机选择一种增强方法
        choices = ['roll', 'rotate', 'shear']
        aug_method = np.random.choice(choices)
        
        if aug_method == 'roll':
            # 随机平移
            off1 = random.randint(self.roll_range[0], self.roll_range[1])
            off2 = random.randint(self.roll_range[0], self.roll_range[1])
            dvs_data = torch.roll(dvs_data, shifts=(off1, off2), dims=(2, 3))
        
        elif aug_method == 'rotate':
            # 随机旋转
            dvs_data = self.rotate_transform(dvs_data)
        
        elif aug_method == 'shear':
            # 随机剪切
            dvs_data = self.shear_transform(dvs_data)
        
        return dvs_data
    
    def __repr__(self):
        return (f"{self.__class__.__name__}("
                f"roll_range={self.roll_range}, "
                f"rotate_degrees={self.rotate_degrees}, "
                f"shear_range={self.shear_range}, "
                f"apply_prob={self.apply_prob})")


class DVSAugmentCaltech101(DVSAugment):
    """
    Caltech101专用的DVS数据增强 (使用较小的增强范围)
    默认包含水平翻转（概率0.5）
    """
    def __init__(self, apply_prob=1.0, flip_prob=0.5):
        super().__init__(
            roll_range=(-3, 3),
            rotate_degrees=15,
            shear_range=(-15, 15),
            apply_prob=apply_prob,
            flip_prob=flip_prob
        )


class DVSAugmentCIFAR10(DVSAugment):
    """
    CIFAR10专用的DVS数据增强 (使用较大的增强范围)
    默认包含水平翻转（概率0.5）
    """
    def __init__(self, apply_prob=1.0, flip_prob=0.5):
        super().__init__(
            roll_range=(-5, 5),
            rotate_degrees=30,
            shear_range=(-30, 30),
            apply_prob=apply_prob,
            flip_prob=flip_prob
        )


def mixup_criterion(criterion, pred, y_a, y_b, lam):
    """
    Mixup损失函数
    
    Args:
        criterion: 损失函数
        pred: 预测结果
        y_a: 第一个样本的标签
        y_b: 第二个样本的标签
        lam: mixup系数
    
    Returns:
        混合后的损失
    """
    return lam * criterion(pred, y_a) + (1 - lam) * criterion(pred, y_b)


def rand_bbox(size, lam):
    """
    生成CutMix的随机边界框
    
    Args:
        size: 输入数据的尺寸 (B, T, C, H, W)
        lam: CutMix系数
    
    Returns:
        边界框坐标 (bbx1, bby1, bbx2, bby2)
    """
    W = size[3]
    H = size[4]
    cut_rat = np.sqrt(1. - lam)
    cut_w = int(W * cut_rat)
    cut_h = int(H * cut_rat)

    # 随机选择中心点
    cx = np.random.randint(W)
    cy = np.random.randint(H)

    bbx1 = np.clip(cx - cut_w // 2, 0, W)
    bby1 = np.clip(cy - cut_h // 2, 0, H)
    bbx2 = np.clip(cx + cut_w // 2, 0, W)
    bby2 = np.clip(cy + cut_h // 2, 0, H)

    return bbx1, bby1, bbx2, bby2


def cutmix_data(input_data, target, alpha=1.0):
    """
    CutMix数据增强 - 集成自NDA_SNN
    
    Args:
        input_data (Tensor): 输入数据，形状为 (B, T, C, H, W)
        target (Tensor): 目标标签
        alpha (float): Beta分布的参数
    
    Returns:
        混合后的数据、标签a、标签b、混合系数
    """
    lam = np.random.beta(alpha, alpha)
    rand_index = torch.randperm(input_data.size()[0]).cuda()

    target_a = target
    target_b = target[rand_index]

    # 生成混合样本
    bbx1, bby1, bbx2, bby2 = rand_bbox(input_data.size(), lam)
    input_data[:, :, :, bbx1:bbx2, bby1:bby2] = input_data[rand_index, :, :, bbx1:bbx2, bby1:bby2]
    
    # 根据像素比例调整lambda
    lam = 1 - ((bbx2 - bbx1) * (bby2 - bby1) / (input_data.size()[-1] * input_data.size()[-2]))
    
    return input_data, target_a, target_b, lam


def mixup_data(input_data, target, alpha=1.0):
    """
    Mixup数据增强
    
    Args:
        input_data (Tensor): 输入数据
        target (Tensor): 目标标签
        alpha (float): Beta分布的参数
    
    Returns:
        混合后的数据、标签a、标签b、混合系数
    """
    lam = np.random.beta(alpha, alpha)
    batch_size = input_data.size()[0]
    
    if input_data.is_cuda:
        index = torch.randperm(batch_size).cuda()
    else:
        index = torch.randperm(batch_size)
    
    mixed_input = lam * input_data + (1 - lam) * input_data[index, :]
    target_a, target_b = target, target[index]
    
    return mixed_input, target_a, target_b, lam
