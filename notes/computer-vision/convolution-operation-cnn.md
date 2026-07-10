---
title: "Convolution Operation in CNNs"
slug: "convolution-operation-cnn"
description: "The 2D convolution operation — kernel sliding, stride, padding, dilation, output size formula, and grouped convolutions — with worked examples in PyTorch."
tags: ["computer-vision"]
topic: "computer-vision"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"Convolution is the fundamental operation in convolutional neural networks. A learnable kernel slides across the input feature map, computing dot products at each position to produce an output feature map. This local connectivity and weight sharing dramatically reduce parameters compared to fully connected layers, while preserving spatial structure in visual data."},{"type":"text","content":"CNNs exploit three key properties: local connectivity (each output depends on a small input region), weight sharing (the same kernel is applied everywhere), and translation equivariance (shifting the input shifts the output by the same amount). These properties make convolutions ideal for image data where patterns can appear anywhere in the scene."},{"type":"heading","level":2,"content":"2D Convolution Math"},{"type":"text","content":"For a 2D input X of shape (H, W) and kernel K of shape (kH, kW), the output Y at position (i, j) is computed as a sum of element-wise products: Y[i,j] = Σ_m Σ_n X[i+m, j+n] · K[m,n]. In deep learning, this operation is technically cross-correlation (no kernel flip), but is universally called convolution. Learnable bias is added after the summation."},{"type":"code","language":"python","content":"import numpy as np\nimport torch\nimport torch.nn.functional as F\n\ndef manual_cross_correlate(x, k):\n    H, W = x.shape\n    kH, kW = k.shape\n    out = np.zeros((H - kH + 1, W - kW + 1))\n    for i in range(out.shape[0]):\n        for j in range(out.shape[1]):\n            out[i, j] = (x[i:i+kH, j:j+kW] * k).sum()\n    return out\n\nx_np = np.random.randn(6, 6).astype(np.float32)\nk_np = np.random.randn(3, 3).astype(np.float32)\nmanual_out = manual_cross_correlate(x_np, k_np)\ntorch_out = F.conv2d(torch.tensor(x_np[None,None]), torch.tensor(k_np[None,None]))\nprint(np.allclose(manual_out, torch_out.numpy()[0,0], atol=1e-5))  # True"},{"type":"text","content":"The output spatial size after convolution is determined by input size, kernel size, stride, and padding. For a 1D case: output_length = floor((input + 2*padding - kernel) / stride) + 1. In PyTorch, nn.Conv2d handles this automatically, but understanding the formula helps diagnose shape mismatches and design architectures with specific output resolutions."},{"type":"heading","level":2,"content":"Stride and Padding"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ndef output_size(H, W, K, S, P):\n    out_H = (H + 2*P - K) // S + 1\n    out_W = (W + 2*P - K) // S + 1\n    return out_H, out_W\n\n# Standard: stride=1, no padding\nprint(output_size(32, 32, 3, 1, 0))   # (30, 30)\n# Same padding: output == input\nprint(output_size(32, 32, 3, 1, 1))   # (32, 32)\n# Stride-2 halving\nprint(output_size(32, 32, 3, 2, 1))   # (16, 16)\n# Verify with nn.Conv2d\nconv = nn.Conv2d(1, 1, kernel_size=3, stride=2, padding=1)\nx = torch.zeros(1, 1, 32, 32)\nprint(conv(x).shape)  # torch.Size([1, 1, 16, 16])"},{"type":"text","content":"Stride controls how far the kernel moves at each step. Stride=1 preserves spatial resolution; stride=2 halves it without explicit pooling, which is used in modern architectures like ResNet to reduce computation. Padding adds zeros around the input boundary. \u0027Same\u0027 padding (P = (K-1)/2 for odd kernels) maintains spatial dimensions and prevents information loss at edges."},{"type":"heading","level":2,"content":"Dilated Convolutions"},{"type":"text","content":"Dilated (atrous) convolutions insert gaps between kernel elements, expanding the receptive field without increasing parameters or losing spatial resolution. A dilation rate d=2 on a 3×3 kernel covers a 5×5 region; d=4 covers 9×9. This is especially useful for dense prediction tasks (segmentation, detection) where large context is needed at full resolution, as used in DeepLab and WaveNet architectures."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nx = torch.arange(25, dtype=torch.float32).reshape(1, 1, 5, 5)\nprint(\"Input:\\n\", x[0,0])\n\n# Standard 3x3 conv: sees 3x3 region\nconv_std = nn.Conv2d(1, 1, 3, dilation=1, padding=0)\nprint(\"Standard output shape:\", conv_std(x).shape)  # [1,1,3,3]\n\n# Dilated 3x3 conv (d=2): sees 5x5 region, same params\nconv_dil = nn.Conv2d(1, 1, 3, dilation=2, padding=0)\n# With dilation=2, effective kernel size = 2*(3-1)+1 = 5\nprint(\"Dilated output shape:\", conv_dil(x).shape)   # [1,1,1,1]\nprint(\"Receptive field: 5x5 from 9 params\")"},{"type":"heading","level":2,"content":"Grouped and Depthwise Convolutions"},{"type":"text","content":"Grouped convolutions split the input channels into G groups and apply separate convolutions to each. When groups equals the number of input channels, each channel gets its own filter — this is depthwise convolution. Combining depthwise conv with a 1×1 pointwise conv gives depthwise separable convolution, which achieves similar capacity as standard convolution with a fraction of the parameters and FLOPs."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nC_in, C_out, H, W = 32, 64, 8, 8\nx = torch.randn(1, C_in, H, W)\n\n# Standard conv\nstd = nn.Conv2d(C_in, C_out, 3, padding=1)\nstd_params = sum(p.numel() for p in std.parameters())\n\n# Depthwise separable conv\ndw = nn.Conv2d(C_in, C_in, 3, padding=1, groups=C_in)  # depthwise\npw = nn.Conv2d(C_in, C_out, 1)                          # pointwise\ndws_params = sum(p.numel() for p in list(dw.parameters()) + list(pw.parameters()))\n\nprint(f\"Standard params: {std_params}\")     # 18,496\nprint(f\"DWS params:      {dws_params}\")     # 2,336  (~8x fewer)"},{"type":"table","headers":["Conv Type","Params","FLOPs","Receptive Field","Use Case"],"rows":[["Standard","C_in × C_out × kH × kW","High","k × k","General feature extraction"],["Depthwise","C_in × kH × kW","Very low","k × k per channel","Spatial filtering (MobileNet)"],["Pointwise (1×1)","C_in × C_out","Low","1 × 1","Channel mixing / projection"],["Grouped (G groups)","C_in × C_out × kH × kW / G","Medium","k × k","Efficient channel separation (ResNeXt)"],["Dilated","C_in × C_out × kH × kW","High","d×(k-1)+1 × d×(k-1)+1","Segmentation, dense prediction (DeepLab)"]]},{"type":"callout","variant":"info","content":"Depthwise separable convolution reduces params by ~8–9× vs standard convolution at similar accuracy — this is the core insight behind MobileNet."},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"The output size formula (H+2P-K)/S+1 is essential for architectural design. Stride-2 convolutions replace pooling in modern networks. Dilated convolutions expand receptive field without downsampling — critical for dense tasks. Depthwise separable convolutions (depthwise + pointwise) offer the best efficiency trade-off and power lightweight models like MobileNet, EfficientNet, and ShuffleNet."},{"type":"text","content":"Grouped convolutions with G=32 or G=64 (as in ResNeXt) offer a middle ground: more expressive than depthwise but more efficient than standard. The 1×1 pointwise convolution is the Swiss Army knife of CNNs — it mixes channels, changes dimensionality, and adds non-linearity at minimal cost. Combining these building blocks enables designing efficient architectures for any compute budget."}]"
---
# Convolution Operation in CNNs

## Overview

Convolution is the fundamental operation in convolutional neural networks. A learnable kernel slides across the input feature map, computing dot products at each position to produce an output feature map. This local connectivity and weight sharing dramatically reduce parameters compared to fully connected layers, while preserving spatial structure in visual data.

CNNs exploit three key properties: local connectivity (each output depends on a small input region), weight sharing (the same kernel is applied everywhere), and translation equivariance (shifting the input shifts the output by the same amount). These properties make convolutions ideal for image data where patterns can appear anywhere in the scene.

## 2D Convolution Math

For a 2D input X of shape (H, W) and kernel K of shape (kH, kW), the output Y at position (i, j) is computed as a sum of element-wise products: Y[i,j] = Σ_m Σ_n X[i+m, j+n] · K[m,n]. In deep learning, this operation is technically cross-correlation (no kernel flip), but is universally called convolution. Learnable bias is added after the summation.

```python
import numpy as np
import torch
import torch.nn.functional as F

def manual_cross_correlate(x, k):
    H, W = x.shape
    kH, kW = k.shape
    out = np.zeros((H - kH + 1, W - kW + 1))
    for i in range(out.shape[0]):
        for j in range(out.shape[1]):
            out[i, j] = (x[i:i+kH, j:j+kW] * k).sum()
    return out

x_np = np.random.randn(6, 6).astype(np.float32)
k_np = np.random.randn(3, 3).astype(np.float32)
manual_out = manual_cross_correlate(x_np, k_np)
torch_out = F.conv2d(torch.tensor(x_np[None,None]), torch.tensor(k_np[None,None]))
print(np.allclose(manual_out, torch_out.numpy()[0,0], atol=1e-5))  # True
```

The output spatial size after convolution is determined by input size, kernel size, stride, and padding. For a 1D case: output_length = floor((input + 2*padding - kernel) / stride) + 1. In PyTorch, nn.Conv2d handles this automatically, but understanding the formula helps diagnose shape mismatches and design architectures with specific output resolutions.

## Stride and Padding

```python
import torch
import torch.nn as nn

def output_size(H, W, K, S, P):
    out_H = (H + 2*P - K) // S + 1
    out_W = (W + 2*P - K) // S + 1
    return out_H, out_W

# Standard: stride=1, no padding
print(output_size(32, 32, 3, 1, 0))   # (30, 30)
# Same padding: output == input
print(output_size(32, 32, 3, 1, 1))   # (32, 32)
# Stride-2 halving
print(output_size(32, 32, 3, 2, 1))   # (16, 16)
# Verify with nn.Conv2d
conv = nn.Conv2d(1, 1, kernel_size=3, stride=2, padding=1)
x = torch.zeros(1, 1, 32, 32)
print(conv(x).shape)  # torch.Size([1, 1, 16, 16])
```

Stride controls how far the kernel moves at each step. Stride=1 preserves spatial resolution; stride=2 halves it without explicit pooling, which is used in modern architectures like ResNet to reduce computation. Padding adds zeros around the input boundary. 'Same' padding (P = (K-1)/2 for odd kernels) maintains spatial dimensions and prevents information loss at edges.

## Dilated Convolutions

Dilated (atrous) convolutions insert gaps between kernel elements, expanding the receptive field without increasing parameters or losing spatial resolution. A dilation rate d=2 on a 3×3 kernel covers a 5×5 region; d=4 covers 9×9. This is especially useful for dense prediction tasks (segmentation, detection) where large context is needed at full resolution, as used in DeepLab and WaveNet architectures.

```python
import torch
import torch.nn as nn

x = torch.arange(25, dtype=torch.float32).reshape(1, 1, 5, 5)
print("Input:\n", x[0,0])

# Standard 3x3 conv: sees 3x3 region
conv_std = nn.Conv2d(1, 1, 3, dilation=1, padding=0)
print("Standard output shape:", conv_std(x).shape)  # [1,1,3,3]

# Dilated 3x3 conv (d=2): sees 5x5 region, same params
conv_dil = nn.Conv2d(1, 1, 3, dilation=2, padding=0)
# With dilation=2, effective kernel size = 2*(3-1)+1 = 5
print("Dilated output shape:", conv_dil(x).shape)   # [1,1,1,1]
print("Receptive field: 5x5 from 9 params")
```

## Grouped and Depthwise Convolutions

Grouped convolutions split the input channels into G groups and apply separate convolutions to each. When groups equals the number of input channels, each channel gets its own filter — this is depthwise convolution. Combining depthwise conv with a 1×1 pointwise conv gives depthwise separable convolution, which achieves similar capacity as standard convolution with a fraction of the parameters and FLOPs.

```python
import torch
import torch.nn as nn

C_in, C_out, H, W = 32, 64, 8, 8
x = torch.randn(1, C_in, H, W)

# Standard conv
std = nn.Conv2d(C_in, C_out, 3, padding=1)
std_params = sum(p.numel() for p in std.parameters())

# Depthwise separable conv
dw = nn.Conv2d(C_in, C_in, 3, padding=1, groups=C_in)  # depthwise
pw = nn.Conv2d(C_in, C_out, 1)                          # pointwise
dws_params = sum(p.numel() for p in list(dw.parameters()) + list(pw.parameters()))

print(f"Standard params: {std_params}")     # 18,496
print(f"DWS params:      {dws_params}")     # 2,336  (~8x fewer)
```

| Conv Type | Params | FLOPs | Receptive Field | Use Case |
| --- | --- | --- | --- | --- |
| Standard | C_in × C_out × kH × kW | High | k × k | General feature extraction |
| Depthwise | C_in × kH × kW | Very low | k × k per channel | Spatial filtering (MobileNet) |
| Pointwise (1×1) | C_in × C_out | Low | 1 × 1 | Channel mixing / projection |
| Grouped (G groups) | C_in × C_out × kH × kW / G | Medium | k × k | Efficient channel separation (ResNeXt) |
| Dilated | C_in × C_out × kH × kW | High | d×(k-1)+1 × d×(k-1)+1 | Segmentation, dense prediction (DeepLab) |

> **info**: Depthwise separable convolution reduces params by ~8–9× vs standard convolution at similar accuracy — this is the core insight behind MobileNet.

## Key Takeaways

The output size formula (H+2P-K)/S+1 is essential for architectural design. Stride-2 convolutions replace pooling in modern networks. Dilated convolutions expand receptive field without downsampling — critical for dense tasks. Depthwise separable convolutions (depthwise + pointwise) offer the best efficiency trade-off and power lightweight models like MobileNet, EfficientNet, and ShuffleNet.

Grouped convolutions with G=32 or G=64 (as in ResNeXt) offer a middle ground: more expressive than depthwise but more efficient than standard. The 1×1 pointwise convolution is the Swiss Army knife of CNNs — it mixes channels, changes dimensionality, and adds non-linearity at minimal cost. Combining these building blocks enables designing efficient architectures for any compute budget.

