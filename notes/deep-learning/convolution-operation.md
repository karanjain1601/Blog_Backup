---
title: "Convolution Operation — Cross-Correlation, Padding, Stride, Dilation"
slug: "convolution-operation"
description: "Derive 2D convolution from first principles, contrast it with cross-correlation, and master stride, padding, dilation, and multi-channel extensions with FLOP analysis."
tags: ["deep-learning", "cnns"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Convolution is the core building block of every convolutional neural network. In signal processing, convolution is defined as (f★g)[n] = Σₖ f[k]·g[n-k], where the kernel is flipped before sliding. Deep learning frameworks implement cross-correlation — the kernel is NOT flipped — but the operation is still called convolution because the network learns the kernel anyway. Understanding the mathematics behind output size, receptive field, and computational cost is essential for designing efficient architectures."},{"type":"heading","level":2,"content":"Cross-Correlation vs True Convolution"},{"type":"text","content":"True convolution flips the kernel: (f★g)[i,j] = ΣₕΣw f[h,w]·g[i-h, j-w]. Cross-correlation does not flip: (f⋆g)[i,j] = ΣₕΣw f[i+h, j+w]·g[h,w]. For a learned kernel the distinction is irrelevant — the network can absorb the flip into the learned weights. PyTorch\u0027s nn.Conv2d and F.conv2d implement cross-correlation. The mathematical convolution theorem (convolution in spatial domain = multiplication in frequency domain) applies to true convolution; in practice CNNs are designed around cross-correlation and the term \u0027convolution\u0027 is used loosely throughout the field."},{"type":"heading","level":2,"content":"2D Convolution from Scratch"},{"type":"text","content":"For a single-channel input of shape H×W and a kernel of shape k×k, the output at position (i,j) is: output[i,j] = ΣₕΣw input[i·s+h, j·s+w] · kernel[h,w], where s is the stride. With padding p zeros added on each side, the output spatial dimensions are: H_out = (H + 2p - k) // s + 1, W_out = (W + 2p - k) // s + 1. For multi-channel inputs (C_in channels), each output channel has one kernel per input channel and the results are summed: the parameter count per output channel is k×k×C_in, and for C_out output channels the total is k×k×C_in×C_out + C_out (bias)."},{"type":"code","language":"python","content":"import numpy as np\n\ndef conv2d_scratch(x, kernel, stride=1, padding=0):\n    \"\"\"Cross-correlation (what DL frameworks call \u0027convolution\u0027).\"\"\"\n    if padding \u003e 0:\n        x = np.pad(x, [(0,0),(0,0),(padding,padding),(padding,padding)])\n    N, C_in, H, W = x.shape\n    C_out, _, k, _ = kernel.shape\n    H_out = (H - k) // stride + 1\n    W_out = (W - k) // stride + 1\n    out = np.zeros((N, C_out, H_out, W_out))\n    for n in range(N):\n        for co in range(C_out):\n            for ci in range(C_in):\n                for i in range(H_out):\n                    for j in range(W_out):\n                        patch = x[n, ci,\n                                  i*stride:i*stride+k,\n                                  j*stride:j*stride+k]\n                        out[n, co, i, j] += (patch * kernel[co, ci]).sum()\n    return out\n\nnp.random.seed(0)\nx = np.random.randn(1, 3, 8, 8)       # (N, C_in, H, W)\nk = np.random.randn(16, 3, 3, 3)      # (C_out, C_in, kH, kW)\nout = conv2d_scratch(x, k, stride=1, padding=1)\nprint(\u0027Input: \u0027, x.shape)\nprint(\u0027Kernel:\u0027, k.shape)\nprint(\u0027Output:\u0027, out.shape)  # (1, 16, 8, 8) — same padding"},{"type":"heading","level":2,"content":"Padding and Stride"},{"type":"text","content":"Padding controls output size relative to input. Valid padding (p=0): no zeros added, output shrinks by k-1 per side. Same padding (p=(k-1)/2 for odd k): output has the same H×W as input. Stride s controls the step size of the sliding window: stride 2 halves the spatial dimensions (cheaper than pooling, learnable). Combining stride and padding: H_out = ⌊(H+2p-k)/s⌋ + 1. In practice, k=3, p=1, s=1 is the workhorse (preserves size); k=3, p=1, s=2 or k=1, p=0, s=2 is used for downsampling."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nx = torch.randn(1, 3, 32, 32)\n\nconfigs = [\n    dict(kernel_size=3, stride=1, padding=0, dilation=1),   # valid\n    dict(kernel_size=3, stride=1, padding=1, dilation=1),   # same\n    dict(kernel_size=3, stride=2, padding=1, dilation=1),   # stride-2 down\n    dict(kernel_size=3, stride=1, padding=2, dilation=2),   # dilated\n    dict(kernel_size=5, stride=1, padding=2, dilation=1),   # 5x5 same\n    dict(kernel_size=1, stride=1, padding=0, dilation=1),   # pointwise\n]\n\nprint(f\u0027{\u0027Config\u0027:\u003c40} Output shape\u0027)\nfor cfg in configs:\n    conv = nn.Conv2d(3, 16, **cfg)\n    out = conv(x)\n    k, s, p, d = cfg[\u0027kernel_size\u0027], cfg[\u0027stride\u0027], cfg[\u0027padding\u0027], cfg[\u0027dilation\u0027]\n    label = f\u0027k={k} s={s} p={p} d={d}\u0027\n    print(f\u0027{label:\u003c40} {tuple(out.shape)}\u0027)"},{"type":"heading","level":2,"content":"Dilation — Expanding Receptive Field for Free"},{"type":"text","content":"Dilation (atrous convolution) inserts d-1 zeros between kernel elements. A 3×3 kernel with dilation d=2 samples 5×5 regions; with d=3 it samples 7×7. The effective kernel size is (k-1)·d + 1, but the parameter count remains k×k×C_in×C_out. This is hugely valuable for semantic segmentation (DeepLab) and audio generation (WaveNet) where large context is needed without strided downsampling. Hybrid dilated convolution (HDC) stacks layers with growing dilation rates (1, 2, 5) to avoid the \u0027gridding artefact\u0027 where dilated convolutions miss input pixels."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ndef effective_rf(kernel_size, dilation):\n    \"\"\"Effective receptive field size for a single dilated conv layer.\"\"\"\n    return (kernel_size - 1) * dilation + 1\n\ndilations = [1, 2, 4, 8, 16]\nprint(f\u0027{\u0027Dilation\u0027:\u003c10} {\u0027Eff. kernel\u0027:\u003c14} {\u0027RF covered\u0027:\u003c12} Params (3x3, 64-\u003e64)\u0027)\nfor d in dilations:\n    eff = effective_rf(3, d)\n    params = 3 * 3 * 64 * 64 + 64  # fixed regardless of dilation\n    print(f\u0027{d:\u003c10} {eff}x{eff:\u003c10} {eff*eff:\u003c12} {params:,}\u0027)\n\n# Compare output shapes\nx = torch.randn(1, 1, 16, 16)\nfor d in [1, 2, 4]:\n    conv = nn.Conv2d(1, 1, kernel_size=3, padding=d, dilation=d)\n    print(f\u0027dilation={d}: out {tuple(conv(x).shape)} (same-size with p=d)\u0027)"},{"type":"heading","level":2,"content":"Visualising Learned Kernels"},{"type":"text","content":"First-layer kernels of a network trained on natural images learn Gabor-like filters — oriented edge detectors, colour blobs, and frequency detectors — because these are the most efficient basis for natural image statistics. Visualising them confirms the network is learning meaningful features rather than noise. For deeper layers, activation maximisation or feature inversion is needed. Weight initialisation matters: He/Kaiming init sets std = sqrt(2/fan_in) for ReLU networks, preventing vanishing/exploding activations."},{"type":"code","language":"python","content":"import torch\nimport torchvision.models as models\nimport matplotlib\nmatplotlib.use(\u0027Agg\u0027)\nimport matplotlib.pyplot as plt\nimport numpy as np\n\n# Load pretrained ResNet-18 and extract first conv layer kernels\nmodel = models.resnet18(weights=models.ResNet18_Weights.DEFAULT)\nkernels = model.conv1.weight.data.clone()  # (64, 3, 7, 7)\n\n# Normalize each kernel for visualization\ndef normalize(t):\n    t = t - t.min()\n    return t / (t.max() + 1e-8)\n\nfig, axes = plt.subplots(4, 8, figsize=(12, 6))\nfor idx, ax in enumerate(axes.flat):\n    if idx \u003c 32:\n        k = normalize(kernels[idx].permute(1, 2, 0).numpy())\n        ax.imshow(k)\n    ax.axis(\u0027off\u0027)\nplt.suptitle(\u0027First 32 of 64 ResNet-18 conv1 kernels (7x7, RGB)\u0027)\nplt.tight_layout()\nplt.savefig(\u0027kernels.png\u0027, dpi=80)\nprint(f\u0027conv1 kernel shape: {tuple(kernels.shape)}\u0027)\nprint(f\u0027Params in conv1: {kernels.numel():,} (+ {model.conv1.bias is None and 0} bias)\u0027)"},{"type":"heading","level":2,"content":"Computational Cost Analysis"},{"type":"text","content":"The floating-point operations (FLOPs) for a convolution layer are: FLOPs ≈ 2 × H_out × W_out × C_in × C_out × k². The factor 2 accounts for multiply-accumulate (MAC = 1 multiply + 1 add). For a typical ResNet-50 layer with H_out=56, W_out=56, C_in=64, C_out=64, k=3: FLOPs ≈ 2×56×56×64×64×9 ≈ 2.3 GFLOPs for that single layer. Memory bandwidth often bottlenecks throughput before compute does, especially for large feature maps. Reducing C_in or C_out by 2× saves 4× FLOPs; reducing k from 3 to 1 saves 9× FLOPs at the cost of no spatial mixing."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ndef conv_flops(H_in, W_in, C_in, C_out, k, s=1, p=0):\n    H_out = (H_in + 2*p - k) // s + 1\n    W_out = (W_in + 2*p - k) // s + 1\n    # 2 ops per MAC (multiply + add), k*k MACs per output element per input channel\n    flops = 2 * H_out * W_out * C_in * C_out * k * k\n    params = C_out * C_in * k * k + C_out\n    return H_out, W_out, flops, params\n\nlayers = [\n    (\u0027conv1 k=7\u0027,  224, 224, 3,   64,  7, 2, 3),\n    (\u0027layer1 k=3\u0027, 56,  56,  64,  64,  3, 1, 1),\n    (\u0027layer1 k=1\u0027, 56,  56,  64,  64,  1, 1, 0),\n    (\u0027layer4 k=3\u0027, 7,   7,   512, 512, 3, 1, 1),\n    (\u0027pw  k=1\u0027,    14,  14,  256, 1024,1, 1, 0),\n]\nprint(f\u0027{\u0027Layer\u0027:\u003c14} {\u0027HxW out\u0027:\u003c10} {\u0027GFLOPs\u0027:\u003e8} {\u0027Params\u0027:\u003e10}\u0027)\nfor name, H, W, Ci, Co, k, s, p in layers:\n    Ho, Wo, fl, pa = conv_flops(H, W, Ci, Co, k, s, p)\n    print(f\u0027{name:\u003c14} {Ho}x{Wo:\u003c6} {fl/1e9:\u003e8.3f} {pa:\u003e10,}\u0027)"},{"type":"callout","variant":"info","title":"Weight Sharing = Translation Equivariance","content":"The same kernel is applied at every spatial location — this is weight sharing. It means a feature detector trained on a cat in the upper-left works equally well in the lower-right. Formally, if T_d denotes a shift-by-d operator, convolution satisfies f(T_d x) = T_d(f(x)): shifting the input shifts the output by the same amount. This inductive bias dramatically reduces the parameters needed and is why CNNs generalise so well on images."},{"type":"heading","level":2,"content":"Multi-Channel Extension and Parameter Count"},{"type":"text","content":"For an input with C_in channels and C_out output channels, the kernel tensor has shape (C_out, C_in, k, k). Each output channel is produced by convolving the full C_in-channel input with one (C_in, k, k) kernel and summing across channels. The parameter count is C_out × C_in × k × k + C_out (bias). For k=3, C_in=256, C_out=256: 256×256×9 + 256 = 590,080 parameters. Compare: a fully-connected layer mapping the same 256×7×7 = 12,544 features to 12,544 outputs would need 12,544² ≈ 157M parameters — 266× more."},{"type":"table","headers":["Parameter","Effect on Output Size","Effect on Receptive Field","Effect on Params","Effect on FLOPs"],"rows":[["Kernel size k↑","(H+2p-k)//s+1 shrinks","Grows linearly with k","×k² per layer","×k²"],["Stride s↑","Divides by s (downsamples)","Multiplies all downstream RF","Unchanged","÷s²"],["Padding p↑","+(2p) before division","No effect","Unchanged","Slightly ↑"],["Dilation d↑","Unchanged (with p=d)","×d per layer","Unchanged","Unchanged"],["C_in↑","Unchanged","Unchanged","×C_in","×C_in"],["C_out↑","More output channels","Unchanged","×C_out","×C_out"]]},{"type":"list","ordered":false,"items":["Valid padding (p=0): output shrinks by k-1 each side — use when reducing spatial size intentionally.","Same padding (p=(k-1)//2): output matches input size — standard in residual blocks.","SAME vs VALID in TensorFlow: SAME adds asymmetric padding; PyTorch requires manual specification.","Grouped convolution (groups=g): reduces params and FLOPs by factor g — covered in the next note.","Bias can be omitted (bias=False) when BatchNorm follows — BN has its own learnable shift parameter.","Output channel ordering: PyTorch uses (N, C, H, W); TensorFlow defaults to (N, H, W, C)."]},{"type":"divider"}]"
---
# Convolution Operation — Cross-Correlation, Padding, Stride, Dilation

Convolution is the core building block of every convolutional neural network. In signal processing, convolution is defined as (f★g)[n] = Σₖ f[k]·g[n-k], where the kernel is flipped before sliding. Deep learning frameworks implement cross-correlation — the kernel is NOT flipped — but the operation is still called convolution because the network learns the kernel anyway. Understanding the mathematics behind output size, receptive field, and computational cost is essential for designing efficient architectures.

## Cross-Correlation vs True Convolution

True convolution flips the kernel: (f★g)[i,j] = ΣₕΣw f[h,w]·g[i-h, j-w]. Cross-correlation does not flip: (f⋆g)[i,j] = ΣₕΣw f[i+h, j+w]·g[h,w]. For a learned kernel the distinction is irrelevant — the network can absorb the flip into the learned weights. PyTorch's nn.Conv2d and F.conv2d implement cross-correlation. The mathematical convolution theorem (convolution in spatial domain = multiplication in frequency domain) applies to true convolution; in practice CNNs are designed around cross-correlation and the term 'convolution' is used loosely throughout the field.

## 2D Convolution from Scratch

For a single-channel input of shape H×W and a kernel of shape k×k, the output at position (i,j) is: output[i,j] = ΣₕΣw input[i·s+h, j·s+w] · kernel[h,w], where s is the stride. With padding p zeros added on each side, the output spatial dimensions are: H_out = (H + 2p - k) // s + 1, W_out = (W + 2p - k) // s + 1. For multi-channel inputs (C_in channels), each output channel has one kernel per input channel and the results are summed: the parameter count per output channel is k×k×C_in, and for C_out output channels the total is k×k×C_in×C_out + C_out (bias).

```python
import numpy as np

def conv2d_scratch(x, kernel, stride=1, padding=0):
    """Cross-correlation (what DL frameworks call 'convolution')."""
    if padding > 0:
        x = np.pad(x, [(0,0),(0,0),(padding,padding),(padding,padding)])
    N, C_in, H, W = x.shape
    C_out, _, k, _ = kernel.shape
    H_out = (H - k) // stride + 1
    W_out = (W - k) // stride + 1
    out = np.zeros((N, C_out, H_out, W_out))
    for n in range(N):
        for co in range(C_out):
            for ci in range(C_in):
                for i in range(H_out):
                    for j in range(W_out):
                        patch = x[n, ci,
                                  i*stride:i*stride+k,
                                  j*stride:j*stride+k]
                        out[n, co, i, j] += (patch * kernel[co, ci]).sum()
    return out

np.random.seed(0)
x = np.random.randn(1, 3, 8, 8)       # (N, C_in, H, W)
k = np.random.randn(16, 3, 3, 3)      # (C_out, C_in, kH, kW)
out = conv2d_scratch(x, k, stride=1, padding=1)
print('Input: ', x.shape)
print('Kernel:', k.shape)
print('Output:', out.shape)  # (1, 16, 8, 8) — same padding
```

## Padding and Stride

Padding controls output size relative to input. Valid padding (p=0): no zeros added, output shrinks by k-1 per side. Same padding (p=(k-1)/2 for odd k): output has the same H×W as input. Stride s controls the step size of the sliding window: stride 2 halves the spatial dimensions (cheaper than pooling, learnable). Combining stride and padding: H_out = ⌊(H+2p-k)/s⌋ + 1. In practice, k=3, p=1, s=1 is the workhorse (preserves size); k=3, p=1, s=2 or k=1, p=0, s=2 is used for downsampling.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

x = torch.randn(1, 3, 32, 32)

configs = [
    dict(kernel_size=3, stride=1, padding=0, dilation=1),   # valid
    dict(kernel_size=3, stride=1, padding=1, dilation=1),   # same
    dict(kernel_size=3, stride=2, padding=1, dilation=1),   # stride-2 down
    dict(kernel_size=3, stride=1, padding=2, dilation=2),   # dilated
    dict(kernel_size=5, stride=1, padding=2, dilation=1),   # 5x5 same
    dict(kernel_size=1, stride=1, padding=0, dilation=1),   # pointwise
]

print(f'{'Config':<40} Output shape')
for cfg in configs:
    conv = nn.Conv2d(3, 16, **cfg)
    out = conv(x)
    k, s, p, d = cfg['kernel_size'], cfg['stride'], cfg['padding'], cfg['dilation']
    label = f'k={k} s={s} p={p} d={d}'
    print(f'{label:<40} {tuple(out.shape)}')
```

## Dilation — Expanding Receptive Field for Free

Dilation (atrous convolution) inserts d-1 zeros between kernel elements. A 3×3 kernel with dilation d=2 samples 5×5 regions; with d=3 it samples 7×7. The effective kernel size is (k-1)·d + 1, but the parameter count remains k×k×C_in×C_out. This is hugely valuable for semantic segmentation (DeepLab) and audio generation (WaveNet) where large context is needed without strided downsampling. Hybrid dilated convolution (HDC) stacks layers with growing dilation rates (1, 2, 5) to avoid the 'gridding artefact' where dilated convolutions miss input pixels.

```python
import torch
import torch.nn as nn

def effective_rf(kernel_size, dilation):
    """Effective receptive field size for a single dilated conv layer."""
    return (kernel_size - 1) * dilation + 1

dilations = [1, 2, 4, 8, 16]
print(f'{'Dilation':<10} {'Eff. kernel':<14} {'RF covered':<12} Params (3x3, 64->64)')
for d in dilations:
    eff = effective_rf(3, d)
    params = 3 * 3 * 64 * 64 + 64  # fixed regardless of dilation
    print(f'{d:<10} {eff}x{eff:<10} {eff*eff:<12} {params:,}')

# Compare output shapes
x = torch.randn(1, 1, 16, 16)
for d in [1, 2, 4]:
    conv = nn.Conv2d(1, 1, kernel_size=3, padding=d, dilation=d)
    print(f'dilation={d}: out {tuple(conv(x).shape)} (same-size with p=d)')
```

## Visualising Learned Kernels

First-layer kernels of a network trained on natural images learn Gabor-like filters — oriented edge detectors, colour blobs, and frequency detectors — because these are the most efficient basis for natural image statistics. Visualising them confirms the network is learning meaningful features rather than noise. For deeper layers, activation maximisation or feature inversion is needed. Weight initialisation matters: He/Kaiming init sets std = sqrt(2/fan_in) for ReLU networks, preventing vanishing/exploding activations.

```python
import torch
import torchvision.models as models
import matplotlib
matplotlib.use('Agg')
import matplotlib.pyplot as plt
import numpy as np

# Load pretrained ResNet-18 and extract first conv layer kernels
model = models.resnet18(weights=models.ResNet18_Weights.DEFAULT)
kernels = model.conv1.weight.data.clone()  # (64, 3, 7, 7)

# Normalize each kernel for visualization
def normalize(t):
    t = t - t.min()
    return t / (t.max() + 1e-8)

fig, axes = plt.subplots(4, 8, figsize=(12, 6))
for idx, ax in enumerate(axes.flat):
    if idx < 32:
        k = normalize(kernels[idx].permute(1, 2, 0).numpy())
        ax.imshow(k)
    ax.axis('off')
plt.suptitle('First 32 of 64 ResNet-18 conv1 kernels (7x7, RGB)')
plt.tight_layout()
plt.savefig('kernels.png', dpi=80)
print(f'conv1 kernel shape: {tuple(kernels.shape)}')
print(f'Params in conv1: {kernels.numel():,} (+ {model.conv1.bias is None and 0} bias)')
```

## Computational Cost Analysis

The floating-point operations (FLOPs) for a convolution layer are: FLOPs ≈ 2 × H_out × W_out × C_in × C_out × k². The factor 2 accounts for multiply-accumulate (MAC = 1 multiply + 1 add). For a typical ResNet-50 layer with H_out=56, W_out=56, C_in=64, C_out=64, k=3: FLOPs ≈ 2×56×56×64×64×9 ≈ 2.3 GFLOPs for that single layer. Memory bandwidth often bottlenecks throughput before compute does, especially for large feature maps. Reducing C_in or C_out by 2× saves 4× FLOPs; reducing k from 3 to 1 saves 9× FLOPs at the cost of no spatial mixing.

```python
import torch
import torch.nn as nn

def conv_flops(H_in, W_in, C_in, C_out, k, s=1, p=0):
    H_out = (H_in + 2*p - k) // s + 1
    W_out = (W_in + 2*p - k) // s + 1
    # 2 ops per MAC (multiply + add), k*k MACs per output element per input channel
    flops = 2 * H_out * W_out * C_in * C_out * k * k
    params = C_out * C_in * k * k + C_out
    return H_out, W_out, flops, params

layers = [
    ('conv1 k=7',  224, 224, 3,   64,  7, 2, 3),
    ('layer1 k=3', 56,  56,  64,  64,  3, 1, 1),
    ('layer1 k=1', 56,  56,  64,  64,  1, 1, 0),
    ('layer4 k=3', 7,   7,   512, 512, 3, 1, 1),
    ('pw  k=1',    14,  14,  256, 1024,1, 1, 0),
]
print(f'{'Layer':<14} {'HxW out':<10} {'GFLOPs':>8} {'Params':>10}')
for name, H, W, Ci, Co, k, s, p in layers:
    Ho, Wo, fl, pa = conv_flops(H, W, Ci, Co, k, s, p)
    print(f'{name:<14} {Ho}x{Wo:<6} {fl/1e9:>8.3f} {pa:>10,}')
```

> **Weight Sharing = Translation Equivariance**: The same kernel is applied at every spatial location — this is weight sharing. It means a feature detector trained on a cat in the upper-left works equally well in the lower-right. Formally, if T_d denotes a shift-by-d operator, convolution satisfies f(T_d x) = T_d(f(x)): shifting the input shifts the output by the same amount. This inductive bias dramatically reduces the parameters needed and is why CNNs generalise so well on images.

## Multi-Channel Extension and Parameter Count

For an input with C_in channels and C_out output channels, the kernel tensor has shape (C_out, C_in, k, k). Each output channel is produced by convolving the full C_in-channel input with one (C_in, k, k) kernel and summing across channels. The parameter count is C_out × C_in × k × k + C_out (bias). For k=3, C_in=256, C_out=256: 256×256×9 + 256 = 590,080 parameters. Compare: a fully-connected layer mapping the same 256×7×7 = 12,544 features to 12,544 outputs would need 12,544² ≈ 157M parameters — 266× more.

| Parameter | Effect on Output Size | Effect on Receptive Field | Effect on Params | Effect on FLOPs |
| --- | --- | --- | --- | --- |
| Kernel size k↑ | (H+2p-k)//s+1 shrinks | Grows linearly with k | ×k² per layer | ×k² |
| Stride s↑ | Divides by s (downsamples) | Multiplies all downstream RF | Unchanged | ÷s² |
| Padding p↑ | +(2p) before division | No effect | Unchanged | Slightly ↑ |
| Dilation d↑ | Unchanged (with p=d) | ×d per layer | Unchanged | Unchanged |
| C_in↑ | Unchanged | Unchanged | ×C_in | ×C_in |
| C_out↑ | More output channels | Unchanged | ×C_out | ×C_out |

- Valid padding (p=0): output shrinks by k-1 each side — use when reducing spatial size intentionally.
- Same padding (p=(k-1)//2): output matches input size — standard in residual blocks.
- SAME vs VALID in TensorFlow: SAME adds asymmetric padding; PyTorch requires manual specification.
- Grouped convolution (groups=g): reduces params and FLOPs by factor g — covered in the next note.
- Bias can be omitted (bias=False) when BatchNorm follows — BN has its own learnable shift parameter.
- Output channel ordering: PyTorch uses (N, C, H, W); TensorFlow defaults to (N, H, W, C).

---

