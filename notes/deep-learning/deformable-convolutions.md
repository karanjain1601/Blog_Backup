---
title: "Deformable Convolutions — Learned Geometric Offsets"
slug: "deformable-convolutions"
description: "Deformable convolutions (Dai et al. 2017): learn spatial offset Δpₙ per kernel position enabling flexible sampling beyond fixed grids. Covers DCNv1 (offsets), DCNv2 (modulation scalars), bilinear interpolation, visualization of sampling patterns, DCNv3, and use in object detection."
tags: ["deep-learning", "cnns", "architectures"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Standard convolutions apply a fixed k×k grid of kernel weights to each spatial location — the sampling pattern never adapts to the content of the image. Deformable Convolutions (Dai et al., ICCV 2017) break this constraint by learning 2D spatial offsets Δpₙ for each of the k² kernel positions. The convolution then samples at perturbed locations x + pₙ + Δpₙ using bilinear interpolation for fractional coordinates. The offsets are learned by an additional lightweight convolutional branch, making the operation end-to-end differentiable. Deformable convolutions dramatically improve detection and segmentation of objects with arbitrary shapes and sizes."},{"type":"heading","level":2,"content":"Limitations of Standard Convolutions"},{"type":"text","content":"A k×k convolution samples k² fixed relative positions: pₙ ∈ {(-1,-1), (-1,0), ..., (1,1)} for k=3. These positions are fixed regardless of the input — the same grid is applied to a thin vertical line, a large circle, and a diagonal edge. This fixed receptive field is poorly suited to objects that vary in scale, aspect ratio, and orientation. Pooling and large strides provide some scale invariance, but they cannot adapt the sampling geometry to match object shape. Augmentation (random rotation, scaling) helps training but does not give the network the ability to dynamically adjust its feature extraction pattern at inference."},{"type":"heading","level":2,"content":"Deformable Convolution v1"},{"type":"text","content":"DCNv1 adds a parallel offset-generating conv branch that takes the input feature map and outputs 2×k² channels — two channels (Δx, Δy) for each of the k² kernel positions. These offsets are added to the standard grid positions, and the feature map is sampled at the resulting fractional locations using bilinear interpolation: y(p) = Σₙ w(pₙ) · x(p + pₙ + Δpₙ). The bilinear interpolation makes the operation differentiable with respect to Δpₙ, allowing gradients to flow through the sampling locations during backpropagation. The offset conv branch is initialized with zero weights so that deformable conv starts as standard conv at the beginning of training."},{"type":"heading","level":2,"content":"Deformable Convolution v2 — Modulation Scalars"},{"type":"text","content":"DCNv2 (Zhu et al., CVPR 2019) extends DCNv1 by additionally learning a modulation scalar mₙ ∈ (0, 1) for each of the k² sampling positions. The modulated sampling becomes: y(p) = Σₙ w(pₙ) · mₙ · x(p + pₙ + Δpₙ). The modulation scalars act as attention weights over the sampling positions — the network can effectively zero out irrelevant sampling locations while amplifying important ones. The combined offset+modulation branch outputs 3×k² channels: 2×k² for (Δx, Δy) offsets and k² for mₙ scalars (passed through Sigmoid to keep in (0,1)). DCNv2 significantly outperforms DCNv1 on detection because it can ignore background samples that fall outside the object boundary."},{"type":"callout","variant":"info","title":"DCNv2 = Deformable + Amplitude Modulation","content":"DCNv2 combines spatial deformation (where to sample) with amplitude modulation (how much to weight each sample). This gives it two degrees of freedom versus standard conv (fixed location, fixed weight) and DCNv1 (free location, fixed unit weight). The modulation effectively makes the sampling pattern sparse and object-adaptive: for a car, the network learns to sample wheel and window positions with high weight and background with near-zero weight."},{"type":"heading","level":2,"content":"Code Examples"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass OffsetGenerator(nn.Module):\n    \"\"\"Learn per-position 2D offsets for a k x k deformable conv kernel.\"\"\"\n    def __init__(self, in_ch, kernel_size=3):\n        super().__init__()\n        self.k = kernel_size\n        n_offsets = 2 * kernel_size * kernel_size  # (dx, dy) per position\n        self.offset_conv = nn.Conv2d(in_ch, n_offsets, kernel_size=3, padding=1)\n        # Zero-init: deformable conv starts as standard conv\n        nn.init.zeros_(self.offset_conv.weight)\n        nn.init.zeros_(self.offset_conv.bias)\n\n    def forward(self, x):\n        offsets = self.offset_conv(x)   # (B, 2*k^2, H, W)\n        return offsets\n\n# Demonstrate offset shapes\ngen = OffsetGenerator(in_ch=64, kernel_size=3)\nx = torch.randn(2, 64, 28, 28)\noffsets = gen(x)\nprint(f\"Input feature map: {x.shape}\")\nprint(f\"Offsets shape:     {offsets.shape}  (2 * 3*3 = 18 channels)\")\nprint(f\"Interpretation:    offset[b, 2n,   h, w] = delta_x for position n at (h,w)\")\nprint(f\"                   offset[b, 2n+1, h, w] = delta_y for position n at (h,w)\")\nprint(f\"Zero-init means: at start of training, all offsets=0 -\u003e standard conv\")\nprint(f\"Params in offset branch: {sum(p.numel() for p in gen.parameters()):,}\")"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom torchvision.ops import DeformConv2d\n\nclass DCNv2(nn.Module):\n    \"\"\"Deformable Conv v2: offsets + modulation scalars via torchvision.\"\"\"\n    def __init__(self, in_ch, out_ch, kernel_size=3, stride=1, padding=1):\n        super().__init__()\n        k2 = kernel_size * kernel_size\n        # Branch: predict 2*k^2 offsets + k^2 modulation scalars\n        self.offset_mask = nn.Conv2d(in_ch, 3 * k2, 3, stride=1, padding=1)\n        self.dcn = DeformConv2d(in_ch, out_ch, kernel_size, stride=stride, padding=padding)\n        nn.init.zeros_(self.offset_mask.weight)\n        nn.init.zeros_(self.offset_mask.bias)\n\n    def forward(self, x):\n        om = self.offset_mask(x)          # (B, 3*k^2, H, W)\n        k2 = om.shape[1] // 3\n        offset = om[:, :2*k2]             # spatial offsets (dx, dy) per position\n        mask   = torch.sigmoid(om[:, 2*k2:])  # modulation in (0, 1)\n        return self.dcn(x, offset, mask)\n\ndcn = DCNv2(64, 128, kernel_size=3, padding=1)\nx = torch.randn(2, 64, 28, 28)\nout = dcn(x)\nprint(f\"Input:  {x.shape}\")\nprint(f\"Output: {out.shape}\")\nprint(f\"Offset+mask conv params: {sum(p.numel() for p in dcn.offset_mask.parameters()):,}\")\nprint(f\"DCN kernel params:       {sum(p.numel() for p in dcn.dcn.parameters()):,}\")\nprint(\"mask=sigmoid(logit) in (0,1) -\u003e attends to relevant sampling positions\")"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport matplotlib\nmatplotlib.use(\u0027Agg\u0027)\nimport matplotlib.pyplot as plt\nimport numpy as np\n\ndef visualize_offsets(offsets, kernel_size=3, loc=(14, 14), save_path=\u0027deform_offsets.png\u0027):\n    \"\"\"Visualize where a deformable conv samples vs standard conv at a given location.\"\"\"\n    k = kernel_size\n    r = k // 2\n    # Standard grid positions relative to center\n    gy, gx = np.meshgrid(range(-r, r+1), range(-r, r+1), indexing=\u0027ij\u0027)\n    base_y, base_x = gy.ravel(), gx.ravel()\n\n    # Learned offsets at the query location\n    k2 = k * k\n    dy = offsets[0, :k2,  loc[0], loc[1]].detach().numpy()\n    dx = offsets[0, k2:, loc[0], loc[1]].detach().numpy()\n\n    sample_y = loc[0] + base_y + dy\n    sample_x = loc[1] + base_x + dx\n\n    plt.figure(figsize=(5, 5))\n    plt.scatter(loc[1] + base_x, loc[0] + base_y, c=\u0027blue\u0027, s=100,\n                label=\u0027Standard conv\u0027, marker=\u0027s\u0027, zorder=3)\n    plt.scatter(sample_x, sample_y, c=\u0027red\u0027, s=100,\n                label=\u0027Deformable conv\u0027, marker=\u0027o\u0027, zorder=3)\n    for bx, by, sx, sy in zip(loc[1]+base_x, loc[0]+base_y, sample_x, sample_y):\n        plt.arrow(bx, by, sx-bx, sy-by, color=\u0027gray\u0027, head_width=0.3, alpha=0.5)\n    plt.legend()\n    plt.title(\u0027Sampling locations: standard (blue) vs deformable (red)\u0027)\n    plt.savefig(save_path, dpi=100, bbox_inches=\u0027tight\u0027)\n    plt.close()\n    print(f\u0027Saved {save_path}\u0027)\n\n# Simulate trained offsets (non-zero = deformation from standard grid)\noffsets = torch.randn(1, 18, 28, 28) * 2.5\nvisualize_offsets(offsets, kernel_size=3, loc=(14, 14))"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\nfrom torchvision.ops import DeformConv2d\n\nclass StdConvBlock(nn.Module):\n    def __init__(self, in_ch, out_ch):\n        super().__init__()\n        self.conv = nn.Conv2d(in_ch, out_ch, 3, padding=1)\n    def forward(self, x):\n        return F.relu(self.conv(x))\n\nclass DeformConvBlock(nn.Module):\n    def __init__(self, in_ch, out_ch):\n        super().__init__()\n        self.offset = nn.Conv2d(in_ch, 18, 3, padding=1)  # 2*3*3=18\n        self.dcn    = DeformConv2d(in_ch, out_ch, 3, padding=1)\n        nn.init.zeros_(self.offset.weight)\n        nn.init.zeros_(self.offset.bias)\n    def forward(self, x):\n        return F.relu(self.dcn(x, self.offset(x)))\n\n# Test on rotated feature map: does deformable conv adapt better?\ntorch.manual_seed(0)\nx = torch.randn(1, 3, 32, 32)\nx_rot = torch.rot90(x, k=1, dims=[2, 3])\n\nstd   = StdConvBlock(3, 64)\ndeform = DeformConvBlock(3, 64)\n\nwith torch.no_grad():\n    diff_std   = (std(x) - std(x_rot)).abs().mean().item()\n    diff_deform = (deform(x) - deform(x_rot)).abs().mean().item()\n\nprint(f\"Standard conv response diff (90-deg rotation): {diff_std:.4f}\")\nprint(f\"Deformable conv response diff:                  {diff_deform:.4f}\")\nprint(\"After training, deformable conv learns offsets that compensate for rotation\")\nprint(\"and other geometric transforms (scale, shear) without explicit augmentation\")"},{"type":"heading","level":2,"content":"DCNv3 and Efficiency Improvements"},{"type":"text","content":"DCNv3 (InternImage, CVPR 2023) introduces grouped deformable convolution: instead of learning one set of offsets and modulations for all channels, it uses G groups each with their own offsets and modulations, similar to grouped convolution or multi-head attention. The output is the sum across groups. DCNv3 also separates the spatial aggregation (deformable sampling) from the channel projection, reducing parameter count. InternImage-H with DCNv3 achieves 89.6% on ImageNet and 65.4 box AP on COCO, setting new state-of-the-art for CNN-based architectures at the time of publication."},{"type":"heading","level":2,"content":"Applications in Object Detection"},{"type":"text","content":"Deformable convolutions are particularly powerful in detection backbones because objects vary in scale and aspect ratio. Replacing standard 3×3 convs in ResNet stage 3 and 4 with DCNv2 consistently adds +2–4% AP on COCO without any other change. Mask R-CNN with DCNv2 improves both box AP and mask AP. The offset patterns learned by detection networks are interpretable: for a car, offsets cluster around wheel positions; for a person, they cluster around joints and torso. This geometric adaptivity replaces the need for explicit multi-scale feature aggregation in some designs."},{"type":"heading","level":2,"content":"Convolution Variant Comparison"},{"type":"table","headers":["Variant","Sampling Pattern","Extra Params (k=3)","Bilinear Interp","Geometric Flexibility","Best Use Case"],"rows":[["Standard Conv","Fixed 3×3 grid","None","No","None — rigid","General feature extraction"],["Deformable Conv v1","Learned offsets Δpₙ per position","2×k² per layer","Yes","High — free offsets","Shape-adaptive detection"],["Deformable Conv v2","Offsets + modulation mₙ ∈ (0,1)","3×k² per layer","Yes","High + amplitude control","Detection, segmentation"],["Deformable Conv v3","Grouped offsets + modulation","3×k²/G per group","Yes","High + channel grouping","Efficient large-scale backbone"]]},{"type":"heading","level":2,"content":"Implementation Notes"},{"type":"text","content":"When using deformable convolutions in practice, keep these points in mind: (1) Zero-initialize the offset branch weights and biases so training starts from a standard conv and deformations are learned gradually; (2) Clip offsets to a reasonable range (typically ±(k-1)) to prevent sampling outside the feature map — torchvision\u0027s DeformConv2d handles border padding automatically; (3) Use DCNv2 (with modulation) over DCNv1 in all detection scenarios — the modulation provides meaningful accuracy gains with minimal overhead; (4) Place deformable convolutions in the deeper stages (stage 3, 4 in ResNet) where semantic features benefit most from shape adaptation; (5) Learning rate for the offset branch may need tuning — starting with a lower LR for offsets (0.1× backbone LR) can improve stability."},{"type":"list","ordered":false,"items":["DCNv1: offset Δpₙ per kernel position; bilinear interpolation at p + pₙ + Δpₙ.","DCNv2: offset + modulation mₙ ∈ (0,1); effectively sparse attention over sampling grid.","DCNv3: grouped offsets; shared offset per group of channels; used in InternImage.","Zero-init offsets: deformable conv degrades to standard conv at initialization.","Practical gain: +2-4 AP on COCO by replacing standard 3×3 in ResNet stages 3-4.","torchvision.ops.DeformConv2d: takes (x, offset) or (x, offset, mask) for DCNv2."]}]"
---
# Deformable Convolutions — Learned Geometric Offsets

Standard convolutions apply a fixed k×k grid of kernel weights to each spatial location — the sampling pattern never adapts to the content of the image. Deformable Convolutions (Dai et al., ICCV 2017) break this constraint by learning 2D spatial offsets Δpₙ for each of the k² kernel positions. The convolution then samples at perturbed locations x + pₙ + Δpₙ using bilinear interpolation for fractional coordinates. The offsets are learned by an additional lightweight convolutional branch, making the operation end-to-end differentiable. Deformable convolutions dramatically improve detection and segmentation of objects with arbitrary shapes and sizes.

## Limitations of Standard Convolutions

A k×k convolution samples k² fixed relative positions: pₙ ∈ {(-1,-1), (-1,0), ..., (1,1)} for k=3. These positions are fixed regardless of the input — the same grid is applied to a thin vertical line, a large circle, and a diagonal edge. This fixed receptive field is poorly suited to objects that vary in scale, aspect ratio, and orientation. Pooling and large strides provide some scale invariance, but they cannot adapt the sampling geometry to match object shape. Augmentation (random rotation, scaling) helps training but does not give the network the ability to dynamically adjust its feature extraction pattern at inference.

## Deformable Convolution v1

DCNv1 adds a parallel offset-generating conv branch that takes the input feature map and outputs 2×k² channels — two channels (Δx, Δy) for each of the k² kernel positions. These offsets are added to the standard grid positions, and the feature map is sampled at the resulting fractional locations using bilinear interpolation: y(p) = Σₙ w(pₙ) · x(p + pₙ + Δpₙ). The bilinear interpolation makes the operation differentiable with respect to Δpₙ, allowing gradients to flow through the sampling locations during backpropagation. The offset conv branch is initialized with zero weights so that deformable conv starts as standard conv at the beginning of training.

## Deformable Convolution v2 — Modulation Scalars

DCNv2 (Zhu et al., CVPR 2019) extends DCNv1 by additionally learning a modulation scalar mₙ ∈ (0, 1) for each of the k² sampling positions. The modulated sampling becomes: y(p) = Σₙ w(pₙ) · mₙ · x(p + pₙ + Δpₙ). The modulation scalars act as attention weights over the sampling positions — the network can effectively zero out irrelevant sampling locations while amplifying important ones. The combined offset+modulation branch outputs 3×k² channels: 2×k² for (Δx, Δy) offsets and k² for mₙ scalars (passed through Sigmoid to keep in (0,1)). DCNv2 significantly outperforms DCNv1 on detection because it can ignore background samples that fall outside the object boundary.

> **DCNv2 = Deformable + Amplitude Modulation**: DCNv2 combines spatial deformation (where to sample) with amplitude modulation (how much to weight each sample). This gives it two degrees of freedom versus standard conv (fixed location, fixed weight) and DCNv1 (free location, fixed unit weight). The modulation effectively makes the sampling pattern sparse and object-adaptive: for a car, the network learns to sample wheel and window positions with high weight and background with near-zero weight.

## Code Examples

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class OffsetGenerator(nn.Module):
    """Learn per-position 2D offsets for a k x k deformable conv kernel."""
    def __init__(self, in_ch, kernel_size=3):
        super().__init__()
        self.k = kernel_size
        n_offsets = 2 * kernel_size * kernel_size  # (dx, dy) per position
        self.offset_conv = nn.Conv2d(in_ch, n_offsets, kernel_size=3, padding=1)
        # Zero-init: deformable conv starts as standard conv
        nn.init.zeros_(self.offset_conv.weight)
        nn.init.zeros_(self.offset_conv.bias)

    def forward(self, x):
        offsets = self.offset_conv(x)   # (B, 2*k^2, H, W)
        return offsets

# Demonstrate offset shapes
gen = OffsetGenerator(in_ch=64, kernel_size=3)
x = torch.randn(2, 64, 28, 28)
offsets = gen(x)
print(f"Input feature map: {x.shape}")
print(f"Offsets shape:     {offsets.shape}  (2 * 3*3 = 18 channels)")
print(f"Interpretation:    offset[b, 2n,   h, w] = delta_x for position n at (h,w)")
print(f"                   offset[b, 2n+1, h, w] = delta_y for position n at (h,w)")
print(f"Zero-init means: at start of training, all offsets=0 -> standard conv")
print(f"Params in offset branch: {sum(p.numel() for p in gen.parameters()):,}")
```

```python
import torch
import torch.nn as nn
from torchvision.ops import DeformConv2d

class DCNv2(nn.Module):
    """Deformable Conv v2: offsets + modulation scalars via torchvision."""
    def __init__(self, in_ch, out_ch, kernel_size=3, stride=1, padding=1):
        super().__init__()
        k2 = kernel_size * kernel_size
        # Branch: predict 2*k^2 offsets + k^2 modulation scalars
        self.offset_mask = nn.Conv2d(in_ch, 3 * k2, 3, stride=1, padding=1)
        self.dcn = DeformConv2d(in_ch, out_ch, kernel_size, stride=stride, padding=padding)
        nn.init.zeros_(self.offset_mask.weight)
        nn.init.zeros_(self.offset_mask.bias)

    def forward(self, x):
        om = self.offset_mask(x)          # (B, 3*k^2, H, W)
        k2 = om.shape[1] // 3
        offset = om[:, :2*k2]             # spatial offsets (dx, dy) per position
        mask   = torch.sigmoid(om[:, 2*k2:])  # modulation in (0, 1)
        return self.dcn(x, offset, mask)

dcn = DCNv2(64, 128, kernel_size=3, padding=1)
x = torch.randn(2, 64, 28, 28)
out = dcn(x)
print(f"Input:  {x.shape}")
print(f"Output: {out.shape}")
print(f"Offset+mask conv params: {sum(p.numel() for p in dcn.offset_mask.parameters()):,}")
print(f"DCN kernel params:       {sum(p.numel() for p in dcn.dcn.parameters()):,}")
print("mask=sigmoid(logit) in (0,1) -> attends to relevant sampling positions")
```

```python
import torch
import torch.nn as nn
import matplotlib
matplotlib.use('Agg')
import matplotlib.pyplot as plt
import numpy as np

def visualize_offsets(offsets, kernel_size=3, loc=(14, 14), save_path='deform_offsets.png'):
    """Visualize where a deformable conv samples vs standard conv at a given location."""
    k = kernel_size
    r = k // 2
    # Standard grid positions relative to center
    gy, gx = np.meshgrid(range(-r, r+1), range(-r, r+1), indexing='ij')
    base_y, base_x = gy.ravel(), gx.ravel()

    # Learned offsets at the query location
    k2 = k * k
    dy = offsets[0, :k2,  loc[0], loc[1]].detach().numpy()
    dx = offsets[0, k2:, loc[0], loc[1]].detach().numpy()

    sample_y = loc[0] + base_y + dy
    sample_x = loc[1] + base_x + dx

    plt.figure(figsize=(5, 5))
    plt.scatter(loc[1] + base_x, loc[0] + base_y, c='blue', s=100,
                label='Standard conv', marker='s', zorder=3)
    plt.scatter(sample_x, sample_y, c='red', s=100,
                label='Deformable conv', marker='o', zorder=3)
    for bx, by, sx, sy in zip(loc[1]+base_x, loc[0]+base_y, sample_x, sample_y):
        plt.arrow(bx, by, sx-bx, sy-by, color='gray', head_width=0.3, alpha=0.5)
    plt.legend()
    plt.title('Sampling locations: standard (blue) vs deformable (red)')
    plt.savefig(save_path, dpi=100, bbox_inches='tight')
    plt.close()
    print(f'Saved {save_path}')

# Simulate trained offsets (non-zero = deformation from standard grid)
offsets = torch.randn(1, 18, 28, 28) * 2.5
visualize_offsets(offsets, kernel_size=3, loc=(14, 14))
```

```python
import torch
import torch.nn as nn
import torch.nn.functional as F
from torchvision.ops import DeformConv2d

class StdConvBlock(nn.Module):
    def __init__(self, in_ch, out_ch):
        super().__init__()
        self.conv = nn.Conv2d(in_ch, out_ch, 3, padding=1)
    def forward(self, x):
        return F.relu(self.conv(x))

class DeformConvBlock(nn.Module):
    def __init__(self, in_ch, out_ch):
        super().__init__()
        self.offset = nn.Conv2d(in_ch, 18, 3, padding=1)  # 2*3*3=18
        self.dcn    = DeformConv2d(in_ch, out_ch, 3, padding=1)
        nn.init.zeros_(self.offset.weight)
        nn.init.zeros_(self.offset.bias)
    def forward(self, x):
        return F.relu(self.dcn(x, self.offset(x)))

# Test on rotated feature map: does deformable conv adapt better?
torch.manual_seed(0)
x = torch.randn(1, 3, 32, 32)
x_rot = torch.rot90(x, k=1, dims=[2, 3])

std   = StdConvBlock(3, 64)
deform = DeformConvBlock(3, 64)

with torch.no_grad():
    diff_std   = (std(x) - std(x_rot)).abs().mean().item()
    diff_deform = (deform(x) - deform(x_rot)).abs().mean().item()

print(f"Standard conv response diff (90-deg rotation): {diff_std:.4f}")
print(f"Deformable conv response diff:                  {diff_deform:.4f}")
print("After training, deformable conv learns offsets that compensate for rotation")
print("and other geometric transforms (scale, shear) without explicit augmentation")
```

## DCNv3 and Efficiency Improvements

DCNv3 (InternImage, CVPR 2023) introduces grouped deformable convolution: instead of learning one set of offsets and modulations for all channels, it uses G groups each with their own offsets and modulations, similar to grouped convolution or multi-head attention. The output is the sum across groups. DCNv3 also separates the spatial aggregation (deformable sampling) from the channel projection, reducing parameter count. InternImage-H with DCNv3 achieves 89.6% on ImageNet and 65.4 box AP on COCO, setting new state-of-the-art for CNN-based architectures at the time of publication.

## Applications in Object Detection

Deformable convolutions are particularly powerful in detection backbones because objects vary in scale and aspect ratio. Replacing standard 3×3 convs in ResNet stage 3 and 4 with DCNv2 consistently adds +2–4% AP on COCO without any other change. Mask R-CNN with DCNv2 improves both box AP and mask AP. The offset patterns learned by detection networks are interpretable: for a car, offsets cluster around wheel positions; for a person, they cluster around joints and torso. This geometric adaptivity replaces the need for explicit multi-scale feature aggregation in some designs.

## Convolution Variant Comparison

| Variant | Sampling Pattern | Extra Params (k=3) | Bilinear Interp | Geometric Flexibility | Best Use Case |
| --- | --- | --- | --- | --- | --- |
| Standard Conv | Fixed 3×3 grid | None | No | None — rigid | General feature extraction |
| Deformable Conv v1 | Learned offsets Δpₙ per position | 2×k² per layer | Yes | High — free offsets | Shape-adaptive detection |
| Deformable Conv v2 | Offsets + modulation mₙ ∈ (0,1) | 3×k² per layer | Yes | High + amplitude control | Detection, segmentation |
| Deformable Conv v3 | Grouped offsets + modulation | 3×k²/G per group | Yes | High + channel grouping | Efficient large-scale backbone |

## Implementation Notes

When using deformable convolutions in practice, keep these points in mind: (1) Zero-initialize the offset branch weights and biases so training starts from a standard conv and deformations are learned gradually; (2) Clip offsets to a reasonable range (typically ±(k-1)) to prevent sampling outside the feature map — torchvision's DeformConv2d handles border padding automatically; (3) Use DCNv2 (with modulation) over DCNv1 in all detection scenarios — the modulation provides meaningful accuracy gains with minimal overhead; (4) Place deformable convolutions in the deeper stages (stage 3, 4 in ResNet) where semantic features benefit most from shape adaptation; (5) Learning rate for the offset branch may need tuning — starting with a lower LR for offsets (0.1× backbone LR) can improve stability.

- DCNv1: offset Δpₙ per kernel position; bilinear interpolation at p + pₙ + Δpₙ.
- DCNv2: offset + modulation mₙ ∈ (0,1); effectively sparse attention over sampling grid.
- DCNv3: grouped offsets; shared offset per group of channels; used in InternImage.
- Zero-init offsets: deformable conv degrades to standard conv at initialization.
- Practical gain: +2-4 AP on COCO by replacing standard 3×3 in ResNet stages 3-4.
- torchvision.ops.DeformConv2d: takes (x, offset) or (x, offset, mask) for DCNv2.

