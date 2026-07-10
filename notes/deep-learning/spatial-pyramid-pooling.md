---
title: "Spatial Pyramid Pooling (SPP) — Multi-Scale Feature Aggregation"
slug: "spatial-pyramid-pooling"
description: "SPP-Net pools at multiple grid sizes to produce fixed-size feature vectors from any input resolution; ASPP applies atrous convolutions at multiple dilation rates for semantic segmentation; PSPNet, SPPF, and PANet extend the idea to detection and scene parsing."
tags: ["deep-learning", "cnns", "architectures"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Spatial Pyramid Pooling (SPP) solves a fundamental mismatch between convolutional feature maps of arbitrary spatial size and downstream layers that require a fixed-length input. By pooling at multiple pyramid levels — 1×1, 2×2, and 4×4 grids — and concatenating the results, SPP produces a fixed-size descriptor regardless of input image resolution. This single idea spawned an entire family of multi-scale pooling architectures spanning image classification, object detection, and semantic segmentation."},{"type":"heading","level":2,"content":"Fixed-Size Feature Vectors from Variable-Size Inputs"},{"type":"text","content":"A standard CNN requires a fixed input size because fully-connected layers expect a fixed number of inputs. The spatial feature map from a conv layer has shape C×H×W where H and W depend on input dimensions. SPP resolves this by applying adaptive pooling at l pyramid levels with grid sizes s₁, s₂, ..., sₗ. Each level pools the C-channel map into C×sᵢ×sᵢ, which is then flattened. Outputs are concatenated to form a fixed vector of length C × Σ(sᵢ²). For pool sizes {1, 2, 4} and C=512, output is always 512×(1+4+16)=10,752 regardless of whether input is 224×224 or 640×480."},{"type":"heading","level":2,"content":"SPP-Net: Computing Features Once for All Proposals"},{"type":"text","content":"R-CNN (Girshick et al., 2014) runs a forward pass through the full CNN for each region proposal independently — typically 2,000 proposals per image, each resized to a fixed 227×227 crop. SPP-Net (He et al., 2015) eliminates this redundancy: it runs the convolutional layers once on the entire image to produce a shared feature map, then applies SPP to each proposal\u0027s region within that feature map. Since proposals overlap heavily, shared computation yields a 24–102× speedup. This insight — compute once, pool per region — directly inspired RoI Pooling in Fast R-CNN and RoI Align in Mask R-CNN."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass SPPModule(nn.Module):\n    \u0027\u0027\u0027Spatial Pyramid Pooling: pools at multiple grid sizes, concatenates.\u0027\u0027\u0027\n    def __init__(self, pool_sizes=(1, 2, 4)):\n        super().__init__()\n        self.pool_sizes = pool_sizes\n\n    def forward(self, x):\n        b, c, h, w = x.shape\n        pooled = []\n        for size in self.pool_sizes:\n            out = F.adaptive_avg_pool2d(x, output_size=(size, size))\n            pooled.append(out.view(b, -1))  # flatten each scale\n        return torch.cat(pooled, dim=1)\n\n    def output_dim(self, in_channels):\n        return in_channels * sum(s * s for s in self.pool_sizes)\n\n# Any input spatial size works — no cropping or warping needed\nmodel = SPPModule(pool_sizes=(1, 2, 4))\nfor h, w in [(7, 7), (14, 10), (20, 15)]:\n    x = torch.randn(2, 512, h, w)\n    out = model(x)\n    print(\u0027Input {}x{} -\u003e SPP output dim: {}\u0027.format(h, w, out.shape[1]))\nprint(\u0027Fixed output dim = 512*(1+4+16) = {:,}\u0027.format(model.output_dim(512)))"},{"type":"heading","level":2,"content":"ASPP: Atrous Spatial Pyramid Pooling"},{"type":"text","content":"DeepLab (Chen et al.) replaces standard max pooling with atrous (dilated) convolutions to capture multi-scale context without reducing feature map resolution. ASPP applies parallel 3×3 dilated convolutions with rates r ∈ {6, 12, 18}, plus a 1×1 conv and global average pooling, all operating on the same high-resolution feature map. With dilation rate r, a 3×3 kernel covers an effective receptive field of (r×2+1)² while maintaining full spatial resolution. Concatenating all branches and projecting with a 1×1 conv gives a rich multi-scale representation for per-pixel classification."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass ASPPConv(nn.Module):\n    def __init__(self, in_ch, out_ch, dilation):\n        super().__init__()\n        self.block = nn.Sequential(\n            nn.Conv2d(in_ch, out_ch, 3, padding=dilation, dilation=dilation, bias=False),\n            nn.BatchNorm2d(out_ch), nn.ReLU(inplace=True))\n    def forward(self, x): return self.block(x)\n\nclass ASPPModule(nn.Module):\n    \u0027\u0027\u0027Atrous Spatial Pyramid Pooling from DeepLab-v3.\u0027\u0027\u0027\n    def __init__(self, in_ch=2048, out_ch=256, rates=(6, 12, 18)):\n        super().__init__()\n        self.conv1x1 = nn.Sequential(\n            nn.Conv2d(in_ch, out_ch, 1, bias=False),\n            nn.BatchNorm2d(out_ch), nn.ReLU(inplace=True))\n        self.atrous = nn.ModuleList([ASPPConv(in_ch, out_ch, r) for r in rates])\n        self.global_pool = nn.Sequential(\n            nn.AdaptiveAvgPool2d(1), nn.Conv2d(in_ch, out_ch, 1, bias=False),\n            nn.BatchNorm2d(out_ch), nn.ReLU(inplace=True))\n        n_branches = 2 + len(rates)\n        self.proj = nn.Sequential(\n            nn.Conv2d(out_ch * n_branches, out_ch, 1, bias=False),\n            nn.BatchNorm2d(out_ch), nn.ReLU(inplace=True), nn.Dropout(0.5))\n\n    def forward(self, x):\n        h, w = x.shape[-2:]\n        branches = [self.conv1x1(x)] + [a(x) for a in self.atrous]\n        gp = F.interpolate(self.global_pool(x), (h, w), mode=\u0027bilinear\u0027, align_corners=False)\n        return self.proj(torch.cat(branches + [gp], dim=1))\n\naspp = ASPPModule()\nx = torch.randn(2, 2048, 32, 32)\nprint(\u0027ASPP input: {} -\u003e output: {}\u0027.format(x.shape, aspp(x).shape))"},{"type":"callout","variant":"info","title":"Choosing Dilation Rates","content":"ASPP rates {6, 12, 18} are calibrated for output stride 16 (feature map is 1/16 of input). Effective receptive fields become 13×13, 25×25, and 37×37. For output stride 8, rates {12, 24, 36} maintain equivalent coverage. Very large rates on small feature maps cause gridding artifacts — the dilated kernel samples mostly background — which is why a global pooling branch is always included to capture image-level context."},{"type":"heading","level":2,"content":"PSPNet: Pyramid Pooling Module"},{"type":"text","content":"Pyramid Scene Parsing Network (Zhao et al., 2017) applies global context via pooling at four sub-region sizes: 1×1 (global average), 2×2, 3×3, and 6×6. Each pooled representation passes through a 1×1 conv reducing channels to in_ch // 4, then is upsampled back to the original feature map size via bilinear interpolation. Concatenating these four context descriptors with the original feature map and applying a final bottleneck conv produces the output for pixel-wise classification. PSPNet won the ImageNet Scene Parsing Challenge 2016 with mIoU 85.4% on ADE20K."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass PyramidPoolingModule(nn.Module):\n    \u0027\u0027\u0027PSPNet Pyramid Pooling Module (Zhao et al., 2017).\u0027\u0027\u0027\n    def __init__(self, in_ch, pool_sizes=(1, 2, 3, 6)):\n        super().__init__()\n        mid_ch = in_ch // len(pool_sizes)\n        self.stages = nn.ModuleList([\n            nn.Sequential(\n                nn.AdaptiveAvgPool2d(s),\n                nn.Conv2d(in_ch, mid_ch, 1, bias=False),\n                nn.BatchNorm2d(mid_ch), nn.ReLU(inplace=True)\n            ) for s in pool_sizes\n        ])\n        self.bottleneck = nn.Sequential(\n            nn.Conv2d(in_ch + mid_ch * len(pool_sizes), in_ch // 2, 3,\n                      padding=1, bias=False),\n            nn.BatchNorm2d(in_ch // 2), nn.ReLU(inplace=True))\n\n    def forward(self, x):\n        h, w = x.shape[-2:]\n        out = [x]\n        for stage in self.stages:\n            pooled = stage(x)\n            out.append(F.interpolate(pooled, (h, w), mode=\u0027bilinear\u0027, align_corners=False))\n        return self.bottleneck(torch.cat(out, dim=1))\n\nppm = PyramidPoolingModule(in_ch=2048)\nx = torch.randn(2, 2048, 60, 60)\nout = ppm(x)\nprint(\u0027PPM {} -\u003e {}\u0027.format(x.shape, out.shape))\nprint(\u0027Output channels: {} (in_ch // 2)\u0027.format(out.shape[1]))"},{"type":"heading","level":2,"content":"SPPF: Sequential Max Pooling in YOLOv5"},{"type":"text","content":"SPPF (Spatial Pyramid Pooling — Fast) replaces parallel multi-scale max pools with three sequential 5×5 max pools. A single 5×5 pool covers a 5×5 region; two sequential 5×5 pools cover 9×9; three cover 13×13. This matches the receptive fields of parallel 5×5, 9×9, and 13×13 pools but runs faster because sequential pools share computation. YOLOv5 inserts SPPF at the end of its backbone (after CSP layers) to aggregate global context before the PANet neck. A channel-halving 1×1 conv precedes the pools and a 1×1 conv projects the concatenated 4-way output, keeping latency low."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass SPPF(nn.Module):\n    \u0027\u0027\u0027SPPF: Spatial Pyramid Pooling - Fast (YOLOv5).\n    Three sequential 5x5 max pools give effective RFs of 5x5, 9x9, 13x13.\n    Faster than parallel SPP due to shared intermediate computations.\n    \u0027\u0027\u0027\n    def __init__(self, in_ch, out_ch, k=5):\n        super().__init__()\n        mid_ch = in_ch // 2\n        self.conv1 = nn.Sequential(\n            nn.Conv2d(in_ch, mid_ch, 1, bias=False),\n            nn.BatchNorm2d(mid_ch), nn.SiLU())\n        self.pool = nn.MaxPool2d(k, stride=1, padding=k // 2)\n        self.conv2 = nn.Sequential(\n            nn.Conv2d(mid_ch * 4, out_ch, 1, bias=False),\n            nn.BatchNorm2d(out_ch), nn.SiLU())\n\n    def forward(self, x):\n        x = self.conv1(x)\n        p1 = self.pool(x)\n        p2 = self.pool(p1)\n        p3 = self.pool(p2)\n        return self.conv2(torch.cat([x, p1, p2, p3], dim=1))\n\nsppf = SPPF(in_ch=512, out_ch=512)\nx = torch.randn(1, 512, 20, 20)\nout = sppf(x)\nparams = sum(p.numel() for p in sppf.parameters())\nprint(\u0027SPPF {} -\u003e {}\u0027.format(x.shape, out.shape))\nprint(\u0027Parameters: {:,}\u0027.format(params))"},{"type":"heading","level":2,"content":"PANet and Multi-Scale Feature Aggregation"},{"type":"text","content":"Path Aggregation Network (PANet, Liu et al. 2018) extends FPN by adding a bottom-up path augmentation after the standard top-down FPN pathway. FPN propagates strong semantic features from low-resolution layers upward to high-resolution layers. PANet adds a shortcut from the low-level features back up through the hierarchy, so high-resolution spatial detail (edges, textures) flows upward into high-level semantic representations. This bidirectional flow — top-down semantics + bottom-up spatial detail — improves instance segmentation and detection across scales. YOLOv5, YOLOv8, and PP-YOLO all adopt PANet-style necks."},{"type":"list","ordered":false,"items":["FPN top-down path: C5 (low-res, high-semantic) → C4 → C3 (high-res) via upsampling and lateral connections.","PANet bottom-up path: P3 (high-res) → P4 → P5 (low-res) via stride-2 downsampling and lateral connections.","Each feature map now sees both top-down context (long path) and bottom-up spatial detail (short path).","Adaptive Feature Pooling: RoI features are pooled from all pyramid levels and fused, ensuring proposals see context at every scale.","SPPF is typically placed at the backbone output before the PANet neck to provide global receptive field coverage."]},{"type":"heading","level":2,"content":"Comparing SPP Variants"},{"type":"text","content":"The SPP family spans pooling strategies optimised for different tasks. Classification networks need fixed-size descriptors; segmentation models need full-resolution outputs with multi-scale context; detection backbones need speed with global receptive field; multi-scale necks need bidirectional information flow across pyramid levels."},{"type":"table","headers":["Variant","Scales / Rates","Pooling Op","Task","Latency","Key Benefit"],"rows":[["SPP (He 2015)","{1×1, 2×2, 4×4}","Adaptive max pool","Classification, Detection","Medium","Fixed output from any input size"],["ASPP (DeepLab)","Dilation {6, 12, 18}","Dilated 3×3 conv","Semantic segmentation","High","Full-resolution multi-scale context"],["PSPNet PPM","{1, 2, 3, 6} grid","Avg pool + upsample","Semantic segmentation","Medium","Global scene context pooling"],["SPPF (YOLOv5)","5×5 sequential × 3","Sequential max pool","Object detection","Low","Fast multi-scale RF expansion"],["PANet","FPN + bottom-up","Stride-2 conv + lateral","Detection, Segmentation","Medium","Bidirectional semantic + spatial flow"]]},{"type":"divider"}]"
---
# Spatial Pyramid Pooling (SPP) — Multi-Scale Feature Aggregation

Spatial Pyramid Pooling (SPP) solves a fundamental mismatch between convolutional feature maps of arbitrary spatial size and downstream layers that require a fixed-length input. By pooling at multiple pyramid levels — 1×1, 2×2, and 4×4 grids — and concatenating the results, SPP produces a fixed-size descriptor regardless of input image resolution. This single idea spawned an entire family of multi-scale pooling architectures spanning image classification, object detection, and semantic segmentation.

## Fixed-Size Feature Vectors from Variable-Size Inputs

A standard CNN requires a fixed input size because fully-connected layers expect a fixed number of inputs. The spatial feature map from a conv layer has shape C×H×W where H and W depend on input dimensions. SPP resolves this by applying adaptive pooling at l pyramid levels with grid sizes s₁, s₂, ..., sₗ. Each level pools the C-channel map into C×sᵢ×sᵢ, which is then flattened. Outputs are concatenated to form a fixed vector of length C × Σ(sᵢ²). For pool sizes {1, 2, 4} and C=512, output is always 512×(1+4+16)=10,752 regardless of whether input is 224×224 or 640×480.

## SPP-Net: Computing Features Once for All Proposals

R-CNN (Girshick et al., 2014) runs a forward pass through the full CNN for each region proposal independently — typically 2,000 proposals per image, each resized to a fixed 227×227 crop. SPP-Net (He et al., 2015) eliminates this redundancy: it runs the convolutional layers once on the entire image to produce a shared feature map, then applies SPP to each proposal's region within that feature map. Since proposals overlap heavily, shared computation yields a 24–102× speedup. This insight — compute once, pool per region — directly inspired RoI Pooling in Fast R-CNN and RoI Align in Mask R-CNN.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class SPPModule(nn.Module):
    '''Spatial Pyramid Pooling: pools at multiple grid sizes, concatenates.'''
    def __init__(self, pool_sizes=(1, 2, 4)):
        super().__init__()
        self.pool_sizes = pool_sizes

    def forward(self, x):
        b, c, h, w = x.shape
        pooled = []
        for size in self.pool_sizes:
            out = F.adaptive_avg_pool2d(x, output_size=(size, size))
            pooled.append(out.view(b, -1))  # flatten each scale
        return torch.cat(pooled, dim=1)

    def output_dim(self, in_channels):
        return in_channels * sum(s * s for s in self.pool_sizes)

# Any input spatial size works — no cropping or warping needed
model = SPPModule(pool_sizes=(1, 2, 4))
for h, w in [(7, 7), (14, 10), (20, 15)]:
    x = torch.randn(2, 512, h, w)
    out = model(x)
    print('Input {}x{} -> SPP output dim: {}'.format(h, w, out.shape[1]))
print('Fixed output dim = 512*(1+4+16) = {:,}'.format(model.output_dim(512)))
```

## ASPP: Atrous Spatial Pyramid Pooling

DeepLab (Chen et al.) replaces standard max pooling with atrous (dilated) convolutions to capture multi-scale context without reducing feature map resolution. ASPP applies parallel 3×3 dilated convolutions with rates r ∈ {6, 12, 18}, plus a 1×1 conv and global average pooling, all operating on the same high-resolution feature map. With dilation rate r, a 3×3 kernel covers an effective receptive field of (r×2+1)² while maintaining full spatial resolution. Concatenating all branches and projecting with a 1×1 conv gives a rich multi-scale representation for per-pixel classification.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class ASPPConv(nn.Module):
    def __init__(self, in_ch, out_ch, dilation):
        super().__init__()
        self.block = nn.Sequential(
            nn.Conv2d(in_ch, out_ch, 3, padding=dilation, dilation=dilation, bias=False),
            nn.BatchNorm2d(out_ch), nn.ReLU(inplace=True))
    def forward(self, x): return self.block(x)

class ASPPModule(nn.Module):
    '''Atrous Spatial Pyramid Pooling from DeepLab-v3.'''
    def __init__(self, in_ch=2048, out_ch=256, rates=(6, 12, 18)):
        super().__init__()
        self.conv1x1 = nn.Sequential(
            nn.Conv2d(in_ch, out_ch, 1, bias=False),
            nn.BatchNorm2d(out_ch), nn.ReLU(inplace=True))
        self.atrous = nn.ModuleList([ASPPConv(in_ch, out_ch, r) for r in rates])
        self.global_pool = nn.Sequential(
            nn.AdaptiveAvgPool2d(1), nn.Conv2d(in_ch, out_ch, 1, bias=False),
            nn.BatchNorm2d(out_ch), nn.ReLU(inplace=True))
        n_branches = 2 + len(rates)
        self.proj = nn.Sequential(
            nn.Conv2d(out_ch * n_branches, out_ch, 1, bias=False),
            nn.BatchNorm2d(out_ch), nn.ReLU(inplace=True), nn.Dropout(0.5))

    def forward(self, x):
        h, w = x.shape[-2:]
        branches = [self.conv1x1(x)] + [a(x) for a in self.atrous]
        gp = F.interpolate(self.global_pool(x), (h, w), mode='bilinear', align_corners=False)
        return self.proj(torch.cat(branches + [gp], dim=1))

aspp = ASPPModule()
x = torch.randn(2, 2048, 32, 32)
print('ASPP input: {} -> output: {}'.format(x.shape, aspp(x).shape))
```

> **Choosing Dilation Rates**: ASPP rates {6, 12, 18} are calibrated for output stride 16 (feature map is 1/16 of input). Effective receptive fields become 13×13, 25×25, and 37×37. For output stride 8, rates {12, 24, 36} maintain equivalent coverage. Very large rates on small feature maps cause gridding artifacts — the dilated kernel samples mostly background — which is why a global pooling branch is always included to capture image-level context.

## PSPNet: Pyramid Pooling Module

Pyramid Scene Parsing Network (Zhao et al., 2017) applies global context via pooling at four sub-region sizes: 1×1 (global average), 2×2, 3×3, and 6×6. Each pooled representation passes through a 1×1 conv reducing channels to in_ch // 4, then is upsampled back to the original feature map size via bilinear interpolation. Concatenating these four context descriptors with the original feature map and applying a final bottleneck conv produces the output for pixel-wise classification. PSPNet won the ImageNet Scene Parsing Challenge 2016 with mIoU 85.4% on ADE20K.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class PyramidPoolingModule(nn.Module):
    '''PSPNet Pyramid Pooling Module (Zhao et al., 2017).'''
    def __init__(self, in_ch, pool_sizes=(1, 2, 3, 6)):
        super().__init__()
        mid_ch = in_ch // len(pool_sizes)
        self.stages = nn.ModuleList([
            nn.Sequential(
                nn.AdaptiveAvgPool2d(s),
                nn.Conv2d(in_ch, mid_ch, 1, bias=False),
                nn.BatchNorm2d(mid_ch), nn.ReLU(inplace=True)
            ) for s in pool_sizes
        ])
        self.bottleneck = nn.Sequential(
            nn.Conv2d(in_ch + mid_ch * len(pool_sizes), in_ch // 2, 3,
                      padding=1, bias=False),
            nn.BatchNorm2d(in_ch // 2), nn.ReLU(inplace=True))

    def forward(self, x):
        h, w = x.shape[-2:]
        out = [x]
        for stage in self.stages:
            pooled = stage(x)
            out.append(F.interpolate(pooled, (h, w), mode='bilinear', align_corners=False))
        return self.bottleneck(torch.cat(out, dim=1))

ppm = PyramidPoolingModule(in_ch=2048)
x = torch.randn(2, 2048, 60, 60)
out = ppm(x)
print('PPM {} -> {}'.format(x.shape, out.shape))
print('Output channels: {} (in_ch // 2)'.format(out.shape[1]))
```

## SPPF: Sequential Max Pooling in YOLOv5

SPPF (Spatial Pyramid Pooling — Fast) replaces parallel multi-scale max pools with three sequential 5×5 max pools. A single 5×5 pool covers a 5×5 region; two sequential 5×5 pools cover 9×9; three cover 13×13. This matches the receptive fields of parallel 5×5, 9×9, and 13×13 pools but runs faster because sequential pools share computation. YOLOv5 inserts SPPF at the end of its backbone (after CSP layers) to aggregate global context before the PANet neck. A channel-halving 1×1 conv precedes the pools and a 1×1 conv projects the concatenated 4-way output, keeping latency low.

```python
import torch
import torch.nn as nn

class SPPF(nn.Module):
    '''SPPF: Spatial Pyramid Pooling - Fast (YOLOv5).
    Three sequential 5x5 max pools give effective RFs of 5x5, 9x9, 13x13.
    Faster than parallel SPP due to shared intermediate computations.
    '''
    def __init__(self, in_ch, out_ch, k=5):
        super().__init__()
        mid_ch = in_ch // 2
        self.conv1 = nn.Sequential(
            nn.Conv2d(in_ch, mid_ch, 1, bias=False),
            nn.BatchNorm2d(mid_ch), nn.SiLU())
        self.pool = nn.MaxPool2d(k, stride=1, padding=k // 2)
        self.conv2 = nn.Sequential(
            nn.Conv2d(mid_ch * 4, out_ch, 1, bias=False),
            nn.BatchNorm2d(out_ch), nn.SiLU())

    def forward(self, x):
        x = self.conv1(x)
        p1 = self.pool(x)
        p2 = self.pool(p1)
        p3 = self.pool(p2)
        return self.conv2(torch.cat([x, p1, p2, p3], dim=1))

sppf = SPPF(in_ch=512, out_ch=512)
x = torch.randn(1, 512, 20, 20)
out = sppf(x)
params = sum(p.numel() for p in sppf.parameters())
print('SPPF {} -> {}'.format(x.shape, out.shape))
print('Parameters: {:,}'.format(params))
```

## PANet and Multi-Scale Feature Aggregation

Path Aggregation Network (PANet, Liu et al. 2018) extends FPN by adding a bottom-up path augmentation after the standard top-down FPN pathway. FPN propagates strong semantic features from low-resolution layers upward to high-resolution layers. PANet adds a shortcut from the low-level features back up through the hierarchy, so high-resolution spatial detail (edges, textures) flows upward into high-level semantic representations. This bidirectional flow — top-down semantics + bottom-up spatial detail — improves instance segmentation and detection across scales. YOLOv5, YOLOv8, and PP-YOLO all adopt PANet-style necks.

- FPN top-down path: C5 (low-res, high-semantic) → C4 → C3 (high-res) via upsampling and lateral connections.
- PANet bottom-up path: P3 (high-res) → P4 → P5 (low-res) via stride-2 downsampling and lateral connections.
- Each feature map now sees both top-down context (long path) and bottom-up spatial detail (short path).
- Adaptive Feature Pooling: RoI features are pooled from all pyramid levels and fused, ensuring proposals see context at every scale.
- SPPF is typically placed at the backbone output before the PANet neck to provide global receptive field coverage.

## Comparing SPP Variants

The SPP family spans pooling strategies optimised for different tasks. Classification networks need fixed-size descriptors; segmentation models need full-resolution outputs with multi-scale context; detection backbones need speed with global receptive field; multi-scale necks need bidirectional information flow across pyramid levels.

| Variant | Scales / Rates | Pooling Op | Task | Latency | Key Benefit |
| --- | --- | --- | --- | --- | --- |
| SPP (He 2015) | {1×1, 2×2, 4×4} | Adaptive max pool | Classification, Detection | Medium | Fixed output from any input size |
| ASPP (DeepLab) | Dilation {6, 12, 18} | Dilated 3×3 conv | Semantic segmentation | High | Full-resolution multi-scale context |
| PSPNet PPM | {1, 2, 3, 6} grid | Avg pool + upsample | Semantic segmentation | Medium | Global scene context pooling |
| SPPF (YOLOv5) | 5×5 sequential × 3 | Sequential max pool | Object detection | Low | Fast multi-scale RF expansion |
| PANet | FPN + bottom-up | Stride-2 conv + lateral | Detection, Segmentation | Medium | Bidirectional semantic + spatial flow |

---

