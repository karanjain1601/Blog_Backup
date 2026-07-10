---
title: "GoogLeNet / Inception — Parallel Branches and Auxiliary Classifiers"
slug: "googlenet-inception"
description: "GoogLeNet introduces the Inception module — parallel 1×1, 3×3, 5×5, and max-pool branches concatenated to capture multi-scale features — achieving 5M parameters (vs AlexNet's 60M) through 1×1 bottlenecks. Inception-v3 adds factorization; Xception pushes to depthwise separable convolutions."
tags: ["deep-learning", "cnns", "architectures"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"GoogLeNet (Szegedy et al., 2014, also Inception-v1) asks a different question from VGG: instead of going deeper uniformly, what if a single layer captures features at multiple scales simultaneously? The Inception module applies parallel convolutions of different kernel sizes and concatenates their outputs. This multi-scale processing — 1×1 for cross-channel projection, 3×3 for local features, 5×5 for broader context, plus max pooling for spatial invariance — captures a richer feature representation than any single kernel size, while 1×1 bottlenecks keep computation tractable."},{"type":"heading","level":2,"content":"Motivation: Efficiency Through Architectural Width"},{"type":"text","content":"Larger networks mean more parameters and more computation — two resources that scale poorly with depth alone. GoogLeNet\u0027s solution is architectural width: within a single layer, apply multiple filter sizes in parallel and let the network learn which scales are most informative. The 1×1 convolution is key: applied before expensive 3×3 and 5×5 convolutions, it acts as a channel-reduction bottleneck. Without 1×1 reduction, a single Inception module on 256-channel input with 64 filters of 5×5 costs 256×64×25×H×W = 409,600×H×W multiply-adds. With a 1×1 reduction to 32 channels first: 256×32 + 32×64×25 = 59,392 — a 7× reduction."},{"type":"heading","level":2,"content":"The Inception Module"},{"type":"text","content":"The Inception-v1 module has four parallel branches: (1) 1×1 conv for direct channel projection; (2) 1×1 conv reducing channels, followed by 3×3 conv; (3) 1×1 conv reducing channels, followed by 5×5 conv; (4) 3×3 max pooling followed by 1×1 conv. All branches preserve spatial dimensions (via appropriate padding) and their outputs are concatenated along the channel dimension. The network learns to weight these pathways through backpropagation — effectively performing sparse, multi-scale feature extraction at each layer."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass InceptionModule(nn.Module):\n    \u0027\u0027\u0027Inception-v1 module: parallel branches at 1x1, 3x3, 5x5, max-pool.\u0027\u0027\u0027\n    def __init__(self, in_ch, ch1x1, ch3x3_r, ch3x3, ch5x5_r, ch5x5, ch_pool):\n        super().__init__()\n        self.branch1 = nn.Sequential(\n            nn.Conv2d(in_ch, ch1x1, 1), nn.ReLU(inplace=True))\n        self.branch2 = nn.Sequential(\n            nn.Conv2d(in_ch, ch3x3_r, 1), nn.ReLU(inplace=True),\n            nn.Conv2d(ch3x3_r, ch3x3, 3, padding=1), nn.ReLU(inplace=True))\n        self.branch3 = nn.Sequential(\n            nn.Conv2d(in_ch, ch5x5_r, 1), nn.ReLU(inplace=True),\n            nn.Conv2d(ch5x5_r, ch5x5, 5, padding=2), nn.ReLU(inplace=True))\n        self.branch4 = nn.Sequential(\n            nn.MaxPool2d(3, stride=1, padding=1),\n            nn.Conv2d(in_ch, ch_pool, 1), nn.ReLU(inplace=True))\n\n    def forward(self, x):\n        return torch.cat([self.branch1(x), self.branch2(x),\n                          self.branch3(x), self.branch4(x)], dim=1)\n\n# Inception-3a from GoogLeNet paper: in=192, out=64+128+32+32=256\nmodule = InceptionModule(192, 64, 96, 128, 16, 32, 32)\nx = torch.randn(2, 192, 28, 28)\nout = module(x)\nparams = sum(p.numel() for p in module.parameters())\nprint(\u0027Inception-3a: {} -\u003e {}\u0027.format(x.shape, out.shape))\nprint(\u0027Output channels: 64+128+32+32 = {}\u0027.format(64+128+32+32))\nprint(\u0027Parameters: {:,}\u0027.format(params))"},{"type":"heading","level":2,"content":"1x1 Convolutions as Channel Bottlenecks"},{"type":"text","content":"The 1×1 convolution (also called a pointwise convolution or network-in-network projection) operates identically to a linear combination across channels at each spatial location. It reduces channels before expensive convolutions — for example, reducing 256 channels to 32 before a 5×5 conv cuts the 5×5 computation by 8× — and expands channels after depthwise convolutions in modern architectures. Beyond channel reduction, 1×1 convs add nonlinearity (paired with ReLU) and mix information across channels without any spatial mixing. Lin et al. (2014) showed that 1×1 conv layers act as \u0027micro-networks\u0027 within each spatial location, greatly increasing representational capacity."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ndef count_params(m): return sum(p.numel() for p in m.parameters())\ndef count_flops_conv(in_ch, out_ch, k, h, w):\n    return 2 * in_ch * out_ch * k * k * h * w\n\nin_ch, out_ch, H, W = 256, 128, 14, 14\n\n# Direct 5x5 conv\ndirect = nn.Conv2d(in_ch, out_ch, 5, padding=2)\n\n# 1x1 bottleneck + 5x5 conv\nbottleneck = nn.Sequential(\n    nn.Conv2d(in_ch, 32, 1), nn.ReLU(inplace=True),\n    nn.Conv2d(32, out_ch, 5, padding=2))\n\ndirect_params = count_params(direct)\nbottle_params = count_params(bottleneck)\ndirect_flops  = count_flops_conv(in_ch, out_ch, 5, H, W)\nbottle_flops  = (count_flops_conv(in_ch, 32, 1, H, W) +\n                 count_flops_conv(32, out_ch, 5, H, W))\n\nprint(\u0027{:\u003c20} {:\u003e12} {:\u003e14}\u0027.format(\u0027Config\u0027, \u0027Params\u0027, \u0027FLOPs\u0027))\nprint(\u0027{:\u003c20} {:\u003e12,} {:\u003e14,}\u0027.format(\u0027Direct 5x5\u0027, direct_params, direct_flops))\nprint(\u0027{:\u003c20} {:\u003e12,} {:\u003e14,}\u0027.format(\u00271x1+5x5 bottleneck\u0027, bottle_params, bottle_flops))\nprint(\u0027Param reduction: {:.1f}x\u0027.format(direct_params / bottle_params))\nprint(\u0027FLOP reduction:  {:.1f}x\u0027.format(direct_flops / bottle_flops))"},{"type":"heading","level":2,"content":"Auxiliary Classifiers"},{"type":"text","content":"GoogLeNet inserts two auxiliary classification heads at intermediate depths (after Inception-4a and Inception-4d). During training, these auxiliary outputs compute softmax losses (weighted by 0.3) that are added to the main loss. Gradients from these intermediate losses flow backward into the lower layers, providing an additional training signal and combating vanishing gradients in the 22-layer network. At inference time, auxiliary classifiers are removed. The Inception authors later acknowledged that the regularisation effect (dropout before auxiliary classifiers) contributed more than the gradient signal — Inception-v3 retained only one auxiliary classifier."},{"type":"callout","variant":"info","title":"Auxiliary Classifiers vs Residuals","content":"Auxiliary classifiers solve the vanishing gradient problem by injecting loss signal at intermediate layers — an engineering workaround. ResNet (2015) solved the same problem more elegantly with skip connections that provide a direct gradient path. With skip connections, auxiliary classifiers become unnecessary. Inception-v4 and Inception-ResNet combine both approaches, but the residual path dominates. Modern architectures universally prefer residuals over auxiliary classifiers."},{"type":"heading","level":2,"content":"Inception-v3: Factorization and Asymmetric Convolutions"},{"type":"text","content":"Inception-v3 (Szegedy et al., 2016) introduces three key improvements: (1) factorize 5×5 convolutions into two stacked 3×3 convolutions (same RF, fewer parameters); (2) factorize n×n convolutions into asymmetric 1×n + n×1 convolutions — for n=7, this reduces parameters from 49C² to 14C² (3.5× saving); (3) label smoothing as a regulariser (target distribution: 0.9 for true class, 0.1/(K-1) for others); (4) BatchNorm applied throughout the auxiliary classifier. These changes reduced computation by a factor of 4 while improving accuracy to 78.8% top-1 on ImageNet."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ndef count_params(m): return sum(p.numel() for p in m.parameters())\n\nin_ch, out_ch, n = 256, 256, 7\n\n# Standard nxn conv\nstandard = nn.Sequential(\n    nn.Conv2d(in_ch, out_ch, n, padding=n//2, bias=False),\n    nn.BatchNorm2d(out_ch), nn.ReLU(inplace=True))\n\n# Factored into two 3x3 convs (for n=5 case)\nfactored_5x5 = nn.Sequential(\n    nn.Conv2d(in_ch, out_ch, 3, padding=1, bias=False),\n    nn.BatchNorm2d(out_ch), nn.ReLU(inplace=True),\n    nn.Conv2d(out_ch, out_ch, 3, padding=1, bias=False),\n    nn.BatchNorm2d(out_ch), nn.ReLU(inplace=True))\n\n# Asymmetric factorization: 1xn + nx1\nasymmetric = nn.Sequential(\n    nn.Conv2d(in_ch, out_ch, (1, n), padding=(0, n//2), bias=False),\n    nn.BatchNorm2d(out_ch), nn.ReLU(inplace=True),\n    nn.Conv2d(out_ch, out_ch, (n, 1), padding=(n//2, 0), bias=False),\n    nn.BatchNorm2d(out_ch), nn.ReLU(inplace=True))\n\nx = torch.randn(2, in_ch, 17, 17)\nfor name, m in [(\u0027{}x{} standard\u0027.format(n,n), standard),\n                (\u0027two 3x3\u0027, factored_5x5),\n                (\u00271x{}+{}x1\u0027.format(n,n), asymmetric)]:\n    print(\u0027{:\u003c18} params={:\u003e8,}  out={}\u0027.format(name, count_params(m), m(x).shape))"},{"type":"heading","level":2,"content":"Xception: Extreme Inception"},{"type":"text","content":"Xception (Chollet, 2017) takes Inception to its logical extreme: if Inception modules are essentially depthwise separable convolutions (spatial filtering per channel, followed by cross-channel mixing), why not replace all convolutions with depthwise separable operations? Xception uses 36 depthwise separable conv layers in a linear stack with residual connections. A depthwise separable conv applies a spatial 3×3 filter to each input channel independently (depthwise), then mixes channels with a 1×1 conv (pointwise). For C input and output channels, this costs C×9 + C² parameters vs C²×9 for a standard conv — roughly a 1/9 + 1/C saving, typically 8–9× fewer parameters."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ndef count_params(m): return sum(p.numel() for p in m.parameters())\n\nclass DepthwiseSeparable(nn.Module):\n    \u0027\u0027\u0027Xception-style depthwise separable convolution block.\u0027\u0027\u0027\n    def __init__(self, in_ch, out_ch):\n        super().__init__()\n        self.dw = nn.Conv2d(in_ch, in_ch, 3, padding=1, groups=in_ch, bias=False)\n        self.pw = nn.Conv2d(in_ch, out_ch, 1, bias=False)\n        self.bn = nn.BatchNorm2d(out_ch)\n        self.relu = nn.ReLU(inplace=True)\n    def forward(self, x): return self.relu(self.bn(self.pw(self.dw(x))))\n\nclass StandardConvBlock(nn.Module):\n    def __init__(self, in_ch, out_ch):\n        super().__init__()\n        self.conv = nn.Conv2d(in_ch, out_ch, 3, padding=1, bias=False)\n        self.bn   = nn.BatchNorm2d(out_ch)\n        self.relu = nn.ReLU(inplace=True)\n    def forward(self, x): return self.relu(self.bn(self.conv(x)))\n\nin_ch, out_ch = 256, 256\nstd = StandardConvBlock(in_ch, out_ch)\ndws = DepthwiseSeparable(in_ch, out_ch)\nx = torch.randn(2, in_ch, 28, 28)\n\nratio = count_params(std) / count_params(dws)\ntheory = 1/9 + 1/out_ch\nprint(\u0027Standard conv:   {:\u003e8,} params  output {}\u0027.format(count_params(std), std(x).shape))\nprint(\u0027DW Separable:    {:\u003e8,} params  output {}\u0027.format(count_params(dws), dws(x).shape))\nprint(\u0027Reduction: {:.2f}x  (theory: 1/9+1/C = {:.4f})\u0027.format(ratio, theory))"},{"type":"heading","level":2,"content":"Inception Versions Comparison"},{"type":"text","content":"Each Inception version addresses a specific limitation of its predecessor: v1 introduced multi-scale parallel branches; v3 factorised operations for efficiency; v4 added residual connections for easier training; Xception replaced inception blocks with depthwise separable convolutions entirely."},{"type":"table","headers":["Model","Year","Params","GFLOPs","Top-1 Acc","Key Innovation"],"rows":[["GoogLeNet (v1)","2014","5M","1.5","69.8%","Inception module + auxiliary classifiers"],["Inception-v3","2016","23M","5.7","78.8%","Factorized 5×5 + asymmetric 1×n, label smoothing"],["Inception-v4","2016","42M","12.3","80.0%","Deeper inception with uniform stem block"],["Inception-ResNet-v2","2016","55M","13.2","80.4%","Inception modules + residual shortcuts"],["Xception","2017","22M","8.4","79.0%","All convolutions replaced by depthwise separable"]]},{"type":"list","ordered":false,"items":["GoogLeNet achieved AlexNet-level accuracy with 12x fewer parameters — demonstrating that architectural design matters more than raw scale.","1x1 convolutions are now universal: they appear in ResNet bottlenecks, MobileNet, EfficientNet, and transformer projection layers.","Asymmetric factorisation (1xn + nx1) inspired the use of depthwise separable convolutions in MobileNet and ShuffleNet.","Auxiliary classifiers were largely abandoned after residual connections provided a cleaner solution to the vanishing gradient problem."]},{"type":"divider"}]"
---
# GoogLeNet / Inception — Parallel Branches and Auxiliary Classifiers

GoogLeNet (Szegedy et al., 2014, also Inception-v1) asks a different question from VGG: instead of going deeper uniformly, what if a single layer captures features at multiple scales simultaneously? The Inception module applies parallel convolutions of different kernel sizes and concatenates their outputs. This multi-scale processing — 1×1 for cross-channel projection, 3×3 for local features, 5×5 for broader context, plus max pooling for spatial invariance — captures a richer feature representation than any single kernel size, while 1×1 bottlenecks keep computation tractable.

## Motivation: Efficiency Through Architectural Width

Larger networks mean more parameters and more computation — two resources that scale poorly with depth alone. GoogLeNet's solution is architectural width: within a single layer, apply multiple filter sizes in parallel and let the network learn which scales are most informative. The 1×1 convolution is key: applied before expensive 3×3 and 5×5 convolutions, it acts as a channel-reduction bottleneck. Without 1×1 reduction, a single Inception module on 256-channel input with 64 filters of 5×5 costs 256×64×25×H×W = 409,600×H×W multiply-adds. With a 1×1 reduction to 32 channels first: 256×32 + 32×64×25 = 59,392 — a 7× reduction.

## The Inception Module

The Inception-v1 module has four parallel branches: (1) 1×1 conv for direct channel projection; (2) 1×1 conv reducing channels, followed by 3×3 conv; (3) 1×1 conv reducing channels, followed by 5×5 conv; (4) 3×3 max pooling followed by 1×1 conv. All branches preserve spatial dimensions (via appropriate padding) and their outputs are concatenated along the channel dimension. The network learns to weight these pathways through backpropagation — effectively performing sparse, multi-scale feature extraction at each layer.

```python
import torch
import torch.nn as nn

class InceptionModule(nn.Module):
    '''Inception-v1 module: parallel branches at 1x1, 3x3, 5x5, max-pool.'''
    def __init__(self, in_ch, ch1x1, ch3x3_r, ch3x3, ch5x5_r, ch5x5, ch_pool):
        super().__init__()
        self.branch1 = nn.Sequential(
            nn.Conv2d(in_ch, ch1x1, 1), nn.ReLU(inplace=True))
        self.branch2 = nn.Sequential(
            nn.Conv2d(in_ch, ch3x3_r, 1), nn.ReLU(inplace=True),
            nn.Conv2d(ch3x3_r, ch3x3, 3, padding=1), nn.ReLU(inplace=True))
        self.branch3 = nn.Sequential(
            nn.Conv2d(in_ch, ch5x5_r, 1), nn.ReLU(inplace=True),
            nn.Conv2d(ch5x5_r, ch5x5, 5, padding=2), nn.ReLU(inplace=True))
        self.branch4 = nn.Sequential(
            nn.MaxPool2d(3, stride=1, padding=1),
            nn.Conv2d(in_ch, ch_pool, 1), nn.ReLU(inplace=True))

    def forward(self, x):
        return torch.cat([self.branch1(x), self.branch2(x),
                          self.branch3(x), self.branch4(x)], dim=1)

# Inception-3a from GoogLeNet paper: in=192, out=64+128+32+32=256
module = InceptionModule(192, 64, 96, 128, 16, 32, 32)
x = torch.randn(2, 192, 28, 28)
out = module(x)
params = sum(p.numel() for p in module.parameters())
print('Inception-3a: {} -> {}'.format(x.shape, out.shape))
print('Output channels: 64+128+32+32 = {}'.format(64+128+32+32))
print('Parameters: {:,}'.format(params))
```

## 1x1 Convolutions as Channel Bottlenecks

The 1×1 convolution (also called a pointwise convolution or network-in-network projection) operates identically to a linear combination across channels at each spatial location. It reduces channels before expensive convolutions — for example, reducing 256 channels to 32 before a 5×5 conv cuts the 5×5 computation by 8× — and expands channels after depthwise convolutions in modern architectures. Beyond channel reduction, 1×1 convs add nonlinearity (paired with ReLU) and mix information across channels without any spatial mixing. Lin et al. (2014) showed that 1×1 conv layers act as 'micro-networks' within each spatial location, greatly increasing representational capacity.

```python
import torch
import torch.nn as nn

def count_params(m): return sum(p.numel() for p in m.parameters())
def count_flops_conv(in_ch, out_ch, k, h, w):
    return 2 * in_ch * out_ch * k * k * h * w

in_ch, out_ch, H, W = 256, 128, 14, 14

# Direct 5x5 conv
direct = nn.Conv2d(in_ch, out_ch, 5, padding=2)

# 1x1 bottleneck + 5x5 conv
bottleneck = nn.Sequential(
    nn.Conv2d(in_ch, 32, 1), nn.ReLU(inplace=True),
    nn.Conv2d(32, out_ch, 5, padding=2))

direct_params = count_params(direct)
bottle_params = count_params(bottleneck)
direct_flops  = count_flops_conv(in_ch, out_ch, 5, H, W)
bottle_flops  = (count_flops_conv(in_ch, 32, 1, H, W) +
                 count_flops_conv(32, out_ch, 5, H, W))

print('{:<20} {:>12} {:>14}'.format('Config', 'Params', 'FLOPs'))
print('{:<20} {:>12,} {:>14,}'.format('Direct 5x5', direct_params, direct_flops))
print('{:<20} {:>12,} {:>14,}'.format('1x1+5x5 bottleneck', bottle_params, bottle_flops))
print('Param reduction: {:.1f}x'.format(direct_params / bottle_params))
print('FLOP reduction:  {:.1f}x'.format(direct_flops / bottle_flops))
```

## Auxiliary Classifiers

GoogLeNet inserts two auxiliary classification heads at intermediate depths (after Inception-4a and Inception-4d). During training, these auxiliary outputs compute softmax losses (weighted by 0.3) that are added to the main loss. Gradients from these intermediate losses flow backward into the lower layers, providing an additional training signal and combating vanishing gradients in the 22-layer network. At inference time, auxiliary classifiers are removed. The Inception authors later acknowledged that the regularisation effect (dropout before auxiliary classifiers) contributed more than the gradient signal — Inception-v3 retained only one auxiliary classifier.

> **Auxiliary Classifiers vs Residuals**: Auxiliary classifiers solve the vanishing gradient problem by injecting loss signal at intermediate layers — an engineering workaround. ResNet (2015) solved the same problem more elegantly with skip connections that provide a direct gradient path. With skip connections, auxiliary classifiers become unnecessary. Inception-v4 and Inception-ResNet combine both approaches, but the residual path dominates. Modern architectures universally prefer residuals over auxiliary classifiers.

## Inception-v3: Factorization and Asymmetric Convolutions

Inception-v3 (Szegedy et al., 2016) introduces three key improvements: (1) factorize 5×5 convolutions into two stacked 3×3 convolutions (same RF, fewer parameters); (2) factorize n×n convolutions into asymmetric 1×n + n×1 convolutions — for n=7, this reduces parameters from 49C² to 14C² (3.5× saving); (3) label smoothing as a regulariser (target distribution: 0.9 for true class, 0.1/(K-1) for others); (4) BatchNorm applied throughout the auxiliary classifier. These changes reduced computation by a factor of 4 while improving accuracy to 78.8% top-1 on ImageNet.

```python
import torch
import torch.nn as nn

def count_params(m): return sum(p.numel() for p in m.parameters())

in_ch, out_ch, n = 256, 256, 7

# Standard nxn conv
standard = nn.Sequential(
    nn.Conv2d(in_ch, out_ch, n, padding=n//2, bias=False),
    nn.BatchNorm2d(out_ch), nn.ReLU(inplace=True))

# Factored into two 3x3 convs (for n=5 case)
factored_5x5 = nn.Sequential(
    nn.Conv2d(in_ch, out_ch, 3, padding=1, bias=False),
    nn.BatchNorm2d(out_ch), nn.ReLU(inplace=True),
    nn.Conv2d(out_ch, out_ch, 3, padding=1, bias=False),
    nn.BatchNorm2d(out_ch), nn.ReLU(inplace=True))

# Asymmetric factorization: 1xn + nx1
asymmetric = nn.Sequential(
    nn.Conv2d(in_ch, out_ch, (1, n), padding=(0, n//2), bias=False),
    nn.BatchNorm2d(out_ch), nn.ReLU(inplace=True),
    nn.Conv2d(out_ch, out_ch, (n, 1), padding=(n//2, 0), bias=False),
    nn.BatchNorm2d(out_ch), nn.ReLU(inplace=True))

x = torch.randn(2, in_ch, 17, 17)
for name, m in [('{}x{} standard'.format(n,n), standard),
                ('two 3x3', factored_5x5),
                ('1x{}+{}x1'.format(n,n), asymmetric)]:
    print('{:<18} params={:>8,}  out={}'.format(name, count_params(m), m(x).shape))
```

## Xception: Extreme Inception

Xception (Chollet, 2017) takes Inception to its logical extreme: if Inception modules are essentially depthwise separable convolutions (spatial filtering per channel, followed by cross-channel mixing), why not replace all convolutions with depthwise separable operations? Xception uses 36 depthwise separable conv layers in a linear stack with residual connections. A depthwise separable conv applies a spatial 3×3 filter to each input channel independently (depthwise), then mixes channels with a 1×1 conv (pointwise). For C input and output channels, this costs C×9 + C² parameters vs C²×9 for a standard conv — roughly a 1/9 + 1/C saving, typically 8–9× fewer parameters.

```python
import torch
import torch.nn as nn

def count_params(m): return sum(p.numel() for p in m.parameters())

class DepthwiseSeparable(nn.Module):
    '''Xception-style depthwise separable convolution block.'''
    def __init__(self, in_ch, out_ch):
        super().__init__()
        self.dw = nn.Conv2d(in_ch, in_ch, 3, padding=1, groups=in_ch, bias=False)
        self.pw = nn.Conv2d(in_ch, out_ch, 1, bias=False)
        self.bn = nn.BatchNorm2d(out_ch)
        self.relu = nn.ReLU(inplace=True)
    def forward(self, x): return self.relu(self.bn(self.pw(self.dw(x))))

class StandardConvBlock(nn.Module):
    def __init__(self, in_ch, out_ch):
        super().__init__()
        self.conv = nn.Conv2d(in_ch, out_ch, 3, padding=1, bias=False)
        self.bn   = nn.BatchNorm2d(out_ch)
        self.relu = nn.ReLU(inplace=True)
    def forward(self, x): return self.relu(self.bn(self.conv(x)))

in_ch, out_ch = 256, 256
std = StandardConvBlock(in_ch, out_ch)
dws = DepthwiseSeparable(in_ch, out_ch)
x = torch.randn(2, in_ch, 28, 28)

ratio = count_params(std) / count_params(dws)
theory = 1/9 + 1/out_ch
print('Standard conv:   {:>8,} params  output {}'.format(count_params(std), std(x).shape))
print('DW Separable:    {:>8,} params  output {}'.format(count_params(dws), dws(x).shape))
print('Reduction: {:.2f}x  (theory: 1/9+1/C = {:.4f})'.format(ratio, theory))
```

## Inception Versions Comparison

Each Inception version addresses a specific limitation of its predecessor: v1 introduced multi-scale parallel branches; v3 factorised operations for efficiency; v4 added residual connections for easier training; Xception replaced inception blocks with depthwise separable convolutions entirely.

| Model | Year | Params | GFLOPs | Top-1 Acc | Key Innovation |
| --- | --- | --- | --- | --- | --- |
| GoogLeNet (v1) | 2014 | 5M | 1.5 | 69.8% | Inception module + auxiliary classifiers |
| Inception-v3 | 2016 | 23M | 5.7 | 78.8% | Factorized 5×5 + asymmetric 1×n, label smoothing |
| Inception-v4 | 2016 | 42M | 12.3 | 80.0% | Deeper inception with uniform stem block |
| Inception-ResNet-v2 | 2016 | 55M | 13.2 | 80.4% | Inception modules + residual shortcuts |
| Xception | 2017 | 22M | 8.4 | 79.0% | All convolutions replaced by depthwise separable |

- GoogLeNet achieved AlexNet-level accuracy with 12x fewer parameters — demonstrating that architectural design matters more than raw scale.
- 1x1 convolutions are now universal: they appear in ResNet bottlenecks, MobileNet, EfficientNet, and transformer projection layers.
- Asymmetric factorisation (1xn + nx1) inspired the use of depthwise separable convolutions in MobileNet and ShuffleNet.
- Auxiliary classifiers were largely abandoned after residual connections provided a cleaner solution to the vanishing gradient problem.

---

