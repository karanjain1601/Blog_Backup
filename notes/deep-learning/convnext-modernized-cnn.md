---
title: "ConvNeXt — Modernized CNN Matching ViT Performance"
slug: "convnext-modernized-cnn"
description: "ConvNeXt (Liu et al. 2022): systematically modernize ResNet-50 using Swin Transformer design choices, step by step. Covers patchify stem, inverted bottleneck, depthwise 7×7, LayerNorm, GELU, ConvNeXt V2 with FCMAE, and the conclusion that training recipe + architecture together explain Transformer gains."
tags: ["deep-learning", "cnns", "architectures"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"ConvNeXt (Liu et al., CVPR 2022) asked: can a purely convolutional network match Swin Transformer accuracy if we adopt the same modern design principles? The answer is yes. Starting from ResNet-50, the paper applies six targeted changes — all inspired by the Swin Transformer — and recovers a CNN that matches or exceeds Swin-T at every scale. This result has important implications: the gains of Vision Transformers come partly from training recipe and design choices, not purely from attention mechanisms."},{"type":"heading","level":2,"content":"Motivation — Transformers vs CNNs"},{"type":"text","content":"By 2021, Swin Transformer had surpassed ResNets on ImageNet, COCO, and ADE20K with hierarchical attention and shifted windows. The common interpretation was that self-attention is inherently superior to convolution. ConvNeXt challenges this interpretation by asking whether the accuracy gap exists because of attention, or because of the many other design differences: training recipe (AdamW, cosine schedule, extensive augmentation), macro structure (stage ratios, stems, downsampling), and micro design (normalization, activations, kernel size). The modernization roadmap answers this question systematically."},{"type":"heading","level":2,"content":"The Modernization Road Map"},{"type":"text","content":"The paper starts with ResNet-50 (76.1% top-1) and adds Swin-inspired changes one at a time, measuring accuracy after each. The order is: (1) training recipe (AdamW, cosine schedule, Mixup, CutMix, RandAugment, Label Smoothing) -\u003e 78.8%; then architecture changes starting from macro design down to micro design. Each step is ablated independently, making the paper an unusually clean analysis of what drives accuracy."},{"type":"list","ordered":true,"items":["Patchify stem: replace 7×7+MaxPool with 4×4 stride-4 Conv (like ViT) — fewer forward passes, less aggressive spatial downsampling at the start.","Stage ratio 3:3:9:3: mirror Swin-T block distribution (fewer blocks in early stages, more in stage 3).","ResNeXt-ify: replace 3×3 conv with depthwise 3×3 conv + increase channel width (inverted bottleneck style).","Inverted bottleneck: expand channels 4× in the middle layer (like Transformer MLP) rather than compressing.","Larger kernel: increase depthwise conv from 3×3 to 7×7 (like Swin\u0027s 7×7 attention window).","Micro design: replace BatchNorm with LayerNorm, replace ReLU with GELU, reduce activations to one per block, separate downsampling layers between stages."]},{"type":"callout","variant":"info","title":"Training Recipe vs Architecture","content":"Simply applying AdamW + cosine schedule + modern augmentation (Mixup, CutMix, RandAugment, Label Smoothing) to ResNet-50 raises accuracy from 76.1% to 78.8% — a 2.7% gain with zero architectural change. This result reveals that a large fraction of the Transformer accuracy advantage is attributable to training recipe, not architecture. The remaining architectural changes add a further 3.3% on top."},{"type":"heading","level":2,"content":"ConvNeXt Block Design"},{"type":"text","content":"The ConvNeXt block is structurally similar to a Transformer block: depthwise 7×7 conv (analogous to attention over a 7×7 window) followed by a 4× inverted bottleneck MLP (pointwise expand -\u003e GELU -\u003e pointwise contract). Normalization uses LayerNorm applied on the channel axis (after permuting to B, H, W, C). There is one GELU activation per block (not one per linear layer as in ResNet). A layer scale parameter γ (initialized to 1e-6) is optionally applied before the residual addition. The depthwise conv operates across the spatial dimensions while the pointwise layers mix channels — exactly as in Transformers where attention mixes positions and MLP mixes channels."},{"type":"heading","level":2,"content":"Code Examples"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass ConvNeXtBlock(nn.Module):\n    \"\"\"ConvNeXt block: depthwise 7x7 -\u003e LN -\u003e pointwise expand -\u003e GELU -\u003e pointwise project.\"\"\"\n    def __init__(self, dim, mlp_ratio=4, layer_scale_init=1e-6):\n        super().__init__()\n        self.dwconv  = nn.Conv2d(dim, dim, kernel_size=7, padding=3, groups=dim)\n        self.norm    = nn.LayerNorm(dim, eps=1e-6)\n        self.pwconv1 = nn.Linear(dim, mlp_ratio * dim)\n        self.act     = nn.GELU()\n        self.pwconv2 = nn.Linear(mlp_ratio * dim, dim)\n        self.gamma   = nn.Parameter(layer_scale_init * torch.ones(dim))\n\n    def forward(self, x):\n        residual = x\n        x = self.dwconv(x)               # (B, C, H, W) -- depthwise spatial mixing\n        x = x.permute(0, 2, 3, 1)       # (B, H, W, C) for LayerNorm\n        x = self.norm(x)\n        x = self.pwconv1(x)              # expand: C -\u003e 4C\n        x = self.act(x)                  # single GELU (not one per layer)\n        x = self.pwconv2(x)              # contract: 4C -\u003e C\n        x = self.gamma * x\n        x = x.permute(0, 3, 1, 2)       # back to (B, C, H, W)\n        return residual + x\n\nblock = ConvNeXtBlock(dim=96)\nx = torch.randn(2, 96, 56, 56)\nprint(f\"Input:  {x.shape}\")\nprint(f\"Output: {block(x).shape}\")\nprint(f\"Params: {sum(p.numel() for p in block.parameters()):,}\")"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass PatchifyStem(nn.Module):\n    \"\"\"Replace 7x7+MaxPool with a single 4x4 stride-4 conv (like ViT patchify).\"\"\"\n    def __init__(self, in_ch=3, out_ch=96):\n        super().__init__()\n        self.proj = nn.Conv2d(in_ch, out_ch, kernel_size=4, stride=4)\n        self.norm = nn.LayerNorm(out_ch, eps=1e-6)\n\n    def forward(self, x):\n        x = self.proj(x)                 # (B, C, H/4, W/4)\n        x = x.permute(0, 2, 3, 1)       # (B, H/4, W/4, C)\n        x = self.norm(x)\n        return x.permute(0, 3, 1, 2)    # (B, C, H/4, W/4)\n\nclass DownsampleLayer(nn.Module):\n    \"\"\"Separate downsampling between stages: LN -\u003e 2x2 stride-2 conv.\"\"\"\n    def __init__(self, in_ch, out_ch):\n        super().__init__()\n        self.norm = nn.LayerNorm(in_ch, eps=1e-6)\n        self.conv = nn.Conv2d(in_ch, out_ch, kernel_size=2, stride=2)\n\n    def forward(self, x):\n        x = x.permute(0, 2, 3, 1)\n        x = self.norm(x)\n        x = x.permute(0, 3, 1, 2)\n        return self.conv(x)\n\nstem = PatchifyStem(3, 96)\ndown = DownsampleLayer(96, 192)\nx = torch.randn(2, 3, 224, 224)\nh = stem(x)\nprint(f\"After patchify stem: {h.shape}\")   # (2, 96, 56, 56)\nprint(f\"After downsample:    {down(h).shape}\")  # (2, 192, 28, 28)\nprint(\"No MaxPool: smoother spatial downsampling vs ResNet stem\")"},{"type":"code","language":"python","content":"import torch\nfrom torchvision import models\n\nconvnext = models.convnext_tiny(weights=models.ConvNeXt_Tiny_Weights.IMAGENET1K_V1)\nswin_t   = models.swin_t(weights=models.Swin_T_Weights.IMAGENET1K_V1)\n\ndef count_params(model):\n    return sum(p.numel() for p in model.parameters()) / 1e6\n\nmodels_info = [\n    (\u0027ConvNeXt-Tiny\u0027, convnext, 82.1),\n    (\u0027Swin-T\u0027,        swin_t,   81.3),\n]\n\nprint(f\"{\u0027Model\u0027:\u003c20} {\u0027Params (M)\u0027:\u003e12} {\u0027Official Top-1\u0027:\u003e15} {\u0027Attention?\u0027:\u003e12}\")\nprint(\u0027-\u0027 * 62)\nfor name, m, acc in models_info:\n    print(f\"{name:\u003c20} {count_params(m):\u003e12.1f} {acc:\u003e14.1f}% {\u0027No\u0027 if \u0027ConvNeXt\u0027 in name else \u0027Yes\u0027:\u003e12}\")\n\nprint()\nx = torch.randn(1, 3, 224, 224)\nconvnext.eval(); swin_t.eval()\nwith torch.no_grad():\n    _ = convnext(x)\nprint(\"ConvNeXt-Tiny matches Swin-T with no self-attention, simpler inductive bias\")\nprint(\"Key: Transformer advantages come from training recipe + design, not attention alone\")"},{"type":"code","language":"python","content":"# Ablation: accuracy gains from each ConvNeXt modernization step\n# Reproduced from Table 1 in \u0027A ConvNet for the 2020s\u0027 (Liu et al., 2022)\nsteps = [\n    (\"Baseline ResNet-50\",                       76.1),\n    (\"+ Modern training recipe (AdamW, augs)\",   78.8),\n    (\"+ Stage ratio 3:3:9:3\",                    79.4),\n    (\"+ Patchify stem (4x4 s4)\",                 79.5),\n    (\"+ Depthwise + inverted bottleneck\",        80.6),\n    (\"+ Large kernel 7x7 depthwise\",             80.6),\n    (\"+ LN, GELU, one activation/block\",         81.3),\n    (\"+ Separate downsampling layers\",           82.1),\n]\n\nprint(f\"{\u0027Modernization Step\u0027:\u003c45} {\u0027Top-1\u0027:\u003e6} {\u0027Delta\u0027:\u003e7}\")\nprint(\u0027-\u0027 * 62)\nprev = None\nfor name, acc in steps:\n    delta = f\"+{acc - prev:.1f}%\" if prev is not None else \"base\"\n    print(f\"{name:\u003c45} {acc:\u003e5.1f}% {delta:\u003e7}\")\n    prev = acc\n\ntotal_gain = steps[-1][1] - steps[0][1]\nprint(f\"\\nTotal gain: +{total_gain:.1f}% (ResNet-50 -\u003e ConvNeXt-T)\")\nprint(\"Training recipe alone: +2.7%; architecture changes: +3.3%\")"},{"type":"heading","level":2,"content":"ConvNeXt V2 — FCMAE and GRN"},{"type":"text","content":"ConvNeXt V2 (Woo et al., 2023) adds two advances: (1) FCMAE (Fully Convolutional Masked Autoencoder) pretraining — a masked autoencoder where the encoder is a ConvNeXt backbone and the decoder reconstructs masked patches, similar to MAE but for CNNs; (2) GRN (Global Response Normalization) — a new normalization layer inserted in the pointwise MLP that normalizes across the spatial dimension (not channels), preventing feature collapse in the masked autoencoder setting. ConvNeXt V2-H achieves 88.9% on ImageNet with FCMAE pretraining, competitive with the best ViT variants."},{"type":"heading","level":2,"content":"ResNet Modernization Steps"},{"type":"table","headers":["Change","Cumulative Top-1 (%)","Delta","Inspired by"],"rows":[["Baseline ResNet-50","76.1","—","He et al. 2016"],["Modern training recipe","78.8","+2.7%","DeiT training strategy"],["Stage ratio 3:3:9:3","79.4","+0.6%","Swin-T stage distribution"],["Patchify stem 4×4 s4","79.5","+0.1%","ViT non-overlapping patches"],["Depthwise + inverted bottleneck","80.6","+1.1%","MobileNetV2 / Swin MLP"],["7×7 depthwise conv","80.6","+0.0%","Swin 7×7 attention window"],["LN + GELU + 1 activation/block","81.3","+0.7%","Transformer micro design"],["Separate downsampling layers","82.1","+0.8%","Swin patch merging"]]},{"type":"heading","level":2,"content":"ConvNeXt vs Vision Transformer"},{"type":"text","content":"ConvNeXt has a simpler inductive bias than Swin Transformer: translation equivariance from convolution, but no shifted-window partitioning or relative position encodings. Inference is faster at high resolution because convolution scales as O(HW) while windowed attention scales as O(HW × window_size²). ConvNeXt is also easier to implement (no custom CUDA kernels for shifted windows). Swin Transformer has slightly stronger performance on dense prediction tasks (detection, segmentation) because its hierarchical attention captures longer-range dependencies. For most practical applications, ConvNeXt is the simpler and more deployable choice."},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"ConvNeXt demonstrates that the gap between Transformers and CNNs in the 2020-2022 period was largely a gap in training recipe and design philosophy, not a fundamental limitation of the convolution operation. A carefully designed CNN, trained with modern techniques, matches Swin Transformer at every scale. The choice between ConvNeXt and a ViT-based model should be driven by deployment constraints (ConvNeXt is simpler and faster), pretraining availability, and whether the specific task benefits from global attention (very long-range dependencies) or local convolution (local texture and structure)."}]"
---
# ConvNeXt — Modernized CNN Matching ViT Performance

ConvNeXt (Liu et al., CVPR 2022) asked: can a purely convolutional network match Swin Transformer accuracy if we adopt the same modern design principles? The answer is yes. Starting from ResNet-50, the paper applies six targeted changes — all inspired by the Swin Transformer — and recovers a CNN that matches or exceeds Swin-T at every scale. This result has important implications: the gains of Vision Transformers come partly from training recipe and design choices, not purely from attention mechanisms.

## Motivation — Transformers vs CNNs

By 2021, Swin Transformer had surpassed ResNets on ImageNet, COCO, and ADE20K with hierarchical attention and shifted windows. The common interpretation was that self-attention is inherently superior to convolution. ConvNeXt challenges this interpretation by asking whether the accuracy gap exists because of attention, or because of the many other design differences: training recipe (AdamW, cosine schedule, extensive augmentation), macro structure (stage ratios, stems, downsampling), and micro design (normalization, activations, kernel size). The modernization roadmap answers this question systematically.

## The Modernization Road Map

The paper starts with ResNet-50 (76.1% top-1) and adds Swin-inspired changes one at a time, measuring accuracy after each. The order is: (1) training recipe (AdamW, cosine schedule, Mixup, CutMix, RandAugment, Label Smoothing) -> 78.8%; then architecture changes starting from macro design down to micro design. Each step is ablated independently, making the paper an unusually clean analysis of what drives accuracy.

1. Patchify stem: replace 7×7+MaxPool with 4×4 stride-4 Conv (like ViT) — fewer forward passes, less aggressive spatial downsampling at the start.
2. Stage ratio 3:3:9:3: mirror Swin-T block distribution (fewer blocks in early stages, more in stage 3).
3. ResNeXt-ify: replace 3×3 conv with depthwise 3×3 conv + increase channel width (inverted bottleneck style).
4. Inverted bottleneck: expand channels 4× in the middle layer (like Transformer MLP) rather than compressing.
5. Larger kernel: increase depthwise conv from 3×3 to 7×7 (like Swin's 7×7 attention window).
6. Micro design: replace BatchNorm with LayerNorm, replace ReLU with GELU, reduce activations to one per block, separate downsampling layers between stages.

> **Training Recipe vs Architecture**: Simply applying AdamW + cosine schedule + modern augmentation (Mixup, CutMix, RandAugment, Label Smoothing) to ResNet-50 raises accuracy from 76.1% to 78.8% — a 2.7% gain with zero architectural change. This result reveals that a large fraction of the Transformer accuracy advantage is attributable to training recipe, not architecture. The remaining architectural changes add a further 3.3% on top.

## ConvNeXt Block Design

The ConvNeXt block is structurally similar to a Transformer block: depthwise 7×7 conv (analogous to attention over a 7×7 window) followed by a 4× inverted bottleneck MLP (pointwise expand -> GELU -> pointwise contract). Normalization uses LayerNorm applied on the channel axis (after permuting to B, H, W, C). There is one GELU activation per block (not one per linear layer as in ResNet). A layer scale parameter γ (initialized to 1e-6) is optionally applied before the residual addition. The depthwise conv operates across the spatial dimensions while the pointwise layers mix channels — exactly as in Transformers where attention mixes positions and MLP mixes channels.

## Code Examples

```python
import torch
import torch.nn as nn

class ConvNeXtBlock(nn.Module):
    """ConvNeXt block: depthwise 7x7 -> LN -> pointwise expand -> GELU -> pointwise project."""
    def __init__(self, dim, mlp_ratio=4, layer_scale_init=1e-6):
        super().__init__()
        self.dwconv  = nn.Conv2d(dim, dim, kernel_size=7, padding=3, groups=dim)
        self.norm    = nn.LayerNorm(dim, eps=1e-6)
        self.pwconv1 = nn.Linear(dim, mlp_ratio * dim)
        self.act     = nn.GELU()
        self.pwconv2 = nn.Linear(mlp_ratio * dim, dim)
        self.gamma   = nn.Parameter(layer_scale_init * torch.ones(dim))

    def forward(self, x):
        residual = x
        x = self.dwconv(x)               # (B, C, H, W) -- depthwise spatial mixing
        x = x.permute(0, 2, 3, 1)       # (B, H, W, C) for LayerNorm
        x = self.norm(x)
        x = self.pwconv1(x)              # expand: C -> 4C
        x = self.act(x)                  # single GELU (not one per layer)
        x = self.pwconv2(x)              # contract: 4C -> C
        x = self.gamma * x
        x = x.permute(0, 3, 1, 2)       # back to (B, C, H, W)
        return residual + x

block = ConvNeXtBlock(dim=96)
x = torch.randn(2, 96, 56, 56)
print(f"Input:  {x.shape}")
print(f"Output: {block(x).shape}")
print(f"Params: {sum(p.numel() for p in block.parameters()):,}")
```

```python
import torch
import torch.nn as nn

class PatchifyStem(nn.Module):
    """Replace 7x7+MaxPool with a single 4x4 stride-4 conv (like ViT patchify)."""
    def __init__(self, in_ch=3, out_ch=96):
        super().__init__()
        self.proj = nn.Conv2d(in_ch, out_ch, kernel_size=4, stride=4)
        self.norm = nn.LayerNorm(out_ch, eps=1e-6)

    def forward(self, x):
        x = self.proj(x)                 # (B, C, H/4, W/4)
        x = x.permute(0, 2, 3, 1)       # (B, H/4, W/4, C)
        x = self.norm(x)
        return x.permute(0, 3, 1, 2)    # (B, C, H/4, W/4)

class DownsampleLayer(nn.Module):
    """Separate downsampling between stages: LN -> 2x2 stride-2 conv."""
    def __init__(self, in_ch, out_ch):
        super().__init__()
        self.norm = nn.LayerNorm(in_ch, eps=1e-6)
        self.conv = nn.Conv2d(in_ch, out_ch, kernel_size=2, stride=2)

    def forward(self, x):
        x = x.permute(0, 2, 3, 1)
        x = self.norm(x)
        x = x.permute(0, 3, 1, 2)
        return self.conv(x)

stem = PatchifyStem(3, 96)
down = DownsampleLayer(96, 192)
x = torch.randn(2, 3, 224, 224)
h = stem(x)
print(f"After patchify stem: {h.shape}")   # (2, 96, 56, 56)
print(f"After downsample:    {down(h).shape}")  # (2, 192, 28, 28)
print("No MaxPool: smoother spatial downsampling vs ResNet stem")
```

```python
import torch
from torchvision import models

convnext = models.convnext_tiny(weights=models.ConvNeXt_Tiny_Weights.IMAGENET1K_V1)
swin_t   = models.swin_t(weights=models.Swin_T_Weights.IMAGENET1K_V1)

def count_params(model):
    return sum(p.numel() for p in model.parameters()) / 1e6

models_info = [
    ('ConvNeXt-Tiny', convnext, 82.1),
    ('Swin-T',        swin_t,   81.3),
]

print(f"{'Model':<20} {'Params (M)':>12} {'Official Top-1':>15} {'Attention?':>12}")
print('-' * 62)
for name, m, acc in models_info:
    print(f"{name:<20} {count_params(m):>12.1f} {acc:>14.1f}% {'No' if 'ConvNeXt' in name else 'Yes':>12}")

print()
x = torch.randn(1, 3, 224, 224)
convnext.eval(); swin_t.eval()
with torch.no_grad():
    _ = convnext(x)
print("ConvNeXt-Tiny matches Swin-T with no self-attention, simpler inductive bias")
print("Key: Transformer advantages come from training recipe + design, not attention alone")
```

```python
# Ablation: accuracy gains from each ConvNeXt modernization step
# Reproduced from Table 1 in 'A ConvNet for the 2020s' (Liu et al., 2022)
steps = [
    ("Baseline ResNet-50",                       76.1),
    ("+ Modern training recipe (AdamW, augs)",   78.8),
    ("+ Stage ratio 3:3:9:3",                    79.4),
    ("+ Patchify stem (4x4 s4)",                 79.5),
    ("+ Depthwise + inverted bottleneck",        80.6),
    ("+ Large kernel 7x7 depthwise",             80.6),
    ("+ LN, GELU, one activation/block",         81.3),
    ("+ Separate downsampling layers",           82.1),
]

print(f"{'Modernization Step':<45} {'Top-1':>6} {'Delta':>7}")
print('-' * 62)
prev = None
for name, acc in steps:
    delta = f"+{acc - prev:.1f}%" if prev is not None else "base"
    print(f"{name:<45} {acc:>5.1f}% {delta:>7}")
    prev = acc

total_gain = steps[-1][1] - steps[0][1]
print(f"\nTotal gain: +{total_gain:.1f}% (ResNet-50 -> ConvNeXt-T)")
print("Training recipe alone: +2.7%; architecture changes: +3.3%")
```

## ConvNeXt V2 — FCMAE and GRN

ConvNeXt V2 (Woo et al., 2023) adds two advances: (1) FCMAE (Fully Convolutional Masked Autoencoder) pretraining — a masked autoencoder where the encoder is a ConvNeXt backbone and the decoder reconstructs masked patches, similar to MAE but for CNNs; (2) GRN (Global Response Normalization) — a new normalization layer inserted in the pointwise MLP that normalizes across the spatial dimension (not channels), preventing feature collapse in the masked autoencoder setting. ConvNeXt V2-H achieves 88.9% on ImageNet with FCMAE pretraining, competitive with the best ViT variants.

## ResNet Modernization Steps

| Change | Cumulative Top-1 (%) | Delta | Inspired by |
| --- | --- | --- | --- |
| Baseline ResNet-50 | 76.1 | — | He et al. 2016 |
| Modern training recipe | 78.8 | +2.7% | DeiT training strategy |
| Stage ratio 3:3:9:3 | 79.4 | +0.6% | Swin-T stage distribution |
| Patchify stem 4×4 s4 | 79.5 | +0.1% | ViT non-overlapping patches |
| Depthwise + inverted bottleneck | 80.6 | +1.1% | MobileNetV2 / Swin MLP |
| 7×7 depthwise conv | 80.6 | +0.0% | Swin 7×7 attention window |
| LN + GELU + 1 activation/block | 81.3 | +0.7% | Transformer micro design |
| Separate downsampling layers | 82.1 | +0.8% | Swin patch merging |

## ConvNeXt vs Vision Transformer

ConvNeXt has a simpler inductive bias than Swin Transformer: translation equivariance from convolution, but no shifted-window partitioning or relative position encodings. Inference is faster at high resolution because convolution scales as O(HW) while windowed attention scales as O(HW × window_size²). ConvNeXt is also easier to implement (no custom CUDA kernels for shifted windows). Swin Transformer has slightly stronger performance on dense prediction tasks (detection, segmentation) because its hierarchical attention captures longer-range dependencies. For most practical applications, ConvNeXt is the simpler and more deployable choice.

## Key Takeaways

ConvNeXt demonstrates that the gap between Transformers and CNNs in the 2020-2022 period was largely a gap in training recipe and design philosophy, not a fundamental limitation of the convolution operation. A carefully designed CNN, trained with modern techniques, matches Swin Transformer at every scale. The choice between ConvNeXt and a ViT-based model should be driven by deployment constraints (ConvNeXt is simpler and faster), pretraining availability, and whether the specific task benefits from global attention (very long-range dependencies) or local convolution (local texture and structure).

