---
title: "Receptive Field — Theoretical vs Effective, Depth and Dilation"
slug: "receptive-field-cnn"
description: "Compute theoretical receptive fields layer by layer, understand why the effective RF is Gaussian-shaped, and compare RF expansion strategies across architectures."
tags: ["deep-learning", "cnns"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"The receptive field (RF) of a neuron in a CNN is the region of the input image that can influence its activation. RF size determines what the network can \u0027see\u0027 — too small and it misses global context needed for object recognition; too large and it processes irrelevant background. Understanding how RF grows with depth, stride, dilation, and kernel size lets architects make deliberate design decisions rather than treating the RF as an afterthought. A key insight from Luo et al. (2017): the effective RF — the region that actually influences the output in proportion to gradient magnitude — is much smaller and Gaussian-shaped, not the full theoretical square."},{"type":"heading","level":2,"content":"Theoretical Receptive Field Formula"},{"type":"text","content":"For a network with L layers, the theoretical RF can be computed recursively. Let RF₀ = 1 (single input pixel). After layer l with kernel size kₗ and stride sₗ: RF_l = RF_{l-1} + (kₗ - 1) · Πᵢ₌₁ˡ⁻¹ sᵢ. Equivalently, RF_l = RF_{l-1} + (kₗ - 1) · jump_{l-1}, where jump_{l-1} = Πᵢ\u003cl sᵢ is the stride accumulated up to layer l-1. For n stacked 3×3 convs with stride 1: RF = 2n+1. For n stacked 3×3 convs with stride 2: RF grows exponentially. Pooling layers count as convolutions with stride equal to the pool size. A 1×1 conv does not increase the RF."},{"type":"code","language":"python","content":"def compute_rf(layers):\n    \"\"\"\n    Compute theoretical receptive field layer-by-layer.\n    layers: list of dicts with keys \u0027name\u0027, \u0027kernel\u0027, \u0027stride\u0027, \u0027dilation\u0027.\n    Returns list of (name, rf, jump, dilation_eff_kernel).\n    \"\"\"\n    rf, jump = 1, 1\n    results = []\n    for l in layers:\n        k = l.get(\u0027kernel\u0027, 1)\n        s = l.get(\u0027stride\u0027, 1)\n        d = l.get(\u0027dilation\u0027, 1)\n        eff_k = (k - 1) * d + 1  # effective kernel size with dilation\n        rf = rf + (eff_k - 1) * jump\n        jump = jump * s\n        results.append((l[\u0027name\u0027], rf, jump))\n    return results\n\n# VGG-style: five blocks of 3x3 convs + max-pool\nvgg_layers = [\n    *[{\u0027name\u0027: f\u0027block1_conv{i}\u0027, \u0027kernel\u0027: 3, \u0027stride\u0027: 1} for i in range(1,3)],\n    {\u0027name\u0027: \u0027pool1\u0027, \u0027kernel\u0027: 2, \u0027stride\u0027: 2},\n    *[{\u0027name\u0027: f\u0027block2_conv{i}\u0027, \u0027kernel\u0027: 3, \u0027stride\u0027: 1} for i in range(1,3)],\n    {\u0027name\u0027: \u0027pool2\u0027, \u0027kernel\u0027: 2, \u0027stride\u0027: 2},\n    *[{\u0027name\u0027: f\u0027block3_conv{i}\u0027, \u0027kernel\u0027: 3, \u0027stride\u0027: 1} for i in range(1,3)],\n    {\u0027name\u0027: \u0027pool3\u0027, \u0027kernel\u0027: 2, \u0027stride\u0027: 2},\n]\nprint(f\u0027{\u0027Layer\u0027:\u003c18} {\u0027Theor. RF\u0027:\u003e10} {\u0027Jump\u0027:\u003e6}\u0027)\nfor name, rf, jump in compute_rf(vgg_layers):\n    print(f\u0027{name:\u003c18} {rf:\u003e10} {jump:\u003e6}\u0027)"},{"type":"heading","level":2,"content":"Effective Receptive Field"},{"type":"text","content":"Luo et al. (2017) showed that the effective RF — measured as the gradient of the centre output unit with respect to all input pixels — is approximately Gaussian, not uniform over the theoretical RF square. Central pixels contribute exponentially more than peripheral ones due to the multiplicative path-count effect: a pixel at the centre of the RF passes through more overlapping kernel windows than one at the edge. The effective RF typically spans about √(theoretical RF) in practice. This means a ResNet-50 with a theoretical RF of 483×483 on ImageNet has an effective RF of roughly 100×100. Increasing depth beyond a certain point gives diminishing returns on effective context."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport numpy as np\n\ndef estimate_effective_rf(model, input_size=(1, 3, 224, 224)):\n    \"\"\"Gradient-based effective receptive field estimation.\"\"\"\n    x = torch.zeros(input_size, requires_grad=True)\n    # Forward pass\n    out = model(x)\n    # Gradient of centre output w.r.t. input\n    centre = out[0, 0, out.shape[2]//2, out.shape[3]//2]\n    centre.backward()\n    grad = x.grad[0].abs().mean(dim=0).detach().numpy()  # (H, W)\n    # Normalise\n    grad = grad / grad.max()\n    # Estimate effective RF as region with grad \u003e threshold\n    threshold = 0.1\n    mask = (grad \u003e threshold)\n    rows = np.any(mask, axis=1)\n    cols = np.any(mask, axis=0)\n    h_eff = rows.sum()\n    w_eff = cols.sum()\n    return grad, h_eff, w_eff\n\n# Use a small custom network for demonstration\nnet = nn.Sequential(\n    nn.Conv2d(3, 32, 3, padding=1), nn.ReLU(),\n    nn.Conv2d(32, 32, 3, padding=1), nn.ReLU(),\n    nn.Conv2d(32, 32, 3, padding=1), nn.ReLU(),\n    nn.Conv2d(32, 1, 3, padding=1),\n)\ngrad, h_eff, w_eff = estimate_effective_rf(net, (1, 3, 32, 32))\ntheor_rf = 2 * 4 + 1  # 4 layers of k=3, s=1\nprint(f\u0027Theoretical RF: {theor_rf}x{theor_rf}\u0027)\nprint(f\u0027Effective RF (grad\u003e0.1): {h_eff}x{w_eff}\u0027)\nprint(f\u0027Gradient is Gaussian-shaped, not uniform rectangular.\u0027)"},{"type":"heading","level":2,"content":"RF Growth with Dilation"},{"type":"text","content":"Dilated convolutions expand the RF without increasing parameters or reducing spatial resolution. A 3×3 conv with dilation d has effective kernel size (3-1)·d+1. Stacking three 3×3 dilated convs with rates d=[1,2,4]: RF contributions are 3, 5, 9 (effective kernel sizes). With stride=1, the total RF = 1 + (3-1) + (5-1)·1 + (9-1)·1 = 15 vs 7 for standard (three d=1 convs). WaveNet used exponentially growing dilation [1,2,4,...,512] in each block, achieving an RF of 1024 samples at 16kHz = 64ms context. DeepLabV3 uses dilations [6,12,18] in ASPP for multi-scale context in segmentation."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ndef rf_with_dilation(dilations, k=3):\n    \"\"\"Compare RF for stacked dilated 3x3 convs vs standard.\"\"\"\n    rf_std = 1 + len(dilations) * (k - 1)  # all dilation=1\n    rf_dil = 1\n    for d in dilations:\n        eff_k = (k - 1) * d + 1\n        rf_dil += eff_k - 1\n    return rf_std, rf_dil\n\nprint(f\u0027{\u0027Dilations\u0027:\u003c30} {\u0027Std RF\u0027:\u003e8} {\u0027Dilated RF\u0027:\u003e12} {\u0027Gain\u0027:\u003e8}\u0027)\nfor dilations in [\n    [1, 1, 1],\n    [1, 2, 4],\n    [1, 2, 4, 8],\n    [1, 2, 4, 8, 16],\n    [1, 2, 4, 8, 16, 32],\n    [6, 12, 18],         # DeepLab ASPP\n    [1, 2, 5],           # Hybrid dilated conv (HDC)\n]:\n    std, dil = rf_with_dilation(dilations)\n    print(f\u0027{str(dilations):\u003c30} {std:\u003e8} {dil:\u003e12} {dil/std:\u003e7.1f}x\u0027)\n\nprint(\u0027\\nDilation multiplies RF with no extra parameters.\u0027)\nprint(\u0027HDC [1,2,5]: avoids gridding artifact (all positions covered).\u0027)"},{"type":"callout","variant":"info","title":"Transformer Global RF from Layer 1","content":"Vision Transformers (ViT) divide the image into patches and apply self-attention across all patch tokens. Every token attends to every other token from the very first layer — the receptive field is global immediately. CNNs build up their RF incrementally through depth. This is why ViTs excel at tasks requiring long-range dependencies (e.g., detecting relationships between distant image regions), while CNNs with local inductive bias often need fewer data to converge on spatially local tasks."},{"type":"heading","level":2,"content":"Architecture RF Comparison"},{"type":"text","content":"Different architectures achieve large RFs through different strategies. VGG-16 uses 13 conv layers of 3×3 with periodic 2×2 max-pooling, reaching a theoretical RF of 212×212 on the final conv layer. ResNet-50 uses bottleneck blocks with 1×1, 3×3, 1×1 convs and stride-2 for downsampling. The 1×1 convs do not grow the RF. DeepLab adds dilated convs to ResNet\u0027s later stages to prevent shrinking the RF while removing strides. ViT patches (16×16) give a fixed patch-level RF of 16 initially, then global through attention."},{"type":"code","language":"python","content":"import torchvision.models as models\nimport torch\n\ndef resnet50_rf():\n    \"\"\"Compute theoretical RF through ResNet-50 up to layer4.\"\"\"\n    layers = [\n        {\u0027name\u0027: \u0027conv1 7x7 s2\u0027,  \u0027kernel\u0027: 7, \u0027stride\u0027: 2},\n        {\u0027name\u0027: \u0027maxpool 3x3 s2\u0027,\u0027kernel\u0027: 3, \u0027stride\u0027: 2},\n        # layer1: 3 bottleneck blocks, each has 1x1, 3x3, 1x1\n        *[{\u0027name\u0027: f\u0027l1.{i}.{n}\u0027, \u0027kernel\u0027: k, \u0027stride\u0027: 1}\n          for i in range(3) for k, n in [(1,\u0027pw1\u0027),(3,\u0027conv\u0027),(1,\u0027pw2\u0027)]],\n        # layer2: stride-2 on first block\u0027s 3x3\n        {\u0027name\u0027: \u0027l2.0.pw1\u0027, \u0027kernel\u0027: 1, \u0027stride\u0027: 1},\n        {\u0027name\u0027: \u0027l2.0.conv\u0027, \u0027kernel\u0027: 3, \u0027stride\u0027: 2},\n        {\u0027name\u0027: \u0027l2.0.pw2\u0027, \u0027kernel\u0027: 1, \u0027stride\u0027: 1},\n        *[{\u0027name\u0027: f\u0027l2.{i}.{n}\u0027, \u0027kernel\u0027: k, \u0027stride\u0027: 1}\n          for i in range(1,4) for k, n in [(1,\u0027pw1\u0027),(3,\u0027conv\u0027),(1,\u0027pw2\u0027)]],\n    ]\n    rf, jump = 1, 1\n    for l in layers:\n        k, s = l[\u0027kernel\u0027], l[\u0027stride\u0027]\n        rf = rf + (k - 1) * jump\n        jump *= s\n    return rf, jump\n\nrf, jump = resnet50_rf()\nprint(f\u0027ResNet-50 theoretical RF after layer2: {rf}x{rf}\u0027)\nprint(f\u0027Total stride (jump): {jump}\u0027)\nprint(\u0027ResNet-50 full theoretical RF at output: ~483x483\u0027)\nprint(\u0027Effective RF typically ~100x100 (Gaussian centre-weighted)\u0027)"},{"type":"heading","level":2,"content":"RF Design Guidelines"},{"type":"text","content":"Practical RF design follows a few guiding principles. For image classification, the RF should cover most of the input by the final conv layer — a 224×224 image needs an RF of at least 100–150 effective pixels. For object detection, the RF should match the object scale at each detection head — FPN (Feature Pyramid Network) uses multiple scales explicitly. For segmentation without downsampling (e.g., medical images), dilated conv is preferred to maintain resolution while expanding RF. For audio (e.g., WaveNet), exponentially growing dilation gives logarithmic RF growth — efficient for long-range temporal dependencies."},{"type":"table","headers":["RF Growth Strategy","RF Per Layer","Extra Params","Extra FLOPs","Spatial Resolution","Use Case"],"rows":[["Stack 3×3 (s=1)","+2 per layer (linear)","None","None","Preserved","Depth-first, cheap local growth"],["Dilation d","+(2d) per layer","None","None","Preserved","Segmentation, audio (DeepLab, WaveNet)"],["Stride 2 / Pool","×2 multiplier","None","None","Halved","Classification, detection backbone"],["Larger kernel k","+k-1 per layer","×(k/3)²","×(k/3)²","Preserved","Rare; two 3×3 preferred over one 5×5"],["Global attention","Full image (1 layer)","O(n²) QKV","O(n²·d)","Preserved","ViT, SASA, non-local networks"]]},{"type":"heading","level":2,"content":"Effective RF and Feature Importance"},{"type":"text","content":"Because the effective RF is Gaussian-shaped and much smaller than the theoretical RF, architectural choices that seem to provide sufficient context may not in practice. Attention mechanisms (CBAM, SE blocks, Transformer layers) complement CNNs by providing a bypass route for long-range dependency modelling that the Gaussian-shaped ERF suppresses. Class Activation Mapping (CAM) and Grad-CAM exploit the spatial RF structure to visualise which input regions drive a classification decision, serving as a diagnostic tool for checking whether the network\u0027s attended regions match human intuition."},{"type":"text","content":"Deformable convolutions (Dai et al. 2017) learn spatial offsets for each kernel sampling location so the RF adapts dynamically to object shape rather than remaining a fixed grid. This improves detection of objects with irregular shapes and large aspect ratios. Deformable DETR uses deformable attention for multi-scale feature aggregation with adaptive RF. Dilated Residual Networks (DRN) remove strides in ResNet\u0027s last two stages and compensate with increasing dilation rates to maintain the full theoretical RF at higher spatial resolution."},{"type":"list","ordered":false,"items":["Grad-CAM uses the gradient of class score w.r.t. the last conv feature map for class-specific saliency maps.","Local Attention (SASA) restricts self-attention to a local window — explicit RF control with O(n·w²) cost.","torch.fx can trace a model graph and compute theoretical RF by tracking tensor shapes layer by layer.","RF mismatch: if an object is larger than the network\u0027s ERF, accuracy collapses — a common failure mode on high-res inputs."]},{"type":"divider"}]"
---
# Receptive Field — Theoretical vs Effective, Depth and Dilation

The receptive field (RF) of a neuron in a CNN is the region of the input image that can influence its activation. RF size determines what the network can 'see' — too small and it misses global context needed for object recognition; too large and it processes irrelevant background. Understanding how RF grows with depth, stride, dilation, and kernel size lets architects make deliberate design decisions rather than treating the RF as an afterthought. A key insight from Luo et al. (2017): the effective RF — the region that actually influences the output in proportion to gradient magnitude — is much smaller and Gaussian-shaped, not the full theoretical square.

## Theoretical Receptive Field Formula

For a network with L layers, the theoretical RF can be computed recursively. Let RF₀ = 1 (single input pixel). After layer l with kernel size kₗ and stride sₗ: RF_l = RF_{l-1} + (kₗ - 1) · Πᵢ₌₁ˡ⁻¹ sᵢ. Equivalently, RF_l = RF_{l-1} + (kₗ - 1) · jump_{l-1}, where jump_{l-1} = Πᵢ<l sᵢ is the stride accumulated up to layer l-1. For n stacked 3×3 convs with stride 1: RF = 2n+1. For n stacked 3×3 convs with stride 2: RF grows exponentially. Pooling layers count as convolutions with stride equal to the pool size. A 1×1 conv does not increase the RF.

```python
def compute_rf(layers):
    """
    Compute theoretical receptive field layer-by-layer.
    layers: list of dicts with keys 'name', 'kernel', 'stride', 'dilation'.
    Returns list of (name, rf, jump, dilation_eff_kernel).
    """
    rf, jump = 1, 1
    results = []
    for l in layers:
        k = l.get('kernel', 1)
        s = l.get('stride', 1)
        d = l.get('dilation', 1)
        eff_k = (k - 1) * d + 1  # effective kernel size with dilation
        rf = rf + (eff_k - 1) * jump
        jump = jump * s
        results.append((l['name'], rf, jump))
    return results

# VGG-style: five blocks of 3x3 convs + max-pool
vgg_layers = [
    *[{'name': f'block1_conv{i}', 'kernel': 3, 'stride': 1} for i in range(1,3)],
    {'name': 'pool1', 'kernel': 2, 'stride': 2},
    *[{'name': f'block2_conv{i}', 'kernel': 3, 'stride': 1} for i in range(1,3)],
    {'name': 'pool2', 'kernel': 2, 'stride': 2},
    *[{'name': f'block3_conv{i}', 'kernel': 3, 'stride': 1} for i in range(1,3)],
    {'name': 'pool3', 'kernel': 2, 'stride': 2},
]
print(f'{'Layer':<18} {'Theor. RF':>10} {'Jump':>6}')
for name, rf, jump in compute_rf(vgg_layers):
    print(f'{name:<18} {rf:>10} {jump:>6}')
```

## Effective Receptive Field

Luo et al. (2017) showed that the effective RF — measured as the gradient of the centre output unit with respect to all input pixels — is approximately Gaussian, not uniform over the theoretical RF square. Central pixels contribute exponentially more than peripheral ones due to the multiplicative path-count effect: a pixel at the centre of the RF passes through more overlapping kernel windows than one at the edge. The effective RF typically spans about √(theoretical RF) in practice. This means a ResNet-50 with a theoretical RF of 483×483 on ImageNet has an effective RF of roughly 100×100. Increasing depth beyond a certain point gives diminishing returns on effective context.

```python
import torch
import torch.nn as nn
import numpy as np

def estimate_effective_rf(model, input_size=(1, 3, 224, 224)):
    """Gradient-based effective receptive field estimation."""
    x = torch.zeros(input_size, requires_grad=True)
    # Forward pass
    out = model(x)
    # Gradient of centre output w.r.t. input
    centre = out[0, 0, out.shape[2]//2, out.shape[3]//2]
    centre.backward()
    grad = x.grad[0].abs().mean(dim=0).detach().numpy()  # (H, W)
    # Normalise
    grad = grad / grad.max()
    # Estimate effective RF as region with grad > threshold
    threshold = 0.1
    mask = (grad > threshold)
    rows = np.any(mask, axis=1)
    cols = np.any(mask, axis=0)
    h_eff = rows.sum()
    w_eff = cols.sum()
    return grad, h_eff, w_eff

# Use a small custom network for demonstration
net = nn.Sequential(
    nn.Conv2d(3, 32, 3, padding=1), nn.ReLU(),
    nn.Conv2d(32, 32, 3, padding=1), nn.ReLU(),
    nn.Conv2d(32, 32, 3, padding=1), nn.ReLU(),
    nn.Conv2d(32, 1, 3, padding=1),
)
grad, h_eff, w_eff = estimate_effective_rf(net, (1, 3, 32, 32))
theor_rf = 2 * 4 + 1  # 4 layers of k=3, s=1
print(f'Theoretical RF: {theor_rf}x{theor_rf}')
print(f'Effective RF (grad>0.1): {h_eff}x{w_eff}')
print(f'Gradient is Gaussian-shaped, not uniform rectangular.')
```

## RF Growth with Dilation

Dilated convolutions expand the RF without increasing parameters or reducing spatial resolution. A 3×3 conv with dilation d has effective kernel size (3-1)·d+1. Stacking three 3×3 dilated convs with rates d=[1,2,4]: RF contributions are 3, 5, 9 (effective kernel sizes). With stride=1, the total RF = 1 + (3-1) + (5-1)·1 + (9-1)·1 = 15 vs 7 for standard (three d=1 convs). WaveNet used exponentially growing dilation [1,2,4,...,512] in each block, achieving an RF of 1024 samples at 16kHz = 64ms context. DeepLabV3 uses dilations [6,12,18] in ASPP for multi-scale context in segmentation.

```python
import torch
import torch.nn as nn

def rf_with_dilation(dilations, k=3):
    """Compare RF for stacked dilated 3x3 convs vs standard."""
    rf_std = 1 + len(dilations) * (k - 1)  # all dilation=1
    rf_dil = 1
    for d in dilations:
        eff_k = (k - 1) * d + 1
        rf_dil += eff_k - 1
    return rf_std, rf_dil

print(f'{'Dilations':<30} {'Std RF':>8} {'Dilated RF':>12} {'Gain':>8}')
for dilations in [
    [1, 1, 1],
    [1, 2, 4],
    [1, 2, 4, 8],
    [1, 2, 4, 8, 16],
    [1, 2, 4, 8, 16, 32],
    [6, 12, 18],         # DeepLab ASPP
    [1, 2, 5],           # Hybrid dilated conv (HDC)
]:
    std, dil = rf_with_dilation(dilations)
    print(f'{str(dilations):<30} {std:>8} {dil:>12} {dil/std:>7.1f}x')

print('\nDilation multiplies RF with no extra parameters.')
print('HDC [1,2,5]: avoids gridding artifact (all positions covered).')
```

> **Transformer Global RF from Layer 1**: Vision Transformers (ViT) divide the image into patches and apply self-attention across all patch tokens. Every token attends to every other token from the very first layer — the receptive field is global immediately. CNNs build up their RF incrementally through depth. This is why ViTs excel at tasks requiring long-range dependencies (e.g., detecting relationships between distant image regions), while CNNs with local inductive bias often need fewer data to converge on spatially local tasks.

## Architecture RF Comparison

Different architectures achieve large RFs through different strategies. VGG-16 uses 13 conv layers of 3×3 with periodic 2×2 max-pooling, reaching a theoretical RF of 212×212 on the final conv layer. ResNet-50 uses bottleneck blocks with 1×1, 3×3, 1×1 convs and stride-2 for downsampling. The 1×1 convs do not grow the RF. DeepLab adds dilated convs to ResNet's later stages to prevent shrinking the RF while removing strides. ViT patches (16×16) give a fixed patch-level RF of 16 initially, then global through attention.

```python
import torchvision.models as models
import torch

def resnet50_rf():
    """Compute theoretical RF through ResNet-50 up to layer4."""
    layers = [
        {'name': 'conv1 7x7 s2',  'kernel': 7, 'stride': 2},
        {'name': 'maxpool 3x3 s2','kernel': 3, 'stride': 2},
        # layer1: 3 bottleneck blocks, each has 1x1, 3x3, 1x1
        *[{'name': f'l1.{i}.{n}', 'kernel': k, 'stride': 1}
          for i in range(3) for k, n in [(1,'pw1'),(3,'conv'),(1,'pw2')]],
        # layer2: stride-2 on first block's 3x3
        {'name': 'l2.0.pw1', 'kernel': 1, 'stride': 1},
        {'name': 'l2.0.conv', 'kernel': 3, 'stride': 2},
        {'name': 'l2.0.pw2', 'kernel': 1, 'stride': 1},
        *[{'name': f'l2.{i}.{n}', 'kernel': k, 'stride': 1}
          for i in range(1,4) for k, n in [(1,'pw1'),(3,'conv'),(1,'pw2')]],
    ]
    rf, jump = 1, 1
    for l in layers:
        k, s = l['kernel'], l['stride']
        rf = rf + (k - 1) * jump
        jump *= s
    return rf, jump

rf, jump = resnet50_rf()
print(f'ResNet-50 theoretical RF after layer2: {rf}x{rf}')
print(f'Total stride (jump): {jump}')
print('ResNet-50 full theoretical RF at output: ~483x483')
print('Effective RF typically ~100x100 (Gaussian centre-weighted)')
```

## RF Design Guidelines

Practical RF design follows a few guiding principles. For image classification, the RF should cover most of the input by the final conv layer — a 224×224 image needs an RF of at least 100–150 effective pixels. For object detection, the RF should match the object scale at each detection head — FPN (Feature Pyramid Network) uses multiple scales explicitly. For segmentation without downsampling (e.g., medical images), dilated conv is preferred to maintain resolution while expanding RF. For audio (e.g., WaveNet), exponentially growing dilation gives logarithmic RF growth — efficient for long-range temporal dependencies.

| RF Growth Strategy | RF Per Layer | Extra Params | Extra FLOPs | Spatial Resolution | Use Case |
| --- | --- | --- | --- | --- | --- |
| Stack 3×3 (s=1) | +2 per layer (linear) | None | None | Preserved | Depth-first, cheap local growth |
| Dilation d | +(2d) per layer | None | None | Preserved | Segmentation, audio (DeepLab, WaveNet) |
| Stride 2 / Pool | ×2 multiplier | None | None | Halved | Classification, detection backbone |
| Larger kernel k | +k-1 per layer | ×(k/3)² | ×(k/3)² | Preserved | Rare; two 3×3 preferred over one 5×5 |
| Global attention | Full image (1 layer) | O(n²) QKV | O(n²·d) | Preserved | ViT, SASA, non-local networks |

## Effective RF and Feature Importance

Because the effective RF is Gaussian-shaped and much smaller than the theoretical RF, architectural choices that seem to provide sufficient context may not in practice. Attention mechanisms (CBAM, SE blocks, Transformer layers) complement CNNs by providing a bypass route for long-range dependency modelling that the Gaussian-shaped ERF suppresses. Class Activation Mapping (CAM) and Grad-CAM exploit the spatial RF structure to visualise which input regions drive a classification decision, serving as a diagnostic tool for checking whether the network's attended regions match human intuition.

Deformable convolutions (Dai et al. 2017) learn spatial offsets for each kernel sampling location so the RF adapts dynamically to object shape rather than remaining a fixed grid. This improves detection of objects with irregular shapes and large aspect ratios. Deformable DETR uses deformable attention for multi-scale feature aggregation with adaptive RF. Dilated Residual Networks (DRN) remove strides in ResNet's last two stages and compensate with increasing dilation rates to maintain the full theoretical RF at higher spatial resolution.

- Grad-CAM uses the gradient of class score w.r.t. the last conv feature map for class-specific saliency maps.
- Local Attention (SASA) restricts self-attention to a local window — explicit RF control with O(n·w²) cost.
- torch.fx can trace a model graph and compute theoretical RF by tracking tensor shapes layer by layer.
- RF mismatch: if an object is larger than the network's ERF, accuracy collapses — a common failure mode on high-res inputs.

---

