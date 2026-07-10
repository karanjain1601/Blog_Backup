---
title: "ConvNeXt: Modernizing CNNs to Match Vision Transformers"
slug: "convnext-modernized-cnn"
description: "How ConvNeXt incrementally modernizes ResNet-50 by adopting ViT training techniques — depthwise 7×7 convolutions, inverted bottleneck, GELU, and layer scale — achieving accuracy parity with Swin Transformer."
tags: ["computer-vision"]
topic: "computer-vision"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"ConvNeXt (2022, Liu et al., Meta AI) asks a simple question: can a plain CNN match Swin Transformer when trained with the same recipe? Starting from ResNet-50, the authors apply ViT-era improvements one at a time — macro design, depthwise convolutions, inverted bottleneck, larger kernels, GELU, fewer activations — measuring accuracy at each step to isolate each contribution."},{"type":"text","content":"The resulting ConvNeXt family (T/S/B/L/XL) spans 29–350 M parameters. ConvNeXt-T matches Swin-T at 82.1% ImageNet-1K top-1 with ~27% higher throughput, while ConvNeXt-L reaches 84.3%. The architecture is purely convolutional — no self-attention — yet competes on classification, object detection, and semantic segmentation benchmarks."},{"type":"text","content":"Published as \u0027A ConvNet for the 2020s\u0027 at CVPR 2022, ConvNeXt challenges the narrative that transformers are inherently superior to CNNs. It shows that with equalized training conditions — AdamW, cosine decay, extended schedules, and modern augmentation — a well-designed convolutional network can match or exceed hierarchical vision transformers."},{"type":"heading","level":2,"content":"Modernization Roadmap"},{"type":"text","content":"The authors begin with ResNet-50 at 76.1% top-1 and apply the ViT training recipe: AdamW optimizer, cosine schedule with warmup, 300 training epochs, Mixup, CutMix, RandAugment, and Label Smoothing. This alone raises accuracy to 78.8% — a 2.7-point gain with no architectural change, revealing that much of the CNN-vs-transformer gap stems from training procedures."},{"type":"text","content":"Architectural changes applied sequentially: stage ratio (3,4,6,3)→(3,3,9,3) → 79.4%; patchify stem → 79.5%; depthwise separable layers → 80.5%; inverted bottleneck (4× expand) → 80.6%; 7×7 depthwise kernel → 80.6%; GELU + single activation per block → 81.3%; separate downsampling layers → 82.0%. Each step is small; compounded they close the gap."},{"type":"heading","level":2,"content":"ConvNeXt Block Design"},{"type":"text","content":"The ConvNeXt block mirrors a transformer block: depthwise 7×7 conv for large-kernel spatial mixing, then a pointwise expand-4× linear layer, GELU, and a pointwise projection back. Unlike ResNet\u0027s bottleneck, the depthwise conv runs at full channel width before expansion. Batch Norm is swapped for Layer Norm, and a single activation per block matches transformer convention."},{"type":"code","language":"python","content":"import torch, torch.nn as nn\nclass ConvNeXtBlock(nn.Module):\n    def __init__(self, dim, ls_init=1e-6):\n        super().__init__()\n        self.dw = nn.Conv2d(dim, dim, 7, padding=3, groups=dim)\n        self.norm = nn.LayerNorm(dim)\n        self.pw1 = nn.Linear(dim, 4 * dim)\n        self.act = nn.GELU()\n        self.pw2 = nn.Linear(4 * dim, dim)\n        self.gamma = nn.Parameter(ls_init * torch.ones(dim))\n    def forward(self, x):\n        r = x\n        x = self.dw(x).permute(0, 2, 3, 1)  # NCHW-\u003eNHWC\n        x = self.pw2(self.act(self.pw1(self.norm(x))))\n        return r + (self.gamma * x).permute(0, 3, 1, 2)"},{"type":"text","content":"Layer scale is a per-channel learnable scalar γ initialized to a tiny value (1e-6). It multiplies the block output before adding the residual, zeroing new blocks at initialization so training starts as if the network were shallow. This prevents gradient explosion in large ConvNeXt models and is critical for stable training at ConvNeXt-B scale and above."},{"type":"code","language":"python","content":"import torch, torch.nn as nn\n\nclass LayerScale(nn.Module):\n    def __init__(self, dim, init=1e-6):\n        super().__init__()\n        self.gamma = nn.Parameter(init * torch.ones(dim))\n    def forward(self, x):\n        # x: (B, H, W, C) -- NHWC layout\n        return self.gamma * x  # broadcasts over B, H, W\n\n# Gradient effect: grad w.r.t. block params scaled by gamma\n# gamma ~= 0 at init -\u003e new blocks contribute near-zero\n# -\u003e network behaves like a shallower model at start of training"},{"type":"code","language":"python","content":"import torch.nn as nn\n\n# Patchify stem: replaces ResNet\u0027s 7x7 conv + MaxPool\n# Produces non-overlapping 4x4 patches (stride = kernel_size)\nstem = nn.Sequential(\n    nn.Conv2d(3, 96, kernel_size=4, stride=4),  # C_out=96 for ConvNeXt-T\n    nn.LayerNorm(96, eps=1e-6),\n)\n# Input : (B, 3, 224, 224)\n# Output: (B, 96, 56, 56)\n# No overlap between patches; stride == kernel_size\n# LayerNorm normalises over channel dim (applied after NHWC permute)"},{"type":"heading","level":2,"content":"Macro Architecture"},{"type":"text","content":"ConvNeXt uses a 4-stage hierarchy: spatial resolution halves and channels double at each stage boundary. Channel counts are (96, 192, 384, 768) for ConvNeXt-T. Downsampling between stages uses a separate LayerNorm + 2×2 stride-2 conv, decoupling spatial reduction from feature transformation. The stage ratio shifts to (3,3,9,3), concentrating compute in stage 3 like Swin."},{"type":"table","headers":["Architecture","Top-1 %","Params (M)","FLOPs (G)","Throughput (img/s)"],"rows":[["ResNet-50","76.1","25","4.1","1226"],["Swin-T","81.3","28","4.5","755"],["ConvNeXt-T","82.1","29","4.5","960"],["ConvNeXt-S","83.1","50","8.7","592"],["ConvNeXt-B","83.8","89","15.4","373"],["ConvNeXt-L","84.3","198","34.4","205"]]},{"type":"text","content":"ConvNeXt\u0027s separate downsampling layers contrast with ResNet, where the first block in each stage simultaneously halves resolution and doubles channels. This clean separation makes each component\u0027s role explicit. The 4-stage feature maps at strides (4, 8, 16, 32) plug directly into FPN for detection and UPerNet for segmentation without architectural modification."},{"type":"heading","level":2,"content":"ConvNeXt vs Swin"},{"type":"text","content":"ConvNeXt-T and Swin-T are a fair comparison at ~29 M parameters and ~4.5 GFLOPs. ConvNeXt-T achieves 82.1% vs Swin-T\u0027s 81.3% on ImageNet-1K, with ~27% higher throughput (960 vs 755 img/s on A100). ConvNeXt avoids shifted window operations and relative position biases, giving it simpler CUDA kernels and better compatibility with deep learning compilers."},{"type":"code","language":"python","content":"import timm, torch, time\n\ndevice = torch.device(\"cuda\" if torch.cuda.is_available() else \"cpu\")\npairs = [(\"convnext_tiny\", 82.1), (\"swin_tiny_patch4_window7_224\", 81.3)]\nfor name, top1 in pairs:\n    m = timm.create_model(name, pretrained=False).eval().to(device)\n    x = torch.randn(32, 3, 224, 224, device=device)\n    with torch.no_grad():\n        for _ in range(3): m(x)          # warmup\n        t0 = time.perf_counter()\n        for _ in range(20): m(x)\n        fps = 32 * 20 / (time.perf_counter() - t0)\n    print(f\"{name}: top-1={top1}%  throughput={fps:.0f} img/s\")"},{"type":"text","content":"Beyond throughput, ConvNeXt supports arbitrary input resolutions without retraining, integrates cleanly with torchvision and timm, and requires no specialized CUDA extensions. On downstream tasks, ConvNeXt-B with Cascade Mask R-CNN achieves 54.0 box AP on COCO vs Swin-B 51.9, and with UPerNet on ADE20K reaches 52.1 mIoU vs Swin-B 51.6."},{"type":"callout","variant":"info","content":"ConvNeXt shows the accuracy gap between CNNs and transformers was largely a training recipe gap — with AdamW, cosine schedule, Mixup, CutMix, and RandAugment, a pure CNN matches Swin Transformer."},{"type":"text","content":"At scale, ConvNeXt-XL fine-tuned on ImageNet-22K reaches 87.8% top-1 at 384² resolution. ConvNeXt-L pre-trained on ImageNet-22K scores 86.6% at 224². These results confirm that the architectural improvements transfer across scales and pretraining datasets, making ConvNeXt a strong backbone for visual recognition tasks requiring large-scale pretraining."},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"ConvNeXt proves that locality and translation equivariance, combined with ViT training recipes, can match attention-based models. Key changes: depthwise 7×7 conv for large receptive field, inverted bottleneck (4× expansion), GELU + single activation per block, Layer Norm replacing Batch Norm, separate downsampling layers, and layer scale for deep model stability."},{"type":"text","content":"For practitioners, ConvNeXt-T is the default drop-in for ResNet-50, offering +6 points top-1 accuracy at similar FLOPs. ConvNeXt-B/L suit higher-compute scenarios. On mobile or edge hardware, depthwise convolutions may underperform on some accelerators — benchmark both before committing. Use timm for pretrained weights and reliable fine-tuning baselines."}]"
---
# ConvNeXt: Modernizing CNNs to Match Vision Transformers

## Overview

ConvNeXt (2022, Liu et al., Meta AI) asks a simple question: can a plain CNN match Swin Transformer when trained with the same recipe? Starting from ResNet-50, the authors apply ViT-era improvements one at a time — macro design, depthwise convolutions, inverted bottleneck, larger kernels, GELU, fewer activations — measuring accuracy at each step to isolate each contribution.

The resulting ConvNeXt family (T/S/B/L/XL) spans 29–350 M parameters. ConvNeXt-T matches Swin-T at 82.1% ImageNet-1K top-1 with ~27% higher throughput, while ConvNeXt-L reaches 84.3%. The architecture is purely convolutional — no self-attention — yet competes on classification, object detection, and semantic segmentation benchmarks.

Published as 'A ConvNet for the 2020s' at CVPR 2022, ConvNeXt challenges the narrative that transformers are inherently superior to CNNs. It shows that with equalized training conditions — AdamW, cosine decay, extended schedules, and modern augmentation — a well-designed convolutional network can match or exceed hierarchical vision transformers.

## Modernization Roadmap

The authors begin with ResNet-50 at 76.1% top-1 and apply the ViT training recipe: AdamW optimizer, cosine schedule with warmup, 300 training epochs, Mixup, CutMix, RandAugment, and Label Smoothing. This alone raises accuracy to 78.8% — a 2.7-point gain with no architectural change, revealing that much of the CNN-vs-transformer gap stems from training procedures.

Architectural changes applied sequentially: stage ratio (3,4,6,3)→(3,3,9,3) → 79.4%; patchify stem → 79.5%; depthwise separable layers → 80.5%; inverted bottleneck (4× expand) → 80.6%; 7×7 depthwise kernel → 80.6%; GELU + single activation per block → 81.3%; separate downsampling layers → 82.0%. Each step is small; compounded they close the gap.

## ConvNeXt Block Design

The ConvNeXt block mirrors a transformer block: depthwise 7×7 conv for large-kernel spatial mixing, then a pointwise expand-4× linear layer, GELU, and a pointwise projection back. Unlike ResNet's bottleneck, the depthwise conv runs at full channel width before expansion. Batch Norm is swapped for Layer Norm, and a single activation per block matches transformer convention.

```python
import torch, torch.nn as nn
class ConvNeXtBlock(nn.Module):
    def __init__(self, dim, ls_init=1e-6):
        super().__init__()
        self.dw = nn.Conv2d(dim, dim, 7, padding=3, groups=dim)
        self.norm = nn.LayerNorm(dim)
        self.pw1 = nn.Linear(dim, 4 * dim)
        self.act = nn.GELU()
        self.pw2 = nn.Linear(4 * dim, dim)
        self.gamma = nn.Parameter(ls_init * torch.ones(dim))
    def forward(self, x):
        r = x
        x = self.dw(x).permute(0, 2, 3, 1)  # NCHW->NHWC
        x = self.pw2(self.act(self.pw1(self.norm(x))))
        return r + (self.gamma * x).permute(0, 3, 1, 2)
```

Layer scale is a per-channel learnable scalar γ initialized to a tiny value (1e-6). It multiplies the block output before adding the residual, zeroing new blocks at initialization so training starts as if the network were shallow. This prevents gradient explosion in large ConvNeXt models and is critical for stable training at ConvNeXt-B scale and above.

```python
import torch, torch.nn as nn

class LayerScale(nn.Module):
    def __init__(self, dim, init=1e-6):
        super().__init__()
        self.gamma = nn.Parameter(init * torch.ones(dim))
    def forward(self, x):
        # x: (B, H, W, C) -- NHWC layout
        return self.gamma * x  # broadcasts over B, H, W

# Gradient effect: grad w.r.t. block params scaled by gamma
# gamma ~= 0 at init -> new blocks contribute near-zero
# -> network behaves like a shallower model at start of training
```

```python
import torch.nn as nn

# Patchify stem: replaces ResNet's 7x7 conv + MaxPool
# Produces non-overlapping 4x4 patches (stride = kernel_size)
stem = nn.Sequential(
    nn.Conv2d(3, 96, kernel_size=4, stride=4),  # C_out=96 for ConvNeXt-T
    nn.LayerNorm(96, eps=1e-6),
)
# Input : (B, 3, 224, 224)
# Output: (B, 96, 56, 56)
# No overlap between patches; stride == kernel_size
# LayerNorm normalises over channel dim (applied after NHWC permute)
```

## Macro Architecture

ConvNeXt uses a 4-stage hierarchy: spatial resolution halves and channels double at each stage boundary. Channel counts are (96, 192, 384, 768) for ConvNeXt-T. Downsampling between stages uses a separate LayerNorm + 2×2 stride-2 conv, decoupling spatial reduction from feature transformation. The stage ratio shifts to (3,3,9,3), concentrating compute in stage 3 like Swin.

| Architecture | Top-1 % | Params (M) | FLOPs (G) | Throughput (img/s) |
| --- | --- | --- | --- | --- |
| ResNet-50 | 76.1 | 25 | 4.1 | 1226 |
| Swin-T | 81.3 | 28 | 4.5 | 755 |
| ConvNeXt-T | 82.1 | 29 | 4.5 | 960 |
| ConvNeXt-S | 83.1 | 50 | 8.7 | 592 |
| ConvNeXt-B | 83.8 | 89 | 15.4 | 373 |
| ConvNeXt-L | 84.3 | 198 | 34.4 | 205 |

ConvNeXt's separate downsampling layers contrast with ResNet, where the first block in each stage simultaneously halves resolution and doubles channels. This clean separation makes each component's role explicit. The 4-stage feature maps at strides (4, 8, 16, 32) plug directly into FPN for detection and UPerNet for segmentation without architectural modification.

## ConvNeXt vs Swin

ConvNeXt-T and Swin-T are a fair comparison at ~29 M parameters and ~4.5 GFLOPs. ConvNeXt-T achieves 82.1% vs Swin-T's 81.3% on ImageNet-1K, with ~27% higher throughput (960 vs 755 img/s on A100). ConvNeXt avoids shifted window operations and relative position biases, giving it simpler CUDA kernels and better compatibility with deep learning compilers.

```python
import timm, torch, time

device = torch.device("cuda" if torch.cuda.is_available() else "cpu")
pairs = [("convnext_tiny", 82.1), ("swin_tiny_patch4_window7_224", 81.3)]
for name, top1 in pairs:
    m = timm.create_model(name, pretrained=False).eval().to(device)
    x = torch.randn(32, 3, 224, 224, device=device)
    with torch.no_grad():
        for _ in range(3): m(x)          # warmup
        t0 = time.perf_counter()
        for _ in range(20): m(x)
        fps = 32 * 20 / (time.perf_counter() - t0)
    print(f"{name}: top-1={top1}%  throughput={fps:.0f} img/s")
```

Beyond throughput, ConvNeXt supports arbitrary input resolutions without retraining, integrates cleanly with torchvision and timm, and requires no specialized CUDA extensions. On downstream tasks, ConvNeXt-B with Cascade Mask R-CNN achieves 54.0 box AP on COCO vs Swin-B 51.9, and with UPerNet on ADE20K reaches 52.1 mIoU vs Swin-B 51.6.

> **info**: ConvNeXt shows the accuracy gap between CNNs and transformers was largely a training recipe gap — with AdamW, cosine schedule, Mixup, CutMix, and RandAugment, a pure CNN matches Swin Transformer.

At scale, ConvNeXt-XL fine-tuned on ImageNet-22K reaches 87.8% top-1 at 384² resolution. ConvNeXt-L pre-trained on ImageNet-22K scores 86.6% at 224². These results confirm that the architectural improvements transfer across scales and pretraining datasets, making ConvNeXt a strong backbone for visual recognition tasks requiring large-scale pretraining.

## Key Takeaways

ConvNeXt proves that locality and translation equivariance, combined with ViT training recipes, can match attention-based models. Key changes: depthwise 7×7 conv for large receptive field, inverted bottleneck (4× expansion), GELU + single activation per block, Layer Norm replacing Batch Norm, separate downsampling layers, and layer scale for deep model stability.

For practitioners, ConvNeXt-T is the default drop-in for ResNet-50, offering +6 points top-1 accuracy at similar FLOPs. ConvNeXt-B/L suit higher-compute scenarios. On mobile or edge hardware, depthwise convolutions may underperform on some accelerators — benchmark both before committing. Use timm for pretrained weights and reliable fine-tuning baselines.

