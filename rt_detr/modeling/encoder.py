from typing import List

import torch
import torch.nn as nn
from detectron2.layers import ShapeSpec
from fvcore.nn import c2_xavier_fill

from .utils import get_activation, get_norm


class DilatedEncoder(nn.Module):
    """
    Dilated Encoder for RTDETR.

    This module contains two types of components:
        - the original FPN lateral convolution layer and fpn convolution layer,
          which are 1x1 conv + 3x3 conv
        - the dilated residual block
    """

    def __init__(self, cfg, input_shape: List[ShapeSpec]):
        super(DilatedEncoder, self).__init__()
        # fmt: off
        self.backbone_level = cfg.MODEL.RTDETR.ENCODER.BACKBONE_LEVEL
        self.in_channels = cfg.MODEL.RTDETR.ENCODER.IN_CHANNELS
        self.encoder_channels = cfg.MODEL.RTDETR.ENCODER.NUM_CHANNELS
        self.block_mid_channels = cfg.MODEL.RTDETR.ENCODER.BLOCK_MID_CHANNELS
        self.num_residual_blocks = cfg.MODEL.RTDETR.ENCODER.NUM_RESIDUAL_BLOCKS
        self.block_dilations = cfg.MODEL.RTDETR.ENCODER.BLOCK_DILATIONS
        self.norm_type = cfg.MODEL.RTDETR.ENCODER.NORM
        self.act_type = cfg.MODEL.RTDETR.ENCODER.ACTIVATION
        self.use_se = cfg.MODEL.RTDETR.ENCODER.USE_SE
        self.freeze_at = cfg.MODEL.RTDETR.ENCODER.FREEZE_AT
        # fmt: on
        assert input_shape[self.backbone_level].channels == self.in_channels
        assert len(self.block_dilations) == self.num_residual_blocks

        # init
        self._init_layers()
        self._init_weight()

    def _init_layers(self):
        self.lateral_conv = nn.Conv2d(
            self.in_channels, self.encoder_channels, kernel_size=1
        )
        self.lateral_norm = get_norm(self.norm_type, self.encoder_channels)
        self.fpn_conv = nn.Conv2d(
            self.encoder_channels, self.encoder_channels, kernel_size=3, padding=1
        )
        self.fpn_norm = get_norm(self.norm_type, self.encoder_channels)
        encoder_blocks = []
        for i in range(self.num_residual_blocks):
            dilation = self.block_dilations[i]
            encoder_blocks.append(
                Bottleneck(
                    self.encoder_channels,
                    self.block_mid_channels,
                    dilation=dilation,
                    norm_type=self.norm_type,
                    act_type=self.act_type,
                    use_se=self.use_se,
                )
            )
        self.dilated_encoder_blocks = nn.Sequential(*encoder_blocks)

        self._freeze_encoder()

    def _init_weight(self):
        if self.freeze_at:
            ValueError(
                "Cannot re-initialise encoder weights when freezing is enabled. " \
                "Please set FREEZE_AT to 0 in config to allow encoder learning and re-initialisation."
            )

        c2_xavier_fill(self.lateral_conv)
        c2_xavier_fill(self.fpn_conv)
        for m in [self.lateral_norm, self.fpn_norm]:
            nn.init.constant_(m.weight, 1)
            nn.init.constant_(m.bias, 0)
        for m in self.dilated_encoder_blocks.modules():
            if isinstance(m, nn.Conv2d):
                nn.init.normal_(m.weight, mean=0, std=0.01)
                if hasattr(m, "bias") and m.bias is not None:
                    nn.init.constant_(m.bias, 0)

            if isinstance(m, (nn.GroupNorm, nn.BatchNorm2d, nn.SyncBatchNorm)):
                nn.init.constant_(m.weight, 1)
                nn.init.constant_(m.bias, 0)

    def _freeze_encoder(self):
        if self.freeze_at == False or self.freeze_at == 0:
            pass  # No freezing, allow all parameters to be updated during training

        elif self.freeze_at == True or self.freeze_at == -1:
            # Freeze entire encoder
            self.lateral_conv.requires_grad_(False)
            if self.lateral_norm is not None:
                self.lateral_norm.requires_grad_(False)
            self.fpn_conv.requires_grad_(False)
            if self.fpn_norm is not None:
                self.fpn_norm.requires_grad_(False)
            self.dilated_encoder_blocks.requires_grad_(False)

        else:
            if self.freeze_at == True or self.freeze_at >= len(self.dilated_encoder_blocks):
                self.dilated_encoder_blocks.requires_grad_(False)  # Freeze all dilated encoder blocks
            else:    
                for param in self.dilated_encoder_blocks[self.freeze_at:].parameters():
                    param.requires_grad = False

    def forward(self, feature: torch.Tensor) -> torch.Tensor:
        out = self.lateral_norm(self.lateral_conv(feature))
        out = self.fpn_norm(self.fpn_conv(out))
        return self.dilated_encoder_blocks(out)


class Bottleneck(nn.Module):
    def __init__(
        self,
        in_channels: int = 512,
        mid_channels: int = 128,
        dilation: int = 1,
        norm_type: str = "BN",
        act_type: str = "ReLU",
        use_se: bool = False,
    ):
        super(Bottleneck, self).__init__()
        self.use_se = use_se
        self.conv1 = nn.Sequential(
            nn.Conv2d(in_channels, mid_channels, kernel_size=1, padding=0),
            get_norm(norm_type, mid_channels),
            get_activation(act_type),
        )
        if self.use_se:
            self.se1 = SEBlock(mid_channels)
        self.conv2 = nn.Sequential(
            nn.Conv2d(
                mid_channels,
                mid_channels,
                kernel_size=3,
                padding=dilation,
                dilation=dilation,
            ),
            get_norm(norm_type, mid_channels),
            get_activation(act_type),
        )
        if self.use_se:
            self.se2 = SEBlock(mid_channels)
        self.conv3 = nn.Sequential(
            nn.Conv2d(mid_channels, in_channels, kernel_size=1, padding=0),
            get_norm(norm_type, in_channels),
            get_activation(act_type),
        )
        if self.use_se:
            self.se3 = SEBlock(in_channels)

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        identity = x
        out = self.conv1(x)
        if self.use_se:
            out = self.se1(out)
        out = self.conv2(out)
        if self.use_se:
            out = self.se2(out)
        out = self.conv3(out)
        if self.use_se:
            out = self.se3(out)
        out = out + identity
        return out


class SEBlock(nn.Module):
    def __init__(self, channel, reduction=16):
        super(SEBlock, self).__init__()
        self.avg_pool = nn.AdaptiveAvgPool2d(1)
        self.fc = nn.Sequential(
            nn.Linear(channel, channel // reduction, bias=False),
            nn.ReLU(inplace=True),
            nn.Linear(channel // reduction, channel, bias=False),
            nn.Sigmoid(),
        )

    def forward(self, x):
        b, c, _, _ = x.size()
        y = self.avg_pool(x).view(b, c)
        y = self.fc(y).view(b, c, 1, 1)
        return x * y.expand_as(x)
