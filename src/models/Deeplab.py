"""
Deeplab model.
"""

import torch.nn as nn
from typing import Any, Optional, Sequence
import torch.nn.functional as F
import torch

class DeeplabModel(nn.Module):
    def __init__(self, backbone, head_dim):
        super(DeeplabModel, self).__init__()
        self.backbone = backbone.backbone
        #
        # Add reconstruction head
        #
        self.reconstruction_head = DeepLabHead(head_dim, 3)  # 960 for mobilenet, 2048 for resnet
        #
        # activation function
        #
        self.activation = nn.Sigmoid()
        
    def forward(self, input):
        # extract features from backbone
        x = self.backbone(input)['out']
        # reconstruction
        x = self.reconstruction_head(x)
        x = F.interpolate(x, size=input.shape[-2:], mode="bilinear", align_corners=False)
        # activation
        x = self.activation(x)
        return x
    

"""
From https://github.com/pytorch/vision/blob/main/torchvision/models/segmentation/deeplabv3.py
"""
class DeepLabHead(nn.Sequential):
    def __init__(self, in_channels: int, num_classes: int, atrous_rates: Sequence[int] = (12, 24, 36)) -> None:
        super().__init__(
            ASPP(in_channels, atrous_rates),
            nn.Conv2d(256, 256, 3, padding=1, bias=False),
            nn.BatchNorm2d(256),
            nn.ReLU(),
            nn.Conv2d(256, num_classes, 1),
        )


class ASPPConv(nn.Sequential):
    def __init__(self, in_channels: int, out_channels: int, dilation: int) -> None:
        modules = [
            nn.Conv2d(in_channels, out_channels, 3, padding=dilation, dilation=dilation, bias=False),
            nn.BatchNorm2d(out_channels),
            nn.ReLU(),
        ]
        super().__init__(*modules)


class ASPPPooling(nn.Sequential):
    def __init__(self, in_channels: int, out_channels: int) -> None:
        super().__init__(
            nn.AdaptiveAvgPool2d(1),
            nn.Conv2d(in_channels, out_channels, 1, bias=False),
            nn.BatchNorm2d(out_channels),
            nn.ReLU(),
        )

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        size = x.shape[-2:]
        for mod in self:
            x = mod(x)
        return F.interpolate(x, size=size, mode="bilinear", align_corners=False)


class ASPP(nn.Module):
    def __init__(self, in_channels: int, atrous_rates: Sequence[int], out_channels: int = 256) -> None:
        super().__init__()
        modules = []
        modules.append(
            nn.Sequential(nn.Conv2d(in_channels, out_channels, 1, bias=False), nn.BatchNorm2d(out_channels), nn.ReLU())
        )

        rates = tuple(atrous_rates)
        for rate in rates:
            modules.append(ASPPConv(in_channels, out_channels, rate))

        # modules.append(ASPPPooling(in_channels, out_channels)) ## --> removed

        self.convs = nn.ModuleList(modules)

        self.project = nn.Sequential(
            nn.Conv2d(len(self.convs) * out_channels, out_channels, 1, bias=False),
            nn.BatchNorm2d(out_channels),
            nn.ReLU(),
            nn.Dropout(0.5),
        )

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        _res = []
        for conv in self.convs:
            _res.append(conv(x))
        res = torch.cat(_res, dim=1)
        return self.project(res)