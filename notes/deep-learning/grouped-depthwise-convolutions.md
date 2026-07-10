---
title: "Grouped and Depthwise Convolutions — MobileNet Efficiency"
slug: "grouped-depthwise-convolutions"
description: "Understand how grouped and depthwise separable convolutions slash parameters and FLOPs, with MobileNetV1/V2 and ShuffleNet as case studies."
tags: ["deep-learning", "cnns"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Standard convolution treats all input channels jointly: each output channel sees every input channel through its own kernel, enabling full cross-channel communication but at the cost of C_in×C_out×k² parameters. Grouped and depthwise convolutions break this coupling selectively. By splitting channels into groups or processing each channel independently, these operations achieve dramatic parameter and FLOP reductions while retaining most of the representational power — the foundation of efficient CNNs for mobile and edge deployment."},{"type":"heading","level":2,"content":"Grouped Convolution"},{"type":"text","content":"Grouped convolution (nn.Conv2d(..., groups=g)) splits C_in into g groups of C_in/g channels each, and C_out into g groups of C_out/g. Each group processes only its corresponding input channels independently. Total parameters: C_in × C_out × k² / g — a factor-g reduction. FLOPs reduce by the same factor. AlexNet used groups=2 as a practical workaround to fit on two GPUs in 2012. ResNeXt (2017) reframed grouped conv as \u0027aggregated residual transformations\u0027: groups=32 with wider channels matches ResNet accuracy with fewer FLOPs. The cost: no cross-group communication without an additional mixing step."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nC_in, C_out, k = 256, 256, 3\n\nconfigs = [\n    (\u0027Standard (g=1)\u0027,  1),\n    (\u0027Grouped g=2\u0027,     2),\n    (\u0027Grouped g=4\u0027,     4),\n    (\u0027Grouped g=8\u0027,     8),\n    (\u0027Grouped g=32\u0027,   32),\n    (\u0027Depthwise g=C\u0027, C_in),\n]\n\nprint(f\u0027{\u0027Config\u0027:\u003c22} {\u0027Params\u0027:\u003e10} {\u0027Reduction\u0027:\u003e10}\u0027)\nstandard_params = None\nfor name, g in configs:\n    conv = nn.Conv2d(C_in, C_out, k, padding=1, groups=g, bias=False)\n    p = sum(x.numel() for x in conv.parameters())\n    if standard_params is None:\n        standard_params = p\n    print(f\u0027{name:\u003c22} {p:\u003e10,} {p/standard_params:\u003e9.3f}x\u0027)\n\n# Verify output shape is same for all\nx = torch.randn(2, C_in, 14, 14)\nfor name, g in configs:\n    conv = nn.Conv2d(C_in, C_out, k, padding=1, groups=g, bias=False)\n    assert conv(x).shape == (2, C_out, 14, 14), f\u0027Shape mismatch for {name}\u0027\nprint(\u0027\\nAll produce identical output shape (2, 256, 14, 14) ✓\u0027)"},{"type":"heading","level":2,"content":"Depthwise Separable Convolution"},{"type":"text","content":"Depthwise separable convolution factorises a standard conv into two steps. Step 1 — Depthwise conv: apply one k×k kernel per input channel independently (groups=C_in), producing C_in output channels with C_in×k² parameters. Step 2 — Pointwise conv: apply a 1×1 conv to mix channels (C_in×C_out parameters). Total: C_in×k² + C_in×C_out vs C_in×C_out×k² for standard. The ratio is 1/C_out + 1/k² ≈ 1/k² = 1/9 for k=3 and large C_out. This is the core innovation of MobileNetV1: replace every 3×3 conv with a depthwise separable block, achieving ~8–9× reduction in computation with only ~1% top-1 accuracy loss on ImageNet."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass DepthwiseSeparableConv(nn.Module):\n    \"\"\"MobileNetV1-style depthwise separable conv block.\"\"\"\n    def __init__(self, C_in, C_out, stride=1):\n        super().__init__()\n        self.dw = nn.Sequential(\n            nn.Conv2d(C_in, C_in, 3, stride=stride, padding=1,\n                      groups=C_in, bias=False),  # depthwise\n            nn.BatchNorm2d(C_in),\n            nn.ReLU6(inplace=True)\n        )\n        self.pw = nn.Sequential(\n            nn.Conv2d(C_in, C_out, 1, bias=False),  # pointwise\n            nn.BatchNorm2d(C_out),\n            nn.ReLU6(inplace=True)\n        )\n\n    def forward(self, x):\n        return self.pw(self.dw(x))\n\n# Compare parameter counts\nC_in, C_out = 128, 256\nstandard = nn.Conv2d(C_in, C_out, 3, padding=1, bias=False)\ndws      = DepthwiseSeparableConv(C_in, C_out)\n\np_std = sum(p.numel() for p in standard.parameters())\np_dws = sum(p.numel() for p in dws.parameters())\nprint(f\u0027Standard conv params:      {p_std:,}\u0027)\nprint(f\u0027Depthwise-sep params:      {p_dws:,}\u0027)\nprint(f\u0027Reduction factor:          {p_std/p_dws:.2f}x\u0027)\n\nx = torch.randn(4, C_in, 28, 28)\nprint(f\u0027\\nInput {tuple(x.shape)} -\u003e Output {tuple(dws(x).shape)}\u0027)"},{"type":"heading","level":2,"content":"MobileNetV2 — Inverted Residuals and Linear Bottleneck"},{"type":"text","content":"MobileNetV2 introduces two key ideas. First, the inverted residual: unlike ResNet\u0027s bottleneck (wide → narrow → wide), MobileNetV2 expands channels (narrow → wide → narrow), applying the depthwise conv in the expanded high-dimensional space where spatial mixing is richer, then projects back. Second, the linear bottleneck: the final pointwise projection uses no activation (linear), because ReLU in low-dimensional spaces destroys information by collapsing the manifold. The skip connection is added only when input and output have the same shape. This design achieves better accuracy/FLOP tradeoff than MobileNetV1."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass InvertedResidual(nn.Module):\n    \"\"\"MobileNetV2 inverted residual block.\"\"\"\n    def __init__(self, C_in, C_out, stride=1, expand_ratio=6):\n        super().__init__()\n        C_mid = C_in * expand_ratio\n        self.use_skip = (stride == 1 and C_in == C_out)\n        layers = []\n        if expand_ratio != 1:  # expansion phase\n            layers += [nn.Conv2d(C_in, C_mid, 1, bias=False),\n                       nn.BatchNorm2d(C_mid), nn.ReLU6(inplace=True)]\n        layers += [\n            nn.Conv2d(C_mid, C_mid, 3, stride=stride,  # depthwise\n                      padding=1, groups=C_mid, bias=False),\n            nn.BatchNorm2d(C_mid), nn.ReLU6(inplace=True),\n            nn.Conv2d(C_mid, C_out, 1, bias=False),    # linear projection\n            nn.BatchNorm2d(C_out)\n            # NO activation after last BN — linear bottleneck\n        ]\n        self.conv = nn.Sequential(*layers)\n\n    def forward(self, x):\n        out = self.conv(x)\n        return out + x if self.use_skip else out\n\nblock = InvertedResidual(32, 32, stride=1, expand_ratio=6)\nx = torch.randn(4, 32, 28, 28)\nprint(f\u0027Output: {tuple(block(x).shape)}\u0027)\np = sum(q.numel() for q in block.parameters())\nprint(f\u0027Params (C=32, t=6): {p:,}\u0027)"},{"type":"heading","level":2,"content":"ShuffleNet — Channel Shuffle for Cross-Group Communication"},{"type":"text","content":"Grouped convolution cuts FLOP and parameter counts but prevents information flow between groups. ShuffleNet (Zhang et al. 2018) solves this with a channel shuffle operation: after a grouped pointwise conv, the output channels are divided into g groups and then interleaved so each group of the next layer sees channels from all previous groups. The shuffle is a simple reshape + transpose + flatten — zero extra parameters, zero extra FLOPs. ShuffleNetV2 (Ma et al. 2018) further shows that equal channel widths in input/output, fewer groups, and split+concat (not add) give the best throughput on real hardware."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ndef channel_shuffle(x, groups):\n    \"\"\"Rearrange channels so grouped conv outputs get cross-group info.\"\"\"\n    N, C, H, W = x.shape\n    assert C % groups == 0\n    x = x.view(N, groups, C // groups, H, W)\n    x = x.transpose(1, 2).contiguous()  # swap group and channel dims\n    return x.view(N, C, H, W)\n\nclass ShuffleBlock(nn.Module):\n    def __init__(self, C_in, C_out, groups=4):\n        super().__init__()\n        self.groups = groups\n        C_mid = C_out\n        self.pw1 = nn.Sequential(\n            nn.Conv2d(C_in, C_mid, 1, groups=groups, bias=False),\n            nn.BatchNorm2d(C_mid), nn.ReLU(inplace=True)\n        )\n        self.dw = nn.Sequential(\n            nn.Conv2d(C_mid, C_mid, 3, padding=1, groups=C_mid, bias=False),\n            nn.BatchNorm2d(C_mid)\n        )\n        self.pw2 = nn.Sequential(\n            nn.Conv2d(C_mid, C_out, 1, groups=groups, bias=False),\n            nn.BatchNorm2d(C_out), nn.ReLU(inplace=True)\n        )\n\n    def forward(self, x):\n        x = self.pw1(x)\n        x = channel_shuffle(x, self.groups)  # \u003c-- cross-group communication\n        x = self.dw(x)\n        x = self.pw2(x)\n        return x\n\nblk = ShuffleBlock(64, 64, groups=4)\nx = torch.randn(2, 64, 14, 14)\nprint(f\u0027Output: {tuple(blk(x).shape)}\u0027)\nprint(f\u0027Params: {sum(p.numel() for p in blk.parameters()):,}\u0027)"},{"type":"callout","variant":"warning","title":"Depthwise Conv is Slow on Accelerators","content":"Depthwise separable convolution has fewer FLOPs than standard conv on paper, but it can be slower on GPUs because its memory access pattern is less cache-friendly and it under-utilises tensor cores designed for large matrix multiplications. ShuffleNetV2 explicitly benchmarks wall-clock time rather than FLOPs, finding that fewer groups and balanced channel widths matter more than raw FLOP counts for actual throughput. Always profile on target hardware."},{"type":"heading","level":2,"content":"Accuracy-Efficiency Tradeoffs"},{"type":"text","content":"The efficiency gains from grouped and depthwise separable convolutions come with an accuracy cost — fewer cross-channel interactions mean the network must learn to compensate with more depth or width. In practice, the tradeoff is excellent for mobile deployment: MobileNetV3-Large achieves 75.2% ImageNet top-1 at 219M MFLOPs, compared to ResNet-50\u0027s 76.1% at 4100M MFLOPs — 19× fewer FLOPs for nearly the same accuracy. The key enabler is the Neural Architecture Search (NAS) used to tune the channel widths and expansion ratios per layer."},{"type":"table","headers":["Conv Type","Params","FLOPs","Cross-Channel Mixing","Accuracy Tradeoff","Use Case"],"rows":[["Standard","C_in·C_out·k²","2HW·C_in·C_out·k²","Full (all→all)","Baseline","General, accuracy-first"],["Grouped (g)","C_in·C_out·k²/g","Same ÷g","Within group only","Small drop","ResNeXt, multi-GPU"],["Depthwise","C_in·k²","2HW·C_in·k²","None (per-channel)","Large drop alone","Always paired with PW"],["DW-Separable","C_in·k²+C_in·C_out","2HW·C_in·(k²+C_out)","Via PW conv","~1% drop vs standard","MobileNet, edge devices"],["Shuffle (g)","Same as grouped÷g","Same ÷g","Cross-group via shuffle","Minimal drop","ShuffleNet, mobile"]]},{"type":"list","ordered":false,"items":["MobileNetV1 width multiplier α: scales all channels by α, reducing params by α², FLOPs by α².","MobileNetV1 resolution multiplier ρ: scales input resolution, reducing FLOPs by ρ².","EfficientNet: compound scaling of depth, width, and resolution simultaneously via NAS.","For groups=C_in (depthwise), PyTorch requires C_out==C_in; use a subsequent 1×1 to change channel count.","TFLite and CoreML optimise depthwise conv separately from standard conv — check platform support."]},{"type":"heading","level":2,"content":"Hardware-Aware Design with Grouped Convolutions"},{"type":"text","content":"The computational advantage of depthwise separable and grouped convolutions is real in FLOP terms but can be elusive on GPU hardware. cuDNN\u0027s GEMM-based convolution is highly tuned for large matrix multiplications that arise in standard conv; grouped conv with many small groups underutilises tensor cores. NVIDIA\u0027s Ampere A100 added dedicated support for grouped convolutions at the hardware level. On ARM CPUs (mobile SoCs), depthwise conv benefits from NEON SIMD instructions and is genuinely faster — Apple\u0027s Neural Engine, Qualcomm\u0027s AI Engine, and Google\u0027s Edge TPU all have first-class depthwise conv support."},{"type":"text","content":"Practical deployment recommendation: benchmark your specific architecture on your specific target hardware. Tools like AI Benchmark, MLPerf Mobile, and torch.utils.benchmark provide accurate latency numbers. A rule of thumb: for server GPU inference, prefer standard conv with moderate channel counts; for mobile CPU/NPU inference, depthwise separable conv with width multiplier α=0.75–1.0 gives the best latency/accuracy tradeoff."},{"type":"list","ordered":false,"items":["Use groups=C_in (depthwise) only when followed immediately by a pointwise 1×1 conv — alone it has limited expressivity.","EfficientNet-B0 through B7 use compound scaling: depth α^φ, width β^φ, resolution γ^φ with α·β²·γ² ≈ 2.","GhostNet: generates \u0027ghost\u0027 feature maps by cheap linear operations on a subset of real conv outputs.","CondConv and DynamicConv: input-conditioned combinations of multiple kernels — adaptive grouped conv."]},{"type":"divider"}]"
---
# Grouped and Depthwise Convolutions — MobileNet Efficiency

Standard convolution treats all input channels jointly: each output channel sees every input channel through its own kernel, enabling full cross-channel communication but at the cost of C_in×C_out×k² parameters. Grouped and depthwise convolutions break this coupling selectively. By splitting channels into groups or processing each channel independently, these operations achieve dramatic parameter and FLOP reductions while retaining most of the representational power — the foundation of efficient CNNs for mobile and edge deployment.

## Grouped Convolution

Grouped convolution (nn.Conv2d(..., groups=g)) splits C_in into g groups of C_in/g channels each, and C_out into g groups of C_out/g. Each group processes only its corresponding input channels independently. Total parameters: C_in × C_out × k² / g — a factor-g reduction. FLOPs reduce by the same factor. AlexNet used groups=2 as a practical workaround to fit on two GPUs in 2012. ResNeXt (2017) reframed grouped conv as 'aggregated residual transformations': groups=32 with wider channels matches ResNet accuracy with fewer FLOPs. The cost: no cross-group communication without an additional mixing step.

```python
import torch
import torch.nn as nn

C_in, C_out, k = 256, 256, 3

configs = [
    ('Standard (g=1)',  1),
    ('Grouped g=2',     2),
    ('Grouped g=4',     4),
    ('Grouped g=8',     8),
    ('Grouped g=32',   32),
    ('Depthwise g=C', C_in),
]

print(f'{'Config':<22} {'Params':>10} {'Reduction':>10}')
standard_params = None
for name, g in configs:
    conv = nn.Conv2d(C_in, C_out, k, padding=1, groups=g, bias=False)
    p = sum(x.numel() for x in conv.parameters())
    if standard_params is None:
        standard_params = p
    print(f'{name:<22} {p:>10,} {p/standard_params:>9.3f}x')

# Verify output shape is same for all
x = torch.randn(2, C_in, 14, 14)
for name, g in configs:
    conv = nn.Conv2d(C_in, C_out, k, padding=1, groups=g, bias=False)
    assert conv(x).shape == (2, C_out, 14, 14), f'Shape mismatch for {name}'
print('\nAll produce identical output shape (2, 256, 14, 14) ✓')
```

## Depthwise Separable Convolution

Depthwise separable convolution factorises a standard conv into two steps. Step 1 — Depthwise conv: apply one k×k kernel per input channel independently (groups=C_in), producing C_in output channels with C_in×k² parameters. Step 2 — Pointwise conv: apply a 1×1 conv to mix channels (C_in×C_out parameters). Total: C_in×k² + C_in×C_out vs C_in×C_out×k² for standard. The ratio is 1/C_out + 1/k² ≈ 1/k² = 1/9 for k=3 and large C_out. This is the core innovation of MobileNetV1: replace every 3×3 conv with a depthwise separable block, achieving ~8–9× reduction in computation with only ~1% top-1 accuracy loss on ImageNet.

```python
import torch
import torch.nn as nn

class DepthwiseSeparableConv(nn.Module):
    """MobileNetV1-style depthwise separable conv block."""
    def __init__(self, C_in, C_out, stride=1):
        super().__init__()
        self.dw = nn.Sequential(
            nn.Conv2d(C_in, C_in, 3, stride=stride, padding=1,
                      groups=C_in, bias=False),  # depthwise
            nn.BatchNorm2d(C_in),
            nn.ReLU6(inplace=True)
        )
        self.pw = nn.Sequential(
            nn.Conv2d(C_in, C_out, 1, bias=False),  # pointwise
            nn.BatchNorm2d(C_out),
            nn.ReLU6(inplace=True)
        )

    def forward(self, x):
        return self.pw(self.dw(x))

# Compare parameter counts
C_in, C_out = 128, 256
standard = nn.Conv2d(C_in, C_out, 3, padding=1, bias=False)
dws      = DepthwiseSeparableConv(C_in, C_out)

p_std = sum(p.numel() for p in standard.parameters())
p_dws = sum(p.numel() for p in dws.parameters())
print(f'Standard conv params:      {p_std:,}')
print(f'Depthwise-sep params:      {p_dws:,}')
print(f'Reduction factor:          {p_std/p_dws:.2f}x')

x = torch.randn(4, C_in, 28, 28)
print(f'\nInput {tuple(x.shape)} -> Output {tuple(dws(x).shape)}')
```

## MobileNetV2 — Inverted Residuals and Linear Bottleneck

MobileNetV2 introduces two key ideas. First, the inverted residual: unlike ResNet's bottleneck (wide → narrow → wide), MobileNetV2 expands channels (narrow → wide → narrow), applying the depthwise conv in the expanded high-dimensional space where spatial mixing is richer, then projects back. Second, the linear bottleneck: the final pointwise projection uses no activation (linear), because ReLU in low-dimensional spaces destroys information by collapsing the manifold. The skip connection is added only when input and output have the same shape. This design achieves better accuracy/FLOP tradeoff than MobileNetV1.

```python
import torch
import torch.nn as nn

class InvertedResidual(nn.Module):
    """MobileNetV2 inverted residual block."""
    def __init__(self, C_in, C_out, stride=1, expand_ratio=6):
        super().__init__()
        C_mid = C_in * expand_ratio
        self.use_skip = (stride == 1 and C_in == C_out)
        layers = []
        if expand_ratio != 1:  # expansion phase
            layers += [nn.Conv2d(C_in, C_mid, 1, bias=False),
                       nn.BatchNorm2d(C_mid), nn.ReLU6(inplace=True)]
        layers += [
            nn.Conv2d(C_mid, C_mid, 3, stride=stride,  # depthwise
                      padding=1, groups=C_mid, bias=False),
            nn.BatchNorm2d(C_mid), nn.ReLU6(inplace=True),
            nn.Conv2d(C_mid, C_out, 1, bias=False),    # linear projection
            nn.BatchNorm2d(C_out)
            # NO activation after last BN — linear bottleneck
        ]
        self.conv = nn.Sequential(*layers)

    def forward(self, x):
        out = self.conv(x)
        return out + x if self.use_skip else out

block = InvertedResidual(32, 32, stride=1, expand_ratio=6)
x = torch.randn(4, 32, 28, 28)
print(f'Output: {tuple(block(x).shape)}')
p = sum(q.numel() for q in block.parameters())
print(f'Params (C=32, t=6): {p:,}')
```

## ShuffleNet — Channel Shuffle for Cross-Group Communication

Grouped convolution cuts FLOP and parameter counts but prevents information flow between groups. ShuffleNet (Zhang et al. 2018) solves this with a channel shuffle operation: after a grouped pointwise conv, the output channels are divided into g groups and then interleaved so each group of the next layer sees channels from all previous groups. The shuffle is a simple reshape + transpose + flatten — zero extra parameters, zero extra FLOPs. ShuffleNetV2 (Ma et al. 2018) further shows that equal channel widths in input/output, fewer groups, and split+concat (not add) give the best throughput on real hardware.

```python
import torch
import torch.nn as nn

def channel_shuffle(x, groups):
    """Rearrange channels so grouped conv outputs get cross-group info."""
    N, C, H, W = x.shape
    assert C % groups == 0
    x = x.view(N, groups, C // groups, H, W)
    x = x.transpose(1, 2).contiguous()  # swap group and channel dims
    return x.view(N, C, H, W)

class ShuffleBlock(nn.Module):
    def __init__(self, C_in, C_out, groups=4):
        super().__init__()
        self.groups = groups
        C_mid = C_out
        self.pw1 = nn.Sequential(
            nn.Conv2d(C_in, C_mid, 1, groups=groups, bias=False),
            nn.BatchNorm2d(C_mid), nn.ReLU(inplace=True)
        )
        self.dw = nn.Sequential(
            nn.Conv2d(C_mid, C_mid, 3, padding=1, groups=C_mid, bias=False),
            nn.BatchNorm2d(C_mid)
        )
        self.pw2 = nn.Sequential(
            nn.Conv2d(C_mid, C_out, 1, groups=groups, bias=False),
            nn.BatchNorm2d(C_out), nn.ReLU(inplace=True)
        )

    def forward(self, x):
        x = self.pw1(x)
        x = channel_shuffle(x, self.groups)  # <-- cross-group communication
        x = self.dw(x)
        x = self.pw2(x)
        return x

blk = ShuffleBlock(64, 64, groups=4)
x = torch.randn(2, 64, 14, 14)
print(f'Output: {tuple(blk(x).shape)}')
print(f'Params: {sum(p.numel() for p in blk.parameters()):,}')
```

> **Depthwise Conv is Slow on Accelerators**: Depthwise separable convolution has fewer FLOPs than standard conv on paper, but it can be slower on GPUs because its memory access pattern is less cache-friendly and it under-utilises tensor cores designed for large matrix multiplications. ShuffleNetV2 explicitly benchmarks wall-clock time rather than FLOPs, finding that fewer groups and balanced channel widths matter more than raw FLOP counts for actual throughput. Always profile on target hardware.

## Accuracy-Efficiency Tradeoffs

The efficiency gains from grouped and depthwise separable convolutions come with an accuracy cost — fewer cross-channel interactions mean the network must learn to compensate with more depth or width. In practice, the tradeoff is excellent for mobile deployment: MobileNetV3-Large achieves 75.2% ImageNet top-1 at 219M MFLOPs, compared to ResNet-50's 76.1% at 4100M MFLOPs — 19× fewer FLOPs for nearly the same accuracy. The key enabler is the Neural Architecture Search (NAS) used to tune the channel widths and expansion ratios per layer.

| Conv Type | Params | FLOPs | Cross-Channel Mixing | Accuracy Tradeoff | Use Case |
| --- | --- | --- | --- | --- | --- |
| Standard | C_in·C_out·k² | 2HW·C_in·C_out·k² | Full (all→all) | Baseline | General, accuracy-first |
| Grouped (g) | C_in·C_out·k²/g | Same ÷g | Within group only | Small drop | ResNeXt, multi-GPU |
| Depthwise | C_in·k² | 2HW·C_in·k² | None (per-channel) | Large drop alone | Always paired with PW |
| DW-Separable | C_in·k²+C_in·C_out | 2HW·C_in·(k²+C_out) | Via PW conv | ~1% drop vs standard | MobileNet, edge devices |
| Shuffle (g) | Same as grouped÷g | Same ÷g | Cross-group via shuffle | Minimal drop | ShuffleNet, mobile |

- MobileNetV1 width multiplier α: scales all channels by α, reducing params by α², FLOPs by α².
- MobileNetV1 resolution multiplier ρ: scales input resolution, reducing FLOPs by ρ².
- EfficientNet: compound scaling of depth, width, and resolution simultaneously via NAS.
- For groups=C_in (depthwise), PyTorch requires C_out==C_in; use a subsequent 1×1 to change channel count.
- TFLite and CoreML optimise depthwise conv separately from standard conv — check platform support.

## Hardware-Aware Design with Grouped Convolutions

The computational advantage of depthwise separable and grouped convolutions is real in FLOP terms but can be elusive on GPU hardware. cuDNN's GEMM-based convolution is highly tuned for large matrix multiplications that arise in standard conv; grouped conv with many small groups underutilises tensor cores. NVIDIA's Ampere A100 added dedicated support for grouped convolutions at the hardware level. On ARM CPUs (mobile SoCs), depthwise conv benefits from NEON SIMD instructions and is genuinely faster — Apple's Neural Engine, Qualcomm's AI Engine, and Google's Edge TPU all have first-class depthwise conv support.

Practical deployment recommendation: benchmark your specific architecture on your specific target hardware. Tools like AI Benchmark, MLPerf Mobile, and torch.utils.benchmark provide accurate latency numbers. A rule of thumb: for server GPU inference, prefer standard conv with moderate channel counts; for mobile CPU/NPU inference, depthwise separable conv with width multiplier α=0.75–1.0 gives the best latency/accuracy tradeoff.

- Use groups=C_in (depthwise) only when followed immediately by a pointwise 1×1 conv — alone it has limited expressivity.
- EfficientNet-B0 through B7 use compound scaling: depth α^φ, width β^φ, resolution γ^φ with α·β²·γ² ≈ 2.
- GhostNet: generates 'ghost' feature maps by cheap linear operations on a subset of real conv outputs.
- CondConv and DynamicConv: input-conditioned combinations of multiple kernels — adaptive grouped conv.

---

