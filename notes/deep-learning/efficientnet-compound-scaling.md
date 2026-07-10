---
title: "EfficientNet — Compound Scaling and NAS Design"
slug: "efficientnet-compound-scaling"
description: "EfficientNet (Tan & Le 2019): systematically scale depth, width, and resolution together using compound coefficient φ. Covers NAS-derived B0 baseline, MBConv with Squeeze-Excitation, compound scaling B0→B7, EfficientNetV2 progressive learning, and EfficientDet."
tags: ["deep-learning", "cnns", "architectures"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"EfficientNet (Tan \u0026 Le, NeurIPS 2019) revolutionized CNN design by asking a fundamental question: given a fixed compute budget, how should you scale network depth, width, and input resolution together? The answer — compound scaling — yields a family of models from B0 (5.3M params) to B7 (66M params) that outperformed every prior CNN at the time of publication. EfficientNet models are derived from a NAS-found B0 baseline and systematically scaled, making them both principled and highly efficient."},{"type":"heading","level":2,"content":"What Is EfficientNet?"},{"type":"text","content":"EfficientNet is a family of CNNs whose architecture and scaling strategy were co-designed by Neural Architecture Search (NAS). The NAS process optimized for accuracy and FLOPs simultaneously on a small proxy task, yielding the B0 baseline architecture. B0 uses Mobile Inverted Bottleneck Convolutions (MBConv) with Squeeze-Excitation attention as the core block. From B0, the B1–B7 variants are obtained by increasing a compound coefficient φ that jointly scales depth, width, and resolution. At equal accuracy, EfficientNet used up to 8.4× fewer parameters and 16× fewer FLOPs than the best competing models such as GPipe."},{"type":"heading","level":2,"content":"Compound Scaling — Depth, Width, and Resolution"},{"type":"text","content":"Naively scaling any single dimension (depth only, width only, or resolution only) quickly hits diminishing returns. Tan \u0026 Le propose scaling all three simultaneously using a compound coefficient φ. Baseline multipliers α (depth), β (width), γ (resolution) are found by grid search at φ=1 subject to the constraint α·β²·γ²≈2, so that doubling φ roughly doubles FLOPs. The scaled model at coefficient φ has: depth d = α^φ, width w = β^φ, resolution r = γ^φ. For EfficientNet, α=1.2, β=1.1, γ=1.15 — giving α·β²·γ² ≈ 1.2×1.21×1.3225 ≈ 1.92 ≈ 2. This means one unit of φ costs approximately 2× the FLOPs of the previous step."},{"type":"heading","level":2,"content":"Squeeze-Excitation Blocks"},{"type":"text","content":"The SE block (Hu et al., 2018) reweights channels adaptively using global context. It has three steps: (1) Squeeze — global average pool across spatial dimensions, yielding a (B, C) descriptor; (2) Excitation — two fully-connected layers with ReLU and Sigmoid, forming a bottleneck C → C/r → C that learns channel importance weights; (3) Scale — multiply the feature map channel-wise by the learned weights ∈ (0, 1). The SE block adds approximately 2·C²/r parameters (r=4 typical), a small overhead that consistently provides +1–2% accuracy. EfficientNet places one SE block inside every MBConv block."},{"type":"callout","variant":"insight","title":"Why SE Blocks Work","content":"The SE block is a lightweight channel attention mechanism. The global average pool squeezes spatial information into a channel descriptor; the FC bottleneck excites informative channels and suppresses less useful ones. Because the learned weights depend on global image content (not local patches), the network can selectively suppress background-activated channels even when those channels fire strongly locally. SE adds \u003c1% parameter overhead while consistently improving accuracy."},{"type":"heading","level":2,"content":"MBConv — Mobile Inverted Bottleneck"},{"type":"text","content":"MBConv (also used in MobileNetV2 and V3) is an inverted bottleneck: channels are first expanded (by factor expand_ratio=6) then reduced — opposite to the classic bottleneck. EfficientNet\u0027s MBConv block: (1) pointwise expansion conv (in → in×expand), (2) depthwise 3×3 or 5×5 conv with stride, (3) Squeeze-Excitation, (4) pointwise projection conv (in×expand → out), (5) skip connection when stride=1 and in_channels=out_channels. The depthwise separable structure dramatically reduces FLOPs versus standard convolution: a k×k depthwise + 1×1 pointwise uses k² + C_out times fewer FLOPs than a k×k standard conv."},{"type":"heading","level":2,"content":"Code Examples"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass SqueezeExcitation(nn.Module):\n    \"\"\"SE block: global avg pool -\u003e FC -\u003e ReLU -\u003e FC -\u003e Sigmoid -\u003e channel scaling.\"\"\"\n    def __init__(self, in_channels, reduction_ratio=4):\n        super().__init__()\n        reduced = max(1, in_channels // reduction_ratio)\n        self.gap  = nn.AdaptiveAvgPool2d(1)\n        self.fc1  = nn.Linear(in_channels, reduced)\n        self.fc2  = nn.Linear(reduced, in_channels)\n        self.relu = nn.ReLU(inplace=True)\n        self.sig  = nn.Sigmoid()\n\n    def forward(self, x):\n        s = self.gap(x).flatten(1)           # (B, C): squeeze\n        s = self.relu(self.fc1(s))           # FC -\u003e ReLU\n        s = self.sig(self.fc2(s))            # FC -\u003e Sigmoid: weights in (0,1)\n        return x * s.unsqueeze(-1).unsqueeze(-1)  # channel-wise scale\n\nse = SqueezeExcitation(64, reduction_ratio=4)\nx  = torch.randn(2, 64, 28, 28)\nout = se(x)\nprint(f\"Input:  {x.shape}\")\nprint(f\"Output: {out.shape}  (same shape, channels re-weighted)\")\nprint(f\"SE params: {sum(p.numel() for p in se.parameters()):,}\")\nprint(\"reduction_ratio=4 -\u003e bottleneck: 64-\u003e16-\u003e64; small overhead, large gain\")"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass MBConv(nn.Module):\n    \"\"\"Mobile Inverted Bottleneck + SE block (EfficientNet core building block).\"\"\"\n    def __init__(self, in_ch, out_ch, expand=6, stride=1, se_ratio=0.25):\n        super().__init__()\n        mid, se_ch = in_ch * expand, max(1, int(in_ch * se_ratio))\n        self.skip  = (stride == 1 and in_ch == out_ch)\n        self.expand = nn.Sequential(nn.Conv2d(in_ch, mid, 1, bias=False),\n                                    nn.BatchNorm2d(mid), nn.SiLU())\n        self.dw = nn.Sequential(\n            nn.Conv2d(mid, mid, 3, stride=stride, padding=1, groups=mid, bias=False),\n            nn.BatchNorm2d(mid), nn.SiLU())\n        self.se_pool = nn.AdaptiveAvgPool2d(1)\n        self.se_fc   = nn.Sequential(nn.Linear(mid, se_ch), nn.ReLU(),\n                                     nn.Linear(se_ch, mid), nn.Sigmoid())\n        self.proj = nn.Sequential(nn.Conv2d(mid, out_ch, 1, bias=False),\n                                  nn.BatchNorm2d(out_ch))\n\n    def forward(self, x):\n        h = self.expand(x)\n        h = self.dw(h)\n        h = h * self.se_fc(self.se_pool(h).flatten(1)).view(h.size(0), h.size(1), 1, 1)\n        h = self.proj(h)\n        return h + x if self.skip else h\n\nm = MBConv(32, 32, expand=6, stride=1)\nx = torch.randn(2, 32, 28, 28)\nprint(f\"Output: {m(x).shape}, Params: {sum(p.numel() for p in m.parameters()):,}\")\nprint(\"Pattern: expand(pw) -\u003e depthwise -\u003e SE -\u003e project(pw) + skip\")"},{"type":"code","language":"python","content":"# EfficientNet compound scaling: depth=alpha^phi, width=beta^phi, resolution=gamma^phi\nALPHA, BETA, GAMMA = 1.2, 1.1, 1.15\nB0_PARAMS_M, B0_FLOPS_B, B0_RES = 5.3, 0.39, 224\n\nprint(f\"Constraint: alpha*beta**2*gamma**2 = {ALPHA * BETA**2 * GAMMA**2:.4f} (target ~2)\")\n\ndef compound_scale(phi):\n    d = ALPHA ** phi\n    w = BETA  ** phi\n    r = GAMMA ** phi\n    return (d, w, r,\n            B0_PARAMS_M * d * w**2,\n            B0_FLOPS_B  * d * w**2 * r**2,\n            int(B0_RES * r / 32) * 32)\n\nnames = [\u0027B0\u0027, \u0027B1\u0027, \u0027B2\u0027, \u0027B3\u0027, \u0027B4\u0027, \u0027B5\u0027, \u0027B6\u0027, \u0027B7\u0027]\nheader = f\"{\u0027Model\u0027:\u003c8} {\u0027phi\u0027:\u003e3}  {\u0027depth\u0027:\u003e6}  {\u0027width\u0027:\u003e6}  {\u0027res\u0027:\u003e5}  {\u0027Params(M)\u0027:\u003e9}  {\u0027GFLOPs\u0027:\u003e7}\"\nprint(header)\nprint(\u0027-\u0027 * len(header))\nfor phi, name in enumerate(names):\n    d, w, r, p, f, res = compound_scale(phi)\n    print(f\"{name:\u003c8} {phi:\u003e3}  {d:\u003e6.2f}  {w:\u003e6.2f}  {res:\u003e5}  {p:\u003e9.1f}  {f:\u003e7.2f}\")\nprint()\nprint(\"Compound scaling is more FLOPs-efficient than single-dimension scaling.\")\nprint(\"B0-\u003eB7 increases FLOPs by ~95x; accuracy rises from 77.3% to 84.4%.\")"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom torchvision import models, transforms\n\nmodel = models.efficientnet_b0(weights=models.EfficientNet_B0_Weights.IMAGENET1K_V1)\n\n# Freeze entire backbone\nfor param in model.parameters():\n    param.requires_grad = False\n\n# Replace classification head (in_features=1280 for B0)\nnum_classes = 10\nmodel.classifier = nn.Sequential(\n    nn.Dropout(p=0.2, inplace=True),\n    nn.Linear(model.classifier[1].in_features, num_classes)\n)\n\ntrainable = sum(p.numel() for p in model.parameters() if p.requires_grad)\ntotal     = sum(p.numel() for p in model.parameters())\nprint(f\"Trainable: {trainable:,} / {total:,} ({100*trainable/total:.2f}%)\")\n\noptimizer = torch.optim.Adam(model.classifier.parameters(), lr=1e-3)\ncriterion = nn.CrossEntropyLoss()\n\n# Standard EfficientNet-B0 preprocessing\ntransform = transforms.Compose([\n    transforms.Resize(256),\n    transforms.CenterCrop(224),\n    transforms.ToTensor(),\n    transforms.Normalize([0.485, 0.456, 0.406], [0.229, 0.224, 0.225]),\n])\nprint(\"To fine-tune more layers: set param.requires_grad=True for model.features[-3:]\")"},{"type":"heading","level":2,"content":"EfficientNetV2 and Progressive Learning"},{"type":"text","content":"EfficientNetV2 (Tan \u0026 Le, 2021) revisited the design with three improvements: (1) Fused-MBConv replaces the expand+depthwise combination in early layers with a single regular 3×3 convolution — faster on accelerators (TPU/GPU) despite more FLOPs because fused ops have better hardware utilization; (2) Progressive learning: training starts with small images (e.g., 128px) and weak augmentation, then gradually increases both to the full resolution — cuts training time by ~4× versus training on large images throughout; (3) Improved scaling: S/M/L/XL variants replace B0-B7, achieving 85.7% on ImageNet for EfficientNetV2-L with 3.1× faster training than EfficientNet-B7."},{"type":"heading","level":2,"content":"EfficientDet — Compound Scaling for Detection"},{"type":"text","content":"EfficientDet applies compound scaling to object detection. The backbone is EfficientNet-Bφ; the neck is BiFPN (bidirectional feature pyramid network) scaled by depth and channel count; the detection head is also scaled with φ. BiFPN applies weighted bidirectional feature fusion across P3–P7 scales, learning a softmax importance weight at each connection. The compound scaling coefficient φ controls all three components simultaneously. EfficientDet D0–D7 set new efficiency records on COCO — EfficientDet-D7 achieves 55.1 AP at 52M parameters versus AmoebaNet+NAS-FPN at 55.7 AP with 167M parameters."},{"type":"heading","level":2,"content":"B0–B7 Scaling Reference"},{"type":"table","headers":["Model","φ","Input Res","Params (M)","GFLOPs","Top-1 Acc (%)"],"rows":[["B0","0","224","5.3","0.39","77.3"],["B1","1","240","7.8","0.70","79.2"],["B2","2","260","9.2","1.0","80.3"],["B3","3","300","12.0","1.8","81.7"],["B4","4","380","19.0","4.2","83.0"],["B5","5","456","30.0","9.9","83.7"],["B6","6","528","43.0","19.0","84.1"],["B7","7","600","66.0","37.0","84.4"]]},{"type":"heading","level":2,"content":"Design Conclusions"},{"type":"text","content":"The central contribution of EfficientNet is the compound scaling methodology, not the B0 architecture itself. By constraining α·β²·γ²≈2, scaling becomes calibrated: each unit of φ costs a predictable 2× in FLOPs. The grid search for α, β, γ is cheap (run at φ=1 on a small dataset) and the result is a clean scaling law from B0 to B7. This methodology is architecture-agnostic and has influenced many subsequent models — EfficientDet, EfficientNetV2, and many detection/segmentation backbones all adopt the same principle."},{"type":"list","ordered":false,"items":["NAS finds B0 baseline; compound scaling with φ multiplies it into B1-B7.","Constraint α·β²·γ²≈2 ensures doubling φ doubles FLOPs (clean scaling law).","MBConv: expand (pointwise) -\u003e depthwise -\u003e SE -\u003e project (pointwise) + skip.","SE block: global avg pool -\u003e FC bottleneck -\u003e Sigmoid -\u003e channel-wise scale.","EfficientNetV2: Fused-MBConv for early layers, progressive image size training.","At equal accuracy, EfficientNet uses up to 8.4× fewer parameters than prior CNNs."]}]"
---
# EfficientNet — Compound Scaling and NAS Design

EfficientNet (Tan & Le, NeurIPS 2019) revolutionized CNN design by asking a fundamental question: given a fixed compute budget, how should you scale network depth, width, and input resolution together? The answer — compound scaling — yields a family of models from B0 (5.3M params) to B7 (66M params) that outperformed every prior CNN at the time of publication. EfficientNet models are derived from a NAS-found B0 baseline and systematically scaled, making them both principled and highly efficient.

## What Is EfficientNet?

EfficientNet is a family of CNNs whose architecture and scaling strategy were co-designed by Neural Architecture Search (NAS). The NAS process optimized for accuracy and FLOPs simultaneously on a small proxy task, yielding the B0 baseline architecture. B0 uses Mobile Inverted Bottleneck Convolutions (MBConv) with Squeeze-Excitation attention as the core block. From B0, the B1–B7 variants are obtained by increasing a compound coefficient φ that jointly scales depth, width, and resolution. At equal accuracy, EfficientNet used up to 8.4× fewer parameters and 16× fewer FLOPs than the best competing models such as GPipe.

## Compound Scaling — Depth, Width, and Resolution

Naively scaling any single dimension (depth only, width only, or resolution only) quickly hits diminishing returns. Tan & Le propose scaling all three simultaneously using a compound coefficient φ. Baseline multipliers α (depth), β (width), γ (resolution) are found by grid search at φ=1 subject to the constraint α·β²·γ²≈2, so that doubling φ roughly doubles FLOPs. The scaled model at coefficient φ has: depth d = α^φ, width w = β^φ, resolution r = γ^φ. For EfficientNet, α=1.2, β=1.1, γ=1.15 — giving α·β²·γ² ≈ 1.2×1.21×1.3225 ≈ 1.92 ≈ 2. This means one unit of φ costs approximately 2× the FLOPs of the previous step.

## Squeeze-Excitation Blocks

The SE block (Hu et al., 2018) reweights channels adaptively using global context. It has three steps: (1) Squeeze — global average pool across spatial dimensions, yielding a (B, C) descriptor; (2) Excitation — two fully-connected layers with ReLU and Sigmoid, forming a bottleneck C → C/r → C that learns channel importance weights; (3) Scale — multiply the feature map channel-wise by the learned weights ∈ (0, 1). The SE block adds approximately 2·C²/r parameters (r=4 typical), a small overhead that consistently provides +1–2% accuracy. EfficientNet places one SE block inside every MBConv block.

> **Why SE Blocks Work**: The SE block is a lightweight channel attention mechanism. The global average pool squeezes spatial information into a channel descriptor; the FC bottleneck excites informative channels and suppresses less useful ones. Because the learned weights depend on global image content (not local patches), the network can selectively suppress background-activated channels even when those channels fire strongly locally. SE adds <1% parameter overhead while consistently improving accuracy.

## MBConv — Mobile Inverted Bottleneck

MBConv (also used in MobileNetV2 and V3) is an inverted bottleneck: channels are first expanded (by factor expand_ratio=6) then reduced — opposite to the classic bottleneck. EfficientNet's MBConv block: (1) pointwise expansion conv (in → in×expand), (2) depthwise 3×3 or 5×5 conv with stride, (3) Squeeze-Excitation, (4) pointwise projection conv (in×expand → out), (5) skip connection when stride=1 and in_channels=out_channels. The depthwise separable structure dramatically reduces FLOPs versus standard convolution: a k×k depthwise + 1×1 pointwise uses k² + C_out times fewer FLOPs than a k×k standard conv.

## Code Examples

```python
import torch
import torch.nn as nn

class SqueezeExcitation(nn.Module):
    """SE block: global avg pool -> FC -> ReLU -> FC -> Sigmoid -> channel scaling."""
    def __init__(self, in_channels, reduction_ratio=4):
        super().__init__()
        reduced = max(1, in_channels // reduction_ratio)
        self.gap  = nn.AdaptiveAvgPool2d(1)
        self.fc1  = nn.Linear(in_channels, reduced)
        self.fc2  = nn.Linear(reduced, in_channels)
        self.relu = nn.ReLU(inplace=True)
        self.sig  = nn.Sigmoid()

    def forward(self, x):
        s = self.gap(x).flatten(1)           # (B, C): squeeze
        s = self.relu(self.fc1(s))           # FC -> ReLU
        s = self.sig(self.fc2(s))            # FC -> Sigmoid: weights in (0,1)
        return x * s.unsqueeze(-1).unsqueeze(-1)  # channel-wise scale

se = SqueezeExcitation(64, reduction_ratio=4)
x  = torch.randn(2, 64, 28, 28)
out = se(x)
print(f"Input:  {x.shape}")
print(f"Output: {out.shape}  (same shape, channels re-weighted)")
print(f"SE params: {sum(p.numel() for p in se.parameters()):,}")
print("reduction_ratio=4 -> bottleneck: 64->16->64; small overhead, large gain")
```

```python
import torch
import torch.nn as nn

class MBConv(nn.Module):
    """Mobile Inverted Bottleneck + SE block (EfficientNet core building block)."""
    def __init__(self, in_ch, out_ch, expand=6, stride=1, se_ratio=0.25):
        super().__init__()
        mid, se_ch = in_ch * expand, max(1, int(in_ch * se_ratio))
        self.skip  = (stride == 1 and in_ch == out_ch)
        self.expand = nn.Sequential(nn.Conv2d(in_ch, mid, 1, bias=False),
                                    nn.BatchNorm2d(mid), nn.SiLU())
        self.dw = nn.Sequential(
            nn.Conv2d(mid, mid, 3, stride=stride, padding=1, groups=mid, bias=False),
            nn.BatchNorm2d(mid), nn.SiLU())
        self.se_pool = nn.AdaptiveAvgPool2d(1)
        self.se_fc   = nn.Sequential(nn.Linear(mid, se_ch), nn.ReLU(),
                                     nn.Linear(se_ch, mid), nn.Sigmoid())
        self.proj = nn.Sequential(nn.Conv2d(mid, out_ch, 1, bias=False),
                                  nn.BatchNorm2d(out_ch))

    def forward(self, x):
        h = self.expand(x)
        h = self.dw(h)
        h = h * self.se_fc(self.se_pool(h).flatten(1)).view(h.size(0), h.size(1), 1, 1)
        h = self.proj(h)
        return h + x if self.skip else h

m = MBConv(32, 32, expand=6, stride=1)
x = torch.randn(2, 32, 28, 28)
print(f"Output: {m(x).shape}, Params: {sum(p.numel() for p in m.parameters()):,}")
print("Pattern: expand(pw) -> depthwise -> SE -> project(pw) + skip")
```

```python
# EfficientNet compound scaling: depth=alpha^phi, width=beta^phi, resolution=gamma^phi
ALPHA, BETA, GAMMA = 1.2, 1.1, 1.15
B0_PARAMS_M, B0_FLOPS_B, B0_RES = 5.3, 0.39, 224

print(f"Constraint: alpha*beta**2*gamma**2 = {ALPHA * BETA**2 * GAMMA**2:.4f} (target ~2)")

def compound_scale(phi):
    d = ALPHA ** phi
    w = BETA  ** phi
    r = GAMMA ** phi
    return (d, w, r,
            B0_PARAMS_M * d * w**2,
            B0_FLOPS_B  * d * w**2 * r**2,
            int(B0_RES * r / 32) * 32)

names = ['B0', 'B1', 'B2', 'B3', 'B4', 'B5', 'B6', 'B7']
header = f"{'Model':<8} {'phi':>3}  {'depth':>6}  {'width':>6}  {'res':>5}  {'Params(M)':>9}  {'GFLOPs':>7}"
print(header)
print('-' * len(header))
for phi, name in enumerate(names):
    d, w, r, p, f, res = compound_scale(phi)
    print(f"{name:<8} {phi:>3}  {d:>6.2f}  {w:>6.2f}  {res:>5}  {p:>9.1f}  {f:>7.2f}")
print()
print("Compound scaling is more FLOPs-efficient than single-dimension scaling.")
print("B0->B7 increases FLOPs by ~95x; accuracy rises from 77.3% to 84.4%.")
```

```python
import torch
import torch.nn as nn
from torchvision import models, transforms

model = models.efficientnet_b0(weights=models.EfficientNet_B0_Weights.IMAGENET1K_V1)

# Freeze entire backbone
for param in model.parameters():
    param.requires_grad = False

# Replace classification head (in_features=1280 for B0)
num_classes = 10
model.classifier = nn.Sequential(
    nn.Dropout(p=0.2, inplace=True),
    nn.Linear(model.classifier[1].in_features, num_classes)
)

trainable = sum(p.numel() for p in model.parameters() if p.requires_grad)
total     = sum(p.numel() for p in model.parameters())
print(f"Trainable: {trainable:,} / {total:,} ({100*trainable/total:.2f}%)")

optimizer = torch.optim.Adam(model.classifier.parameters(), lr=1e-3)
criterion = nn.CrossEntropyLoss()

# Standard EfficientNet-B0 preprocessing
transform = transforms.Compose([
    transforms.Resize(256),
    transforms.CenterCrop(224),
    transforms.ToTensor(),
    transforms.Normalize([0.485, 0.456, 0.406], [0.229, 0.224, 0.225]),
])
print("To fine-tune more layers: set param.requires_grad=True for model.features[-3:]")
```

## EfficientNetV2 and Progressive Learning

EfficientNetV2 (Tan & Le, 2021) revisited the design with three improvements: (1) Fused-MBConv replaces the expand+depthwise combination in early layers with a single regular 3×3 convolution — faster on accelerators (TPU/GPU) despite more FLOPs because fused ops have better hardware utilization; (2) Progressive learning: training starts with small images (e.g., 128px) and weak augmentation, then gradually increases both to the full resolution — cuts training time by ~4× versus training on large images throughout; (3) Improved scaling: S/M/L/XL variants replace B0-B7, achieving 85.7% on ImageNet for EfficientNetV2-L with 3.1× faster training than EfficientNet-B7.

## EfficientDet — Compound Scaling for Detection

EfficientDet applies compound scaling to object detection. The backbone is EfficientNet-Bφ; the neck is BiFPN (bidirectional feature pyramid network) scaled by depth and channel count; the detection head is also scaled with φ. BiFPN applies weighted bidirectional feature fusion across P3–P7 scales, learning a softmax importance weight at each connection. The compound scaling coefficient φ controls all three components simultaneously. EfficientDet D0–D7 set new efficiency records on COCO — EfficientDet-D7 achieves 55.1 AP at 52M parameters versus AmoebaNet+NAS-FPN at 55.7 AP with 167M parameters.

## B0–B7 Scaling Reference

| Model | φ | Input Res | Params (M) | GFLOPs | Top-1 Acc (%) |
| --- | --- | --- | --- | --- | --- |
| B0 | 0 | 224 | 5.3 | 0.39 | 77.3 |
| B1 | 1 | 240 | 7.8 | 0.70 | 79.2 |
| B2 | 2 | 260 | 9.2 | 1.0 | 80.3 |
| B3 | 3 | 300 | 12.0 | 1.8 | 81.7 |
| B4 | 4 | 380 | 19.0 | 4.2 | 83.0 |
| B5 | 5 | 456 | 30.0 | 9.9 | 83.7 |
| B6 | 6 | 528 | 43.0 | 19.0 | 84.1 |
| B7 | 7 | 600 | 66.0 | 37.0 | 84.4 |

## Design Conclusions

The central contribution of EfficientNet is the compound scaling methodology, not the B0 architecture itself. By constraining α·β²·γ²≈2, scaling becomes calibrated: each unit of φ costs a predictable 2× in FLOPs. The grid search for α, β, γ is cheap (run at φ=1 on a small dataset) and the result is a clean scaling law from B0 to B7. This methodology is architecture-agnostic and has influenced many subsequent models — EfficientDet, EfficientNetV2, and many detection/segmentation backbones all adopt the same principle.

- NAS finds B0 baseline; compound scaling with φ multiplies it into B1-B7.
- Constraint α·β²·γ²≈2 ensures doubling φ doubles FLOPs (clean scaling law).
- MBConv: expand (pointwise) -> depthwise -> SE -> project (pointwise) + skip.
- SE block: global avg pool -> FC bottleneck -> Sigmoid -> channel-wise scale.
- EfficientNetV2: Fused-MBConv for early layers, progressive image size training.
- At equal accuracy, EfficientNet uses up to 8.4× fewer parameters than prior CNNs.

