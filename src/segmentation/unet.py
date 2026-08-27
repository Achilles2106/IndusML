import torch
import torch.nn as nn


class DoubleConv(nn.Module):
    """(Conv -> BatchNorm -> ReLU) twice"""
    def __init__(self, in_channels, out_channels):
        super().__init__()
        self.block = nn.Sequential(
            nn.Conv2d(in_channels, out_channels, kernel_size=3, padding=1),
            nn.BatchNorm2d(out_channels),
            nn.ReLU(inplace=True),
            nn.Conv2d(out_channels, out_channels, kernel_size=3, padding=1),
            nn.BatchNorm2d(out_channels),
            nn.ReLU(inplace=True),
        )

    def forward(self, x):
        return self.block(x)


class UNet(nn.Module):
    def __init__(self, in_channels=3, out_channels=1, base_channels=32):
        super().__init__()

        # Encoder
        self.enc1 = DoubleConv(in_channels, base_channels)          # 256 -> 256
        self.pool1 = nn.MaxPool2d(2)                                 # 256 -> 128

        self.enc2 = DoubleConv(base_channels, base_channels * 2)     # 128
        self.pool2 = nn.MaxPool2d(2)                                 # 128 -> 64

        self.enc3 = DoubleConv(base_channels * 2, base_channels * 4)  # 64
        self.pool3 = nn.MaxPool2d(2)                                  # 64 -> 32

        self.enc4 = DoubleConv(base_channels * 4, base_channels * 8)  # 32
        self.pool4 = nn.MaxPool2d(2)                                  # 32 -> 16

        # Bottleneck
        self.bottleneck = DoubleConv(base_channels * 8, base_channels * 16)  # 16

        # Decoder
        self.up4 = nn.ConvTranspose2d(base_channels * 16, base_channels * 8, kernel_size=2, stride=2)  # 16 -> 32
        self.dec4 = DoubleConv(base_channels * 16, base_channels * 8)  # after concat with enc4

        self.up3 = nn.ConvTranspose2d(base_channels * 8, base_channels * 4, kernel_size=2, stride=2)  # 32 -> 64
        self.dec3 = DoubleConv(base_channels * 8, base_channels * 4)

        self.up2 = nn.ConvTranspose2d(base_channels * 4, base_channels * 2, kernel_size=2, stride=2)  # 64 -> 128
        self.dec2 = DoubleConv(base_channels * 4, base_channels * 2)

        self.up1 = nn.ConvTranspose2d(base_channels * 2, base_channels, kernel_size=2, stride=2)  # 128 -> 256
        self.dec1 = DoubleConv(base_channels * 2, base_channels)

        # Final output layer -> 1 channel (defect probability map), raw logits
        self.final_conv = nn.Conv2d(base_channels, out_channels, kernel_size=1)

    def forward(self, x):
        # Encoder path (save outputs for skip connections)
        e1 = self.enc1(x)
        p1 = self.pool1(e1)

        e2 = self.enc2(p1)
        p2 = self.pool2(e2)

        e3 = self.enc3(p2)
        p3 = self.pool3(e3)

        e4 = self.enc4(p3)
        p4 = self.pool4(e4)

        # Bottleneck
        b = self.bottleneck(p4)

        # Decoder path (concat skip connections)
        d4 = self.up4(b)
        d4 = torch.cat([d4, e4], dim=1)
        d4 = self.dec4(d4)

        d3 = self.up3(d4)
        d3 = torch.cat([d3, e3], dim=1)
        d3 = self.dec3(d3)

        d2 = self.up2(d3)
        d2 = torch.cat([d2, e2], dim=1)
        d2 = self.dec2(d2)

        d1 = self.up1(d2)
        d1 = torch.cat([d1, e1], dim=1)
        d1 = self.dec1(d1)

        out = self.final_conv(d1)  # raw logits, shape [B, 1, 256, 256]
        return out