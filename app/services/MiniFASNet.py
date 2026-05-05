# app/services/MiniFASNet.py
"""
MiniFASNet – Lightweight Anti-Spoofing Network

This module implements MiniFASNetV1/V2 and their SE variants as described in
the Silent-Face-Anti-Spoofing project (MiniVision).

Designed for low computational cost (~80×80 input, <0.5M params).

Supported variants:
- MiniFASNetV1
- MiniFASNetV2
- MiniFASNetV1SE
- MiniFASNetV2SE
"""

import torch
import torch.nn as nn
import torch.nn.functional as F


class L2Norm(nn.Module):
    """L2 normalization layer."""
    def forward(self, x: torch.Tensor) -> torch.Tensor:
        return F.normalize(x)


class Flatten(nn.Module):
    """Flatten layer."""
    def forward(self, x: torch.Tensor) -> torch.Tensor:
        return x.view(x.size(0), -1)


class ConvBlock(nn.Module):
    """Basic convolution + BN + PReLU block."""
    def __init__(self, in_c: int, out_c: int, kernel: tuple = (1, 1),
                 stride: tuple = (1, 1), padding: tuple = (0, 0), groups: int = 1):
        super().__init__()
        self.conv = nn.Conv2d(in_c, out_c, kernel_size=kernel, stride=stride,
                              padding=padding, groups=groups, bias=False)
        self.bn = nn.BatchNorm2d(out_c)
        self.prelu = nn.PReLU(out_c)

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        x = self.conv(x)
        x = self.bn(x)
        x = self.prelu(x)
        return x


class LinearBlock(nn.Module):
    """Linear (1×1) conv + BN block (no activation)."""
    def __init__(self, in_c: int, out_c: int, kernel: tuple = (1, 1),
                 stride: tuple = (1, 1), padding: tuple = (0, 0), groups: int = 1):
        super().__init__()
        self.conv = nn.Conv2d(in_c, out_c, kernel_size=kernel, stride=stride,
                              padding=padding, groups=groups, bias=False)
        self.bn = nn.BatchNorm2d(out_c)

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        x = self.conv(x)
        x = self.bn(x)
        return x


class DepthWise(nn.Module):
    """Depthwise separable block + optional residual."""
    def __init__(self, c1: tuple, c2: tuple, c3: tuple, residual: bool = False,
                 kernel: tuple = (3, 3), stride: tuple = (2, 2), padding: tuple = (1, 1),
                 groups: int = 1):
        super().__init__()
        c1_in, c1_out = c1
        c2_in, c2_out = c2
        c3_in, c3_out = c3

        self.conv = ConvBlock(c1_in, c1_out, kernel=(1, 1), padding=(0, 0), stride=(1, 1))
        self.conv_dw = ConvBlock(c2_in, c2_out, kernel=kernel, padding=padding,
                                 stride=stride, groups=c2_in)
        self.project = LinearBlock(c3_in, c3_out, kernel=(1, 1), padding=(0, 0), stride=(1, 1))
        self.residual = residual

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        if self.residual:
            shortcut = x
        x = self.conv(x)
        x = self.conv_dw(x)
        x = self.project(x)
        if self.residual:
            x = shortcut + x
        return x


class Residual(nn.Module):
    """Stacked depthwise residual blocks."""
    def __init__(self, c1: list, c2: list, c3: list, num_block: int, groups: int,
                 kernel: tuple = (3, 3), stride: tuple = (1, 1), padding: tuple = (1, 1)):
        super().__init__()
        modules = []
        for i in range(num_block):
            modules.append(DepthWise(c1[i], c2[i], c3[i], residual=True,
                                     kernel=kernel, stride=stride, padding=padding,
                                     groups=groups))
        self.model = nn.Sequential(*modules)

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        return self.model(x)


class SEModule(nn.Module):
    """Squeeze-and-Excitation module."""
    def __init__(self, channels: int, reduction: int = 4):
        super().__init__()
        self.avg_pool = nn.AdaptiveAvgPool2d(1)
        self.fc1 = nn.Conv2d(channels, channels // reduction, kernel_size=1,
                             bias=False)
        self.bn1 = nn.BatchNorm2d(channels // reduction)
        self.relu = nn.ReLU(inplace=True)
        self.fc2 = nn.Conv2d(channels // reduction, channels, kernel_size=1,
                             bias=False)
        self.bn2 = nn.BatchNorm2d(channels)
        self.sigmoid = nn.Sigmoid()

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        module_input = x
        x = self.avg_pool(x)
        x = self.fc1(x)
        x = self.bn1(x)
        x = self.relu(x)
        x = self.fc2(x)
        x = self.bn2(x)
        x = self.sigmoid(x)
        return module_input * x


class DepthWiseSE(nn.Module):
    """Depthwise block with SE attention + optional residual."""
    def __init__(self, c1: tuple, c2: tuple, c3: tuple, residual: bool = False,
                 kernel: tuple = (3, 3), stride: tuple = (2, 2), padding: tuple = (1, 1),
                 groups: int = 1, se_reduct: int = 8):
        super().__init__()
        c1_in, c1_out = c1
        c2_in, c2_out = c2
        c3_in, c3_out = c3

        self.conv = ConvBlock(c1_in, c1_out, kernel=(1, 1), padding=(0, 0), stride=(1, 1))
        self.conv_dw = ConvBlock(c2_in, c2_out, kernel=kernel, padding=padding,
                                 stride=stride, groups=c2_in)
        self.project = LinearBlock(c3_in, c3_out, kernel=(1, 1), padding=(0, 0), stride=(1, 1))
        self.se_module = SEModule(c3_out, reduction=se_reduct)
        self.residual = residual

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        if self.residual:
            shortcut = x
        x = self.conv(x)
        x = self.conv_dw(x)
        x = self.project(x)
        if self.residual:
            x = self.se_module(x)
            x = shortcut + x
        return x


class ResidualSE(nn.Module):
    """Residual block stack with SE attention on the last block."""
    def __init__(self, c1: list, c2: list, c3: list, num_block: int, groups: int,
                 kernel: tuple = (3, 3), stride: tuple = (1, 1), padding: tuple = (1, 1),
                 se_reduct: int = 4):
        super().__init__()
        modules = []
        for i in range(num_block):
            if i == num_block - 1:
                modules.append(
                    DepthWiseSE(c1[i], c2[i], c3[i], residual=True,
                                kernel=kernel, stride=stride, padding=padding,
                                groups=groups, se_reduct=se_reduct)
                )
            else:
                modules.append(
                    DepthWise(c1[i], c2[i], c3[i], residual=True,
                              kernel=kernel, stride=stride, padding=padding,
                              groups=groups)
                )
        self.model = nn.Sequential(*modules)

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        return self.model(x)


class MiniFASNet(nn.Module):
    """Base MiniFASNet architecture."""
    def __init__(self, keep: list, embedding_size: int, conv6_kernel: tuple = (7, 7),
                 drop_p: float = 0.0, num_classes: int = 3, img_channel: int = 3):
        super().__init__()
        self.embedding_size = embedding_size

        self.conv1 = ConvBlock(img_channel, keep[0], kernel=(3, 3),
                               stride=(2, 2), padding=(1, 1))
        self.conv2_dw = ConvBlock(keep[0], keep[1], kernel=(3, 3),
                                  stride=(1, 1), padding=(1, 1), groups=keep[1])

        c1 = [(keep[1], keep[2])]
        c2 = [(keep[2], keep[3])]
        c3 = [(keep[3], keep[4])]
        self.conv_23 = DepthWise(c1[0], c2[0], c3[0], kernel=(3, 3),
                                 stride=(2, 2), padding=(1, 1), groups=keep[3])

        c1 = [(keep[4], keep[5]), (keep[7], keep[8]), (keep[10], keep[11]), (keep[13], keep[14])]
        c2 = [(keep[5], keep[6]), (keep[8], keep[9]), (keep[11], keep[12]), (keep[14], keep[15])]
        c3 = [(keep[6], keep[7]), (keep[9], keep[10]), (keep[12], keep[13]), (keep[15], keep[16])]
        self.conv_3 = Residual(c1, c2, c3, num_block=4, groups=keep[4])

        c1 = [(keep[16], keep[17])]
        c2 = [(keep[17], keep[18])]
        c3 = [(keep[18], keep[19])]
        self.conv_34 = DepthWise(c1[0], c2[0], c3[0], kernel=(3, 3),
                                 stride=(2, 2), padding=(1, 1), groups=keep[19])

        c1 = [(keep[19], keep[20]), (keep[22], keep[23]), (keep[25], keep[26]),
              (keep[28], keep[29]), (keep[31], keep[32]), (keep[34], keep[35])]
        c2 = [(keep[20], keep[21]), (keep[23], keep[24]), (keep[26], keep[27]),
              (keep[29], keep[30]), (keep[32], keep[33]), (keep[35], keep[36])]
        c3 = [(keep[21], keep[22]), (keep[24], keep[25]), (keep[27], keep[28]),
              (keep[30], keep[31]), (keep[33], keep[34]), (keep[36], keep[37])]
        self.conv_4 = Residual(c1, c2, c3, num_block=6, groups=keep[19])

        c1 = [(keep[37], keep[38])]
        c2 = [(keep[38], keep[39])]
        c3 = [(keep[39], keep[40])]
        self.conv_45 = DepthWise(c1[0], c2[0], c3[0], kernel=(3, 3),
                                 stride=(2, 2), padding=(1, 1), groups=keep[40])

        c1 = [(keep[40], keep[41]), (keep[43], keep[44])]
        c2 = [(keep[41], keep[42]), (keep[44], keep[45])]
        c3 = [(keep[42], keep[43]), (keep[45], keep[46])]
        self.conv_5 = Residual(c1, c2, c3, num_block=2, groups=keep[40])

        self.conv_6_sep = ConvBlock(keep[46], keep[47], kernel=(1, 1),
                                    stride=(1, 1), padding=(0, 0))
        self.conv_6_dw = LinearBlock(keep[47], keep[48], groups=keep[48],
                                     kernel=conv6_kernel, stride=(1, 1), padding=(0, 0))
        self.conv_6_flatten = Flatten()

        self.linear = nn.Linear(512, embedding_size, bias=False) if embedding_size != 512 else nn.Identity()
        self.bn = nn.BatchNorm1d(embedding_size)
        self.drop = nn.Dropout(p=drop_p)
        self.prob = nn.Linear(embedding_size, num_classes, bias=False)

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        x = self.conv1(x)
        x = self.conv2_dw(x)
        x = self.conv_23(x)
        x = self.conv_3(x)
        x = self.conv_34(x)
        x = self.conv_4(x)
        x = self.conv_45(x)
        x = self.conv_5(x)
        x = self.conv_6_sep(x)
        x = self.conv_6_dw(x)
        x = self.conv_6_flatten(x)
        x = self.linear(x)
        x = self.bn(x)
        x = self.drop(x)
        x = self.prob(x)
        return x


class MiniFASNetSE(MiniFASNet):
    """MiniFASNet with Squeeze-and-Excitation in residual blocks."""
    def __init__(self, keep: list, embedding_size: int, conv6_kernel: tuple = (7, 7),
                 drop_p: float = 0.75, num_classes: int = 4, img_channel: int = 3):
        super().__init__(keep, embedding_size, conv6_kernel, drop_p, num_classes, img_channel)

        # Replace some residual blocks with SE versions
        c1 = [(keep[4], keep[5]), (keep[7], keep[8]), (keep[10], keep[11]), (keep[13], keep[14])]
        c2 = [(keep[5], keep[6]), (keep[8], keep[9]), (keep[11], keep[12]), (keep[14], keep[15])]
        c3 = [(keep[6], keep[7]), (keep[9], keep[10]), (keep[12], keep[13]), (keep[15], keep[16])]
        self.conv_3 = ResidualSE(c1, c2, c3, num_block=4, groups=keep[4])

        c1 = [(keep[19], keep[20]), (keep[22], keep[23]), (keep[25], keep[26]),
              (keep[28], keep[29]), (keep[31], keep[32]), (keep[34], keep[35])]
        c2 = [(keep[20], keep[21]), (keep[23], keep[24]), (keep[26], keep[27]),
              (keep[29], keep[30]), (keep[32], keep[33]), (keep[35], keep[36])]
        c3 = [(keep[21], keep[22]), (keep[24], keep[25]), (keep[27], keep[28]),
              (keep[30], keep[31]), (keep[33], keep[34]), (keep[36], keep[37])]
        self.conv_4 = ResidualSE(c1, c2, c3, num_block=6, groups=keep[19])

        c1 = [(keep[40], keep[41]), (keep[43], keep[44])]
        c2 = [(keep[41], keep[42]), (keep[44], keep[45])]
        c3 = [(keep[42], keep[43]), (keep[45], keep[46])]
        self.conv_5 = ResidualSE(c1, c2, c3, num_block=2, groups=keep[40])


# Channel configurations for different variants
KEEP_DICT = {
    '1.8M': [32, 32, 103, 103, 64, 13, 13, 64, 26, 26,
             64, 13, 13, 64, 52, 52, 64, 231, 231, 128,
             154, 154, 128, 52, 52, 128, 26, 26, 128, 52,
             52, 128, 26, 26, 128, 26, 26, 128, 308, 308,
             128, 26, 26, 128, 26, 26, 128, 512, 512],

    '1.8M_': [32, 32, 103, 103, 64, 13, 13, 64, 13, 13, 64, 13,
              13, 64, 13, 13, 64, 231, 231, 128, 231, 231, 128, 52,
              52, 128, 26, 26, 128, 77, 77, 128, 26, 26, 128, 26, 26,
              128, 308, 308, 128, 26, 26, 128, 26, 26, 128, 512, 512]
}


def MiniFASNetV1(embedding_size: int = 128, conv6_kernel: tuple = (7, 7),
                 drop_p: float = 0.2, num_classes: int = 3, img_channel: int = 3):
    """MiniFASNetV1 (~0.41M params, 80×80 input)."""
    return MiniFASNet(KEEP_DICT['1.8M'], embedding_size, conv6_kernel,
                      drop_p, num_classes, img_channel)


def MiniFASNetV2(embedding_size: int = 128, conv6_kernel: tuple = (7, 7),
                 drop_p: float = 0.2, num_classes: int = 3, img_channel: int = 3):
    """MiniFASNetV2 (~0.43M params, 80×80 input)."""
    return MiniFASNet(KEEP_DICT['1.8M_'], embedding_size, conv6_kernel,
                      drop_p, num_classes, img_channel)


def MiniFASNetV1SE(embedding_size: int = 128, conv6_kernel: tuple = (7, 7),
                   drop_p: float = 0.75, num_classes: int = 3, img_channel: int = 3):
    """MiniFASNetV1 with SE attention."""
    return MiniFASNetSE(KEEP_DICT['1.8M'], embedding_size, conv6_kernel,
                        drop_p, num_classes, img_channel)


def MiniFASNetV2SE(embedding_size: int = 128, conv6_kernel: tuple = (7, 7),
                   drop_p: float = 0.75, num_classes: int = 4, img_channel: int = 3):
    """MiniFASNetV2 with SE attention (most commonly used variant)."""
    return MiniFASNetSE(KEEP_DICT['1.8M_'], embedding_size, conv6_kernel,
                        drop_p, num_classes, img_channel)


__all__ = [
    'MiniFASNetV1',
    'MiniFASNetV2',
    'MiniFASNetV1SE',
    'MiniFASNetV2SE',
]