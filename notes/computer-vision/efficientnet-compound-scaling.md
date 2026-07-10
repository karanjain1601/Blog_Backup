---
title: "EfficientNet: Compound Scaling of CNNs"
slug: "efficientnet-compound-scaling"
description: "Neural architecture search baseline (EfficientNet-B0) and compound scaling — simultaneously scaling width, depth, and resolution with coefficient φ for efficient accuracy gains."
tags: ["computer-vision"]
topic: "computer-vision"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"EfficientNet (Tan \u0026 Le, 2019) introduced a principled approach to CNN scaling. Instead of arbitrarily increasing width, depth, or resolution, it uses Neural Architecture Search to find a baseline (B0) and then a compound scaling method to derive B1–B7, achieving state-of-the-art accuracy with far fewer parameters than prior models like ResNet or DenseNet."},{"type":"text","content":"The core insight is that width, depth, and resolution are not independent — scaling all three together in a fixed ratio, controlled by a single coefficient φ, produces better results than scaling any one dimension alone. EfficientNet-B7 achieves 84.3% top-1 on ImageNet using 8.4× fewer parameters than the best contemporary models."},{"type":"heading","level":2,"content":"EfficientNet-B0 Baseline"},{"type":"text","content":"The B0 baseline is found via Neural Architecture Search optimizing a multi-objective reward: ACC(m) × [FLOPS(m)/T]^w where w=−0.07. The search space includes MBConv blocks with squeeze-and-excitation, varying expansion ratios (1 or 6), kernel sizes (3×3 or 5×5), and number of layers per stage across 9 stages."},{"type":"text","content":"EfficientNet-B0 has 5.3M parameters and achieves 77.1% top-1 accuracy at 224×224 resolution. It uses 7 MBConv stages with varying channel widths (16→320) and expansion ratios, plus an initial stem conv and a final head with 1280 channels. This compact baseline is the foundation for all EfficientNet-B1 through B7 variants."},{"type":"heading","level":2,"content":"Compound Scaling Equations"},{"type":"text","content":"Compound scaling uses a single user-defined coefficient φ to uniformly scale network width, depth, and input resolution. This contrasts with ad-hoc scaling where practitioners independently tune each dimension. The method is grounded in the observation that larger inputs need deeper networks (more receptive field) and wider networks (more fine-grained features) to capture richer patterns."},{"type":"code","language":"python","content":"# Compound scaling coefficients (Tan \u0026 Le 2019)\n# Constraint: alpha * beta^2 * gamma^2 ≈ 2\n# Found via grid search on B0: alpha=1.2, beta=1.1, gamma=1.15\n# phi is the user-chosen scaling coefficient\n\nalpha, beta, gamma = 1.2, 1.1, 1.15\n\ndef compound_scale(phi):\n    depth_mult  = alpha ** phi        # scales number of layers\n    width_mult  = beta  ** phi        # scales channel widths\n    resolution  = gamma ** phi        # scales input resolution\n    # FLOP cost ≈ alpha * beta^2 * gamma^2 ≈ 2^phi\n    return depth_mult, width_mult, resolution"},{"type":"text","content":"The constraint α·β²·γ² ≈ 2 ensures that total FLOPs grow by approximately 2^φ with each unit increase in φ. Since FLOPs scale quadratically with resolution and width but linearly with depth, the squaring of β and γ accounts for this asymmetry and keeps compute budgets predictable across the entire EfficientNet scaling family."},{"type":"heading","level":2,"content":"MBConv Block"},{"type":"text","content":"The MBConv (Mobile Inverted Bottleneck Convolution) block is the core building block of EfficientNet, inherited from MobileNetV2 with an added Squeeze-and-Excitation (SE) module. Each block expands channels by a factor (1× or 6×), applies a depthwise separable convolution, applies channel attention via SE, then projects back to the output channel count."},{"type":"code","language":"python","content":"import torch.nn as nn\n\nclass MBConv(nn.Module):\n    def __init__(self, inp, oup, stride, expand_ratio, se_ratio=0.25):\n        super().__init__()\n        mid = inp * expand_ratio\n        self.skip = (stride == 1 and inp == oup)\n        self.conv = nn.Sequential(\n            nn.Conv2d(inp, mid, 1, bias=False), nn.BatchNorm2d(mid), nn.SiLU(),\n            nn.Conv2d(mid, mid, 3, stride, 1, groups=mid, bias=False), nn.BatchNorm2d(mid), nn.SiLU(),\n            SEBlock(mid, int(inp * se_ratio)),\n            nn.Conv2d(mid, oup, 1, bias=False), nn.BatchNorm2d(oup),\n        )\n    def forward(self, x):\n        return x + self.conv(x) if self.skip else self.conv(x)"},{"type":"text","content":"The SiLU (Swish) activation — f(x)=x·σ(x) — replaces ReLU throughout EfficientNet and contributes measurably to accuracy. The SE block performs global average pooling then two FC layers to produce per-channel attention weights in [0,1], letting the network recalibrate feature maps. Skip connections are applied when stride=1 and input/output channel counts match exactly."},{"type":"heading","level":2,"content":"Scaling from B0 to B7"},{"type":"text","content":"EfficientNet-B1 through B7 are obtained by applying compound scaling with φ=1 through 7 to the B0 baseline. Resolution increases from 224px (B0) to 600px (B7), while depth and width scale proportionally. Each increment of φ roughly doubles FLOPs but improves accuracy by 0.5–1.5% top-1, making the tradeoff curve far more favorable than scaling any single dimension alone."},{"type":"table","headers":["Model","Input Res","Width × Depth Mult","Top-1 %","Params (M)","FLOPs (G)"],"rows":[["B0","224","1.0 × 1.0","77.1","5.3","0.39"],["B1","240","1.0 × 1.1","79.1","7.8","0.70"],["B2","260","1.1 × 1.2","80.1","9.2","1.0"],["B3","300","1.2 × 1.4","81.6","12","1.8"],["B4","380","1.4 × 1.8","82.9","19","4.2"],["B5","456","1.6 × 2.2","83.6","30","9.9"],["B6","528","1.8 × 2.6","84.0","43","19"],["B7","600","2.0 × 3.1","84.3","66","37"]]},{"type":"text","content":"The Width × Depth multipliers are applied to B0 channel counts and layer counts per stage. Note that FLOPs grow super-linearly with model index — B7 uses ~95× more FLOPs than B0 for only 7.2% higher accuracy. This illustrates why B4 is often the practical ceiling, and why EfficientNetV2 redesigned large model stages to reduce this overhead."},{"type":"code","language":"python","content":"import torchvision.models as models\nimport torch.nn as nn\n\n# Load pretrained EfficientNet-B0; swap classifier for custom task\nmodel = models.efficientnet_b0(weights=models.EfficientNet_B0_Weights.IMAGENET1K_V1)\n\nnum_classes = 10\nin_features = model.classifier[1].in_features\nmodel.classifier[1] = nn.Linear(in_features, num_classes)\n\ntotal = sum(p.numel() for p in model.parameters())\ntrainable = sum(p.numel() for p in model.parameters() if p.requires_grad)\nprint(f\"Total params: {total/1e6:.2f}M | Trainable: {trainable/1e6:.2f}M\")"},{"type":"text","content":"When fine-tuning EfficientNet, freeze the stem and early stages and train only later stages plus the classifier head. This typically yields 90%+ of full fine-tune accuracy with 3–5× faster convergence. Use input sizes matching the variant (224 for B0, 380 for B4) and apply ImageNet normalization (mean=[0.485,0.456,0.406], std=[0.229,0.224,0.225]) consistently."},{"type":"code","language":"python","content":"from thop import profile\nimport torch, torchvision.models as M\n\nresults = {}\nfor name, cls, res in [\n    (\"B0\", M.efficientnet_b0, 224), (\"B1\", M.efficientnet_b1, 240),\n    (\"B2\", M.efficientnet_b2, 260), (\"B3\", M.efficientnet_b3, 300),\n    (\"B4\", M.efficientnet_b4, 380),\n]:\n    m = cls(weights=None)\n    x = torch.randn(1, 3, res, res)\n    flops, params = profile(m, inputs=(x,), verbose=False)\n    results[name] = {\"gflops\": flops/1e9, \"params_m\": params/1e6}\n    print(f\"{name} ({res}px): {flops/1e9:.2f} GFLOPs, {params/1e6:.1f}M params\")"},{"type":"text","content":"FLOPs roughly double with each step from B0 to B3, then increase more steeply as resolution grows. Plotting accuracy vs. FLOPs on a log scale shows EfficientNet on a Pareto frontier above ResNet and VGG at all compute points. For batch inference on V100, B0 achieves ~2500 images/sec while B4 achieves ~350 images/sec — a 7× throughput gap for 5.8% accuracy gain."},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"callout","variant":"tip","content":"EfficientNet-B4 (380px, 19M params) is usually the best tradeoff — B5+ give diminishing returns at much higher cost. Use B0 for edge/mobile and B4 for server inference."},{"type":"text","content":"EfficientNet showed that compound scaling beats ad-hoc single-axis scaling. The pattern generalizes: EfficientDet applies it to detection backbones, EfficientNetV2 swaps early MBConv6 for Fused-MBConv and adds progressive training. Core lesson: jointly optimizing width, depth, and resolution under a fixed compute budget yields models that transfer exceptionally well with minimal fine-tuning effort."}]"
---
# EfficientNet: Compound Scaling of CNNs

## Overview

EfficientNet (Tan & Le, 2019) introduced a principled approach to CNN scaling. Instead of arbitrarily increasing width, depth, or resolution, it uses Neural Architecture Search to find a baseline (B0) and then a compound scaling method to derive B1–B7, achieving state-of-the-art accuracy with far fewer parameters than prior models like ResNet or DenseNet.

The core insight is that width, depth, and resolution are not independent — scaling all three together in a fixed ratio, controlled by a single coefficient φ, produces better results than scaling any one dimension alone. EfficientNet-B7 achieves 84.3% top-1 on ImageNet using 8.4× fewer parameters than the best contemporary models.

## EfficientNet-B0 Baseline

The B0 baseline is found via Neural Architecture Search optimizing a multi-objective reward: ACC(m) × [FLOPS(m)/T]^w where w=−0.07. The search space includes MBConv blocks with squeeze-and-excitation, varying expansion ratios (1 or 6), kernel sizes (3×3 or 5×5), and number of layers per stage across 9 stages.

EfficientNet-B0 has 5.3M parameters and achieves 77.1% top-1 accuracy at 224×224 resolution. It uses 7 MBConv stages with varying channel widths (16→320) and expansion ratios, plus an initial stem conv and a final head with 1280 channels. This compact baseline is the foundation for all EfficientNet-B1 through B7 variants.

## Compound Scaling Equations

Compound scaling uses a single user-defined coefficient φ to uniformly scale network width, depth, and input resolution. This contrasts with ad-hoc scaling where practitioners independently tune each dimension. The method is grounded in the observation that larger inputs need deeper networks (more receptive field) and wider networks (more fine-grained features) to capture richer patterns.

```python
# Compound scaling coefficients (Tan & Le 2019)
# Constraint: alpha * beta^2 * gamma^2 ≈ 2
# Found via grid search on B0: alpha=1.2, beta=1.1, gamma=1.15
# phi is the user-chosen scaling coefficient

alpha, beta, gamma = 1.2, 1.1, 1.15

def compound_scale(phi):
    depth_mult  = alpha ** phi        # scales number of layers
    width_mult  = beta  ** phi        # scales channel widths
    resolution  = gamma ** phi        # scales input resolution
    # FLOP cost ≈ alpha * beta^2 * gamma^2 ≈ 2^phi
    return depth_mult, width_mult, resolution
```

The constraint α·β²·γ² ≈ 2 ensures that total FLOPs grow by approximately 2^φ with each unit increase in φ. Since FLOPs scale quadratically with resolution and width but linearly with depth, the squaring of β and γ accounts for this asymmetry and keeps compute budgets predictable across the entire EfficientNet scaling family.

## MBConv Block

The MBConv (Mobile Inverted Bottleneck Convolution) block is the core building block of EfficientNet, inherited from MobileNetV2 with an added Squeeze-and-Excitation (SE) module. Each block expands channels by a factor (1× or 6×), applies a depthwise separable convolution, applies channel attention via SE, then projects back to the output channel count.

```python
import torch.nn as nn

class MBConv(nn.Module):
    def __init__(self, inp, oup, stride, expand_ratio, se_ratio=0.25):
        super().__init__()
        mid = inp * expand_ratio
        self.skip = (stride == 1 and inp == oup)
        self.conv = nn.Sequential(
            nn.Conv2d(inp, mid, 1, bias=False), nn.BatchNorm2d(mid), nn.SiLU(),
            nn.Conv2d(mid, mid, 3, stride, 1, groups=mid, bias=False), nn.BatchNorm2d(mid), nn.SiLU(),
            SEBlock(mid, int(inp * se_ratio)),
            nn.Conv2d(mid, oup, 1, bias=False), nn.BatchNorm2d(oup),
        )
    def forward(self, x):
        return x + self.conv(x) if self.skip else self.conv(x)
```

The SiLU (Swish) activation — f(x)=x·σ(x) — replaces ReLU throughout EfficientNet and contributes measurably to accuracy. The SE block performs global average pooling then two FC layers to produce per-channel attention weights in [0,1], letting the network recalibrate feature maps. Skip connections are applied when stride=1 and input/output channel counts match exactly.

## Scaling from B0 to B7

EfficientNet-B1 through B7 are obtained by applying compound scaling with φ=1 through 7 to the B0 baseline. Resolution increases from 224px (B0) to 600px (B7), while depth and width scale proportionally. Each increment of φ roughly doubles FLOPs but improves accuracy by 0.5–1.5% top-1, making the tradeoff curve far more favorable than scaling any single dimension alone.

| Model | Input Res | Width × Depth Mult | Top-1 % | Params (M) | FLOPs (G) |
| --- | --- | --- | --- | --- | --- |
| B0 | 224 | 1.0 × 1.0 | 77.1 | 5.3 | 0.39 |
| B1 | 240 | 1.0 × 1.1 | 79.1 | 7.8 | 0.70 |
| B2 | 260 | 1.1 × 1.2 | 80.1 | 9.2 | 1.0 |
| B3 | 300 | 1.2 × 1.4 | 81.6 | 12 | 1.8 |
| B4 | 380 | 1.4 × 1.8 | 82.9 | 19 | 4.2 |
| B5 | 456 | 1.6 × 2.2 | 83.6 | 30 | 9.9 |
| B6 | 528 | 1.8 × 2.6 | 84.0 | 43 | 19 |
| B7 | 600 | 2.0 × 3.1 | 84.3 | 66 | 37 |

The Width × Depth multipliers are applied to B0 channel counts and layer counts per stage. Note that FLOPs grow super-linearly with model index — B7 uses ~95× more FLOPs than B0 for only 7.2% higher accuracy. This illustrates why B4 is often the practical ceiling, and why EfficientNetV2 redesigned large model stages to reduce this overhead.

```python
import torchvision.models as models
import torch.nn as nn

# Load pretrained EfficientNet-B0; swap classifier for custom task
model = models.efficientnet_b0(weights=models.EfficientNet_B0_Weights.IMAGENET1K_V1)

num_classes = 10
in_features = model.classifier[1].in_features
model.classifier[1] = nn.Linear(in_features, num_classes)

total = sum(p.numel() for p in model.parameters())
trainable = sum(p.numel() for p in model.parameters() if p.requires_grad)
print(f"Total params: {total/1e6:.2f}M | Trainable: {trainable/1e6:.2f}M")
```

When fine-tuning EfficientNet, freeze the stem and early stages and train only later stages plus the classifier head. This typically yields 90%+ of full fine-tune accuracy with 3–5× faster convergence. Use input sizes matching the variant (224 for B0, 380 for B4) and apply ImageNet normalization (mean=[0.485,0.456,0.406], std=[0.229,0.224,0.225]) consistently.

```python
from thop import profile
import torch, torchvision.models as M

results = {}
for name, cls, res in [
    ("B0", M.efficientnet_b0, 224), ("B1", M.efficientnet_b1, 240),
    ("B2", M.efficientnet_b2, 260), ("B3", M.efficientnet_b3, 300),
    ("B4", M.efficientnet_b4, 380),
]:
    m = cls(weights=None)
    x = torch.randn(1, 3, res, res)
    flops, params = profile(m, inputs=(x,), verbose=False)
    results[name] = {"gflops": flops/1e9, "params_m": params/1e6}
    print(f"{name} ({res}px): {flops/1e9:.2f} GFLOPs, {params/1e6:.1f}M params")
```

FLOPs roughly double with each step from B0 to B3, then increase more steeply as resolution grows. Plotting accuracy vs. FLOPs on a log scale shows EfficientNet on a Pareto frontier above ResNet and VGG at all compute points. For batch inference on V100, B0 achieves ~2500 images/sec while B4 achieves ~350 images/sec — a 7× throughput gap for 5.8% accuracy gain.

## Key Takeaways

> **tip**: EfficientNet-B4 (380px, 19M params) is usually the best tradeoff — B5+ give diminishing returns at much higher cost. Use B0 for edge/mobile and B4 for server inference.

EfficientNet showed that compound scaling beats ad-hoc single-axis scaling. The pattern generalizes: EfficientDet applies it to detection backbones, EfficientNetV2 swaps early MBConv6 for Fused-MBConv and adds progressive training. Core lesson: jointly optimizing width, depth, and resolution under a fixed compute budget yields models that transfer exceptionally well with minimal fine-tuning effort.

