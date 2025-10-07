"""
Residual architectures for CIFAR-scale inputs.
"""

from __future__ import annotations

import torch
import torch.nn as nn

__all__ = ["ResNetCIFAR"]


class _BasicBlock(nn.Module):
    """
    Minimal residual block for CIFAR-style ResNet variants.
    """

    expansion = 1

    def __init__(self, in_planes: int, planes: int, stride: int = 1) -> None:
        super().__init__()
        self.conv1 = nn.Conv2d(in_planes, planes, 3, stride=stride, padding=1, bias=False)
        self.bn1 = nn.BatchNorm2d(planes)
        self.conv2 = nn.Conv2d(planes, planes, 3, padding=1, bias=False)
        self.bn2 = nn.BatchNorm2d(planes)
        self.shortcut = nn.Identity()
        if stride != 1 or in_planes != planes:
            self.shortcut = nn.Sequential(
                nn.Conv2d(in_planes, planes, 1, stride=stride, bias=False),
                nn.BatchNorm2d(planes),
            )

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        out = torch.relu(self.bn1(self.conv1(x)))
        out = self.bn2(self.conv2(out))
        out += self.shortcut(x)
        return torch.relu(out)


class ResNetCIFAR(nn.Module):
    """
    Residual network adapted from ResNet-18 for CIFAR-10 scale inputs.

    Parameters
    ----------
    num_blocks : tuple[int, int, int, int], optional
        Number of blocks per stage, by default ``(2, 2, 2, 2)``.
    num_classes : int, optional
        Number of output classes, by default 10.
    """

    def __init__(self, num_blocks=(2, 2, 2, 2), num_classes: int = 10) -> None:
        super().__init__()
        self.in_planes = 64
        self.conv1 = nn.Conv2d(3, 64, 3, 1, 1, bias=False)
        self.bn1 = nn.BatchNorm2d(64)
        self.layer1 = self._make_layer(64, num_blocks[0], 1)
        self.layer2 = self._make_layer(128, num_blocks[1], 2)
        self.layer3 = self._make_layer(256, num_blocks[2], 2)
        self.layer4 = self._make_layer(512, num_blocks[3], 2)
        self.avgpool = nn.AdaptiveAvgPool2d(1)
        self.fc = nn.Linear(512, num_classes)

    def _make_layer(self, planes: int, n: int, stride: int) -> nn.Sequential:
        layers = []
        strides = [stride] + [1] * (n - 1)
        for current_stride in strides:
            layers.append(_BasicBlock(self.in_planes, planes, current_stride))
            self.in_planes = planes * _BasicBlock.expansion
        return nn.Sequential(*layers)

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        out = torch.relu(self.bn1(self.conv1(x)))
        out = self.layer1(out)
        out = self.layer2(out)
        out = self.layer3(out)
        out = self.layer4(out)
        out = self.avgpool(out)
        out = torch.flatten(out, 1)
        return self.fc(out)
