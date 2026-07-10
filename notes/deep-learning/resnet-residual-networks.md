---
title: "ResNet — Residual Connections and Bottleneck Blocks"
slug: "resnet-residual-networks"
description: "ResNet (He et al., 2015) introduces skip connections y=F(x)+x that let very deep networks learn residual functions instead of unreferenced mappings, solving the degradation problem and enabling networks of 50–1000+ layers. Bottleneck blocks and pre-activation variants extend the core idea."
tags: ["deep-learning", "cnns", "architectures"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"The degradation problem — where adding more layers to an already deep network increases training error, not just test error — suggests that deeper plain networks are harder to optimise, not that they overfit. He et al. (2015) hypothesised that learning the identity mapping through multiple nonlinear layers is difficult. Their solution: add an explicit shortcut y = F(x, W) + x so the network only needs to learn the residual F(x) ≈ 0 when the identity is optimal. This simple change enabled networks of 152 layers to outperform all prior architectures while being easier to optimise."},{"type":"heading","level":2,"content":"The Degradation Problem in Deep Networks"},{"type":"text","content":"A 56-layer plain network has higher training error than a 20-layer network on CIFAR-10 — counterintuitively worse despite having strictly more capacity. The 56-layer network could, in principle, learn the same function as the 20-layer network by setting extra layers to identity (F(x) = x). But in practice, random initialisation and SGD cannot find this solution efficiently. The optimisation landscape of deep networks without skip connections has many local minima and vanishing gradients make it hard to update early layers. Batch normalisation helps but does not fully solve the problem at 56+ layers."},{"type":"heading","level":2,"content":"Residual Learning: y = F(x) + x"},{"type":"text","content":"The residual formulation y = F(x, W) + x has two components: F(x, W) is the residual to be learned (a stack of conv-BN-ReLU layers), and x is the identity shortcut. When the optimal mapping is the identity, the network only needs to push F(x) → 0, which is easy — weights near zero is the natural initialisation. Gradient flow analysis reveals why this works: ∂L/∂x = ∂L/∂y · (∂F/∂x + I). The identity term I ensures gradients always flow backward without vanishing, regardless of the learned F. When input and output dimensions differ (due to stride or channel change), a projection shortcut uses a 1×1 conv to match dimensions."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass BasicBlock(nn.Module):\n    \u0027\u0027\u0027ResNet basic block: two 3x3 convs + identity/projection shortcut.\u0027\u0027\u0027\n    expansion = 1\n    def __init__(self, in_ch, out_ch, stride=1):\n        super().__init__()\n        self.conv1 = nn.Conv2d(in_ch, out_ch, 3, stride=stride, padding=1, bias=False)\n        self.bn1   = nn.BatchNorm2d(out_ch)\n        self.conv2 = nn.Conv2d(out_ch, out_ch, 3, padding=1, bias=False)\n        self.bn2   = nn.BatchNorm2d(out_ch)\n        self.relu  = nn.ReLU(inplace=True)\n        self.shortcut = nn.Sequential(\n            nn.Conv2d(in_ch, out_ch, 1, stride=stride, bias=False),\n            nn.BatchNorm2d(out_ch)) if (stride != 1 or in_ch != out_ch) else nn.Identity()\n\n    def forward(self, x):\n        return self.relu(self.bn2(self.conv2(self.relu(self.bn1(self.conv1(x))))) + self.shortcut(x))\n\nclass Bottleneck(nn.Module):\n    \u0027\u0027\u0027ResNet bottleneck: 1x1 reduce -\u003e 3x3 -\u003e 1x1 expand + shortcut.\u0027\u0027\u0027\n    expansion = 4\n    def __init__(self, in_ch, mid_ch, stride=1):\n        super().__init__()\n        out_ch = mid_ch * self.expansion\n        self.conv1 = nn.Conv2d(in_ch, mid_ch, 1, bias=False)\n        self.bn1   = nn.BatchNorm2d(mid_ch)\n        self.conv2 = nn.Conv2d(mid_ch, mid_ch, 3, stride=stride, padding=1, bias=False)\n        self.bn2   = nn.BatchNorm2d(mid_ch)\n        self.conv3 = nn.Conv2d(mid_ch, out_ch, 1, bias=False)\n        self.bn3   = nn.BatchNorm2d(out_ch)\n        self.relu  = nn.ReLU(inplace=True)\n        self.shortcut = nn.Sequential(\n            nn.Conv2d(in_ch, out_ch, 1, stride=stride, bias=False),\n            nn.BatchNorm2d(out_ch)) if (in_ch != out_ch or stride != 1) else nn.Identity()\n\n    def forward(self, x):\n        out = self.relu(self.bn1(self.conv1(x)))\n        out = self.relu(self.bn2(self.conv2(out)))\n        return self.relu(self.bn3(self.conv3(out)) + self.shortcut(x))\n\nfor B, args in [(BasicBlock, (64, 64)), (Bottleneck, (64, 64))]:\n    m = B(*args)\n    p = sum(x.numel() for x in m.parameters())\n    print(\u0027{}: {:,} params\u0027.format(B.__name__, p))"},{"type":"heading","level":2,"content":"Pre-Activation ResNet"},{"type":"text","content":"He et al. (2016) revisited the residual block and found that moving BatchNorm and ReLU before the convolutions (pre-activation) improves gradient flow and regularisation. The pre-activation ordering is BN → ReLU → Conv → BN → ReLU → Conv, and the shortcut carries the raw (pre-activation) input. This ensures the shortcut path is always a clean identity with no activations applied, allowing gradient to flow through the skip path without any transformation. Experimentally, pre-activation ResNet-1001 achieves 4.62% error on CIFAR-10 vs 7.61% for the original ResNet-1202."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass PostActivBlock(nn.Module):\n    \u0027\u0027\u0027Original ResNet: Conv-\u003eBN-\u003eReLU-\u003eConv-\u003eBN, then add shortcut, then ReLU.\u0027\u0027\u0027\n    def __init__(self, ch):\n        super().__init__()\n        self.seq = nn.Sequential(\n            nn.Conv2d(ch, ch, 3, padding=1, bias=False), nn.BatchNorm2d(ch), nn.ReLU(inplace=True),\n            nn.Conv2d(ch, ch, 3, padding=1, bias=False), nn.BatchNorm2d(ch))\n        self.relu = nn.ReLU(inplace=True)\n    def forward(self, x): return self.relu(self.seq(x) + x)\n\nclass PreActivBlock(nn.Module):\n    \u0027\u0027\u0027Pre-activation ResNet (He 2016): BN-\u003eReLU-\u003eConv-\u003eBN-\u003eReLU-\u003eConv, then add shortcut.\u0027\u0027\u0027\n    def __init__(self, ch):\n        super().__init__()\n        self.seq = nn.Sequential(\n            nn.BatchNorm2d(ch), nn.ReLU(inplace=True), nn.Conv2d(ch, ch, 3, padding=1, bias=False),\n            nn.BatchNorm2d(ch), nn.ReLU(inplace=True), nn.Conv2d(ch, ch, 3, padding=1, bias=False))\n    def forward(self, x): return self.seq(x) + x\n\ndef grad_norm(block, x):\n    x = x.clone().detach().requires_grad_(True)\n    block(x).sum().backward()\n    return x.grad.norm().item()\n\ntorch.manual_seed(0)\nx = torch.randn(4, 64, 28, 28)\npost10 = nn.Sequential(*[PostActivBlock(64) for _ in range(10)])\npre10  = nn.Sequential(*[PreActivBlock(64)  for _ in range(10)])\nprint(\u002710-block post-activation grad norm: {:.4f}\u0027.format(grad_norm(post10, x)))\nprint(\u002710-block pre-activation  grad norm: {:.4f}\u0027.format(grad_norm(pre10, x)))\nprint(\u0027Pre-activation maintains gradient magnitude through deep stacks.\u0027)"},{"type":"callout","variant":"info","title":"The Identity Shortcut Is the Key Insight","content":"The skip connection y = F(x) + x is computationally free (just addition) yet fundamentally changes optimisation. Veit et al. (2016) showed that a ResNet with n blocks implicitly ensembles 2^n paths of varying depths — most gradient flows through the shorter paths during early training, gradually engaging deeper paths as the network converges. This ensemble view explains why residual networks are much more robust to removing individual layers than plain networks, where layer removal completely disrupts information flow."},{"type":"heading","level":2,"content":"ResNet-50 from Scratch"},{"type":"text","content":"ResNet-50 uses bottleneck blocks exclusively: each block has a 1×1 conv reducing channels by 4×, a 3×3 conv at the reduced size, and a 1×1 conv expanding back to 4× the mid channels. The architecture: stem (7×7 conv + max pool), then four stages with (3, 4, 6, 3) bottleneck blocks and channel counts (64, 128, 256, 512) — the actual output channels are 4× these values (256, 512, 1024, 2048). Global average pooling replaces the large FC layers of AlexNet/VGG, giving only 2048→1000 at the head. Total: 25M parameters — vs 138M for VGG-16 at better accuracy."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass Bottleneck(nn.Module):\n    expansion = 4\n    def __init__(self, in_ch, mid_ch, stride=1):\n        super().__init__()\n        out_ch = mid_ch * self.expansion\n        self.body = nn.Sequential(\n            nn.Conv2d(in_ch, mid_ch, 1, bias=False), nn.BatchNorm2d(mid_ch), nn.ReLU(inplace=True),\n            nn.Conv2d(mid_ch, mid_ch, 3, stride=stride, padding=1, bias=False),\n            nn.BatchNorm2d(mid_ch), nn.ReLU(inplace=True),\n            nn.Conv2d(mid_ch, out_ch, 1, bias=False), nn.BatchNorm2d(out_ch))\n        self.shortcut = (nn.Sequential(\n            nn.Conv2d(in_ch, out_ch, 1, stride=stride, bias=False), nn.BatchNorm2d(out_ch))\n            if in_ch != out_ch or stride != 1 else nn.Identity())\n        self.relu = nn.ReLU(inplace=True)\n    def forward(self, x): return self.relu(self.body(x) + self.shortcut(x))\n\ndef make_layer(in_ch, mid_ch, n_blocks, stride=1):\n    layers = [Bottleneck(in_ch, mid_ch, stride)]\n    out_ch = mid_ch * 4\n    for _ in range(1, n_blocks):\n        layers.append(Bottleneck(out_ch, mid_ch))\n    return nn.Sequential(*layers)\n\nclass ResNet50(nn.Module):\n    def __init__(self, num_classes=1000):\n        super().__init__()\n        self.stem   = nn.Sequential(\n            nn.Conv2d(3, 64, 7, stride=2, padding=3, bias=False),\n            nn.BatchNorm2d(64), nn.ReLU(inplace=True), nn.MaxPool2d(3, stride=2, padding=1))\n        self.layer1 = make_layer(64,   64,  3)\n        self.layer2 = make_layer(256,  128, 4, stride=2)\n        self.layer3 = make_layer(512,  256, 6, stride=2)\n        self.layer4 = make_layer(1024, 512, 3, stride=2)\n        self.head   = nn.Sequential(nn.AdaptiveAvgPool2d(1), nn.Flatten(), nn.Linear(2048, num_classes))\n    def forward(self, x):\n        return self.head(self.layer4(self.layer3(self.layer2(self.layer1(self.stem(x))))))\n\nmodel = ResNet50()\nx = torch.randn(2, 3, 224, 224)\nparams = sum(p.numel() for p in model.parameters()) / 1e6\nprint(\u0027ResNet-50 output: {}  params: {:.1f}M\u0027.format(model(x).shape, params))"},{"type":"heading","level":2,"content":"Width vs Depth: WideResNet"},{"type":"text","content":"Zagoruyko \u0026 Komodakis (2016) showed that widening residual networks — increasing channels by a widening factor k — can outperform depth increases while being more computationally efficient. WRN-28-10 (28 layers, k=10) achieves 3.89% error on CIFAR-10, better than ResNet-1001. Wide networks benefit more from parallelism on modern GPUs than deep-but-thin networks whose sequential bottlenecks are hard to parallelise. The trade-off: WideResNet has more parameters for a given depth but fewer training steps to convergence. Dropout in wide blocks acts as effective regularisation when channels are large."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass WideBlock(nn.Module):\n    \u0027\u0027\u0027Wide ResNet block: pre-activation + dropout for regularisation.\u0027\u0027\u0027\n    def __init__(self, in_ch, out_ch, stride=1, dropout=0.3):\n        super().__init__()\n        self.bn1  = nn.BatchNorm2d(in_ch)\n        self.conv1 = nn.Conv2d(in_ch, out_ch, 3, stride=stride, padding=1, bias=False)\n        self.drop  = nn.Dropout(dropout)\n        self.bn2   = nn.BatchNorm2d(out_ch)\n        self.conv2 = nn.Conv2d(out_ch, out_ch, 3, padding=1, bias=False)\n        self.relu  = nn.ReLU(inplace=True)\n        self.shortcut = (nn.Conv2d(in_ch, out_ch, 1, stride=stride, bias=False)\n                         if in_ch != out_ch or stride != 1 else nn.Identity())\n\n    def forward(self, x):\n        out = self.conv1(self.relu(self.bn1(x)))\n        out = self.conv2(self.drop(self.relu(self.bn2(out))))\n        return out + self.shortcut(x)\n\ndef wrn(depth=16, k=10, num_classes=10):\n    return nn.Sequential(\n        nn.Conv2d(3, 16, 3, padding=1, bias=False),\n        WideBlock(16, 16*k), WideBlock(16*k, 32*k, stride=2), WideBlock(32*k, 64*k, stride=2),\n        nn.BatchNorm2d(64*k), nn.ReLU(inplace=True),\n        nn.AdaptiveAvgPool2d(1), nn.Flatten(), nn.Linear(64*k, num_classes))\n\nprint(\u0027{:\u003c12} {:\u003e10} {:\u003e14}\u0027.format(\u0027Model\u0027, \u0027Params\u0027, \u0027GFLOPs (est)\u0027))\nfor k in [1, 4, 8, 10]:\n    m = wrn(k=k)\n    p = sum(x.numel() for x in m.parameters()) / 1e6\n    print(\u0027WRN-16-{:\u003c4} {:\u003e9.2f}M\u0027.format(k, p))"},{"type":"heading","level":2,"content":"Why Skip Connections Work"},{"type":"text","content":"Multiple theoretical perspectives explain the effectiveness of residual connections. The ensemble view (Veit et al.) shows that a ResNet with n blocks implicitly represents a 2^n-path ensemble, where gradients primarily flow through shorter paths early in training. The unrolled iterative estimation view interprets each residual block as one refinement step in an iterative estimation of the target representation. Information-theoretic analysis shows that skip connections provide an information superhighway that prevents bottlenecks in early layers. Empirically, residual networks with removed intermediate layers degrade gracefully, while plain networks fail catastrophically when layers are removed."},{"type":"list","ordered":false,"items":["Gradient flow: skip connection contributes +I to the Jacobian, ensuring non-vanishing gradients at all depths.","Ensemble effect: 2^n implicit paths of varying depths — shorter paths dominate early training, longer paths refine later.","Identity initialisation: at initialisation F(x) ≈ 0 (small weights), so the block is approximately identity — a sensible starting point.","Shattered gradients (Balduzzi et al.): plain networks have near-zero gradient correlation between adjacent layers; residuals preserve it.","Loss landscape (Li et al.): skip connections create smoother loss landscapes with fewer local minima and sharper global minima."]},{"type":"heading","level":2,"content":"ResNet Variants Comparison"},{"type":"table","headers":["Model","Blocks","Params","GFLOPs","Top-1 Acc","Key Variant"],"rows":[["ResNet-18","8 basic","11M","1.8","69.8%","Baseline, used as lightweight backbone"],["ResNet-34","16 basic","21M","3.7","73.3%","Larger basic-block network"],["ResNet-50","16 bottleneck","25M","4.1","76.1%","Standard bottleneck design"],["ResNet-101","33 bottleneck","44M","7.9","77.4%","Deeper backbone for segmentation"],["ResNet-152","50 bottleneck","60M","11.6","78.3%","ILSVRC 2015 winner"],["WideResNet-28-10","12 wide basic","36M","5.2","95.8% CIFAR","Wider, shallower, dropout"],["ResNeXt-50 (32×4d)","16 grouped bottleneck","25M","4.3","77.8%","Grouped convolutions, multi-branch"]]},{"type":"divider"}]"
---
# ResNet — Residual Connections and Bottleneck Blocks

The degradation problem — where adding more layers to an already deep network increases training error, not just test error — suggests that deeper plain networks are harder to optimise, not that they overfit. He et al. (2015) hypothesised that learning the identity mapping through multiple nonlinear layers is difficult. Their solution: add an explicit shortcut y = F(x, W) + x so the network only needs to learn the residual F(x) ≈ 0 when the identity is optimal. This simple change enabled networks of 152 layers to outperform all prior architectures while being easier to optimise.

## The Degradation Problem in Deep Networks

A 56-layer plain network has higher training error than a 20-layer network on CIFAR-10 — counterintuitively worse despite having strictly more capacity. The 56-layer network could, in principle, learn the same function as the 20-layer network by setting extra layers to identity (F(x) = x). But in practice, random initialisation and SGD cannot find this solution efficiently. The optimisation landscape of deep networks without skip connections has many local minima and vanishing gradients make it hard to update early layers. Batch normalisation helps but does not fully solve the problem at 56+ layers.

## Residual Learning: y = F(x) + x

The residual formulation y = F(x, W) + x has two components: F(x, W) is the residual to be learned (a stack of conv-BN-ReLU layers), and x is the identity shortcut. When the optimal mapping is the identity, the network only needs to push F(x) → 0, which is easy — weights near zero is the natural initialisation. Gradient flow analysis reveals why this works: ∂L/∂x = ∂L/∂y · (∂F/∂x + I). The identity term I ensures gradients always flow backward without vanishing, regardless of the learned F. When input and output dimensions differ (due to stride or channel change), a projection shortcut uses a 1×1 conv to match dimensions.

```python
import torch
import torch.nn as nn

class BasicBlock(nn.Module):
    '''ResNet basic block: two 3x3 convs + identity/projection shortcut.'''
    expansion = 1
    def __init__(self, in_ch, out_ch, stride=1):
        super().__init__()
        self.conv1 = nn.Conv2d(in_ch, out_ch, 3, stride=stride, padding=1, bias=False)
        self.bn1   = nn.BatchNorm2d(out_ch)
        self.conv2 = nn.Conv2d(out_ch, out_ch, 3, padding=1, bias=False)
        self.bn2   = nn.BatchNorm2d(out_ch)
        self.relu  = nn.ReLU(inplace=True)
        self.shortcut = nn.Sequential(
            nn.Conv2d(in_ch, out_ch, 1, stride=stride, bias=False),
            nn.BatchNorm2d(out_ch)) if (stride != 1 or in_ch != out_ch) else nn.Identity()

    def forward(self, x):
        return self.relu(self.bn2(self.conv2(self.relu(self.bn1(self.conv1(x))))) + self.shortcut(x))

class Bottleneck(nn.Module):
    '''ResNet bottleneck: 1x1 reduce -> 3x3 -> 1x1 expand + shortcut.'''
    expansion = 4
    def __init__(self, in_ch, mid_ch, stride=1):
        super().__init__()
        out_ch = mid_ch * self.expansion
        self.conv1 = nn.Conv2d(in_ch, mid_ch, 1, bias=False)
        self.bn1   = nn.BatchNorm2d(mid_ch)
        self.conv2 = nn.Conv2d(mid_ch, mid_ch, 3, stride=stride, padding=1, bias=False)
        self.bn2   = nn.BatchNorm2d(mid_ch)
        self.conv3 = nn.Conv2d(mid_ch, out_ch, 1, bias=False)
        self.bn3   = nn.BatchNorm2d(out_ch)
        self.relu  = nn.ReLU(inplace=True)
        self.shortcut = nn.Sequential(
            nn.Conv2d(in_ch, out_ch, 1, stride=stride, bias=False),
            nn.BatchNorm2d(out_ch)) if (in_ch != out_ch or stride != 1) else nn.Identity()

    def forward(self, x):
        out = self.relu(self.bn1(self.conv1(x)))
        out = self.relu(self.bn2(self.conv2(out)))
        return self.relu(self.bn3(self.conv3(out)) + self.shortcut(x))

for B, args in [(BasicBlock, (64, 64)), (Bottleneck, (64, 64))]:
    m = B(*args)
    p = sum(x.numel() for x in m.parameters())
    print('{}: {:,} params'.format(B.__name__, p))
```

## Pre-Activation ResNet

He et al. (2016) revisited the residual block and found that moving BatchNorm and ReLU before the convolutions (pre-activation) improves gradient flow and regularisation. The pre-activation ordering is BN → ReLU → Conv → BN → ReLU → Conv, and the shortcut carries the raw (pre-activation) input. This ensures the shortcut path is always a clean identity with no activations applied, allowing gradient to flow through the skip path without any transformation. Experimentally, pre-activation ResNet-1001 achieves 4.62% error on CIFAR-10 vs 7.61% for the original ResNet-1202.

```python
import torch
import torch.nn as nn

class PostActivBlock(nn.Module):
    '''Original ResNet: Conv->BN->ReLU->Conv->BN, then add shortcut, then ReLU.'''
    def __init__(self, ch):
        super().__init__()
        self.seq = nn.Sequential(
            nn.Conv2d(ch, ch, 3, padding=1, bias=False), nn.BatchNorm2d(ch), nn.ReLU(inplace=True),
            nn.Conv2d(ch, ch, 3, padding=1, bias=False), nn.BatchNorm2d(ch))
        self.relu = nn.ReLU(inplace=True)
    def forward(self, x): return self.relu(self.seq(x) + x)

class PreActivBlock(nn.Module):
    '''Pre-activation ResNet (He 2016): BN->ReLU->Conv->BN->ReLU->Conv, then add shortcut.'''
    def __init__(self, ch):
        super().__init__()
        self.seq = nn.Sequential(
            nn.BatchNorm2d(ch), nn.ReLU(inplace=True), nn.Conv2d(ch, ch, 3, padding=1, bias=False),
            nn.BatchNorm2d(ch), nn.ReLU(inplace=True), nn.Conv2d(ch, ch, 3, padding=1, bias=False))
    def forward(self, x): return self.seq(x) + x

def grad_norm(block, x):
    x = x.clone().detach().requires_grad_(True)
    block(x).sum().backward()
    return x.grad.norm().item()

torch.manual_seed(0)
x = torch.randn(4, 64, 28, 28)
post10 = nn.Sequential(*[PostActivBlock(64) for _ in range(10)])
pre10  = nn.Sequential(*[PreActivBlock(64)  for _ in range(10)])
print('10-block post-activation grad norm: {:.4f}'.format(grad_norm(post10, x)))
print('10-block pre-activation  grad norm: {:.4f}'.format(grad_norm(pre10, x)))
print('Pre-activation maintains gradient magnitude through deep stacks.')
```

> **The Identity Shortcut Is the Key Insight**: The skip connection y = F(x) + x is computationally free (just addition) yet fundamentally changes optimisation. Veit et al. (2016) showed that a ResNet with n blocks implicitly ensembles 2^n paths of varying depths — most gradient flows through the shorter paths during early training, gradually engaging deeper paths as the network converges. This ensemble view explains why residual networks are much more robust to removing individual layers than plain networks, where layer removal completely disrupts information flow.

## ResNet-50 from Scratch

ResNet-50 uses bottleneck blocks exclusively: each block has a 1×1 conv reducing channels by 4×, a 3×3 conv at the reduced size, and a 1×1 conv expanding back to 4× the mid channels. The architecture: stem (7×7 conv + max pool), then four stages with (3, 4, 6, 3) bottleneck blocks and channel counts (64, 128, 256, 512) — the actual output channels are 4× these values (256, 512, 1024, 2048). Global average pooling replaces the large FC layers of AlexNet/VGG, giving only 2048→1000 at the head. Total: 25M parameters — vs 138M for VGG-16 at better accuracy.

```python
import torch
import torch.nn as nn

class Bottleneck(nn.Module):
    expansion = 4
    def __init__(self, in_ch, mid_ch, stride=1):
        super().__init__()
        out_ch = mid_ch * self.expansion
        self.body = nn.Sequential(
            nn.Conv2d(in_ch, mid_ch, 1, bias=False), nn.BatchNorm2d(mid_ch), nn.ReLU(inplace=True),
            nn.Conv2d(mid_ch, mid_ch, 3, stride=stride, padding=1, bias=False),
            nn.BatchNorm2d(mid_ch), nn.ReLU(inplace=True),
            nn.Conv2d(mid_ch, out_ch, 1, bias=False), nn.BatchNorm2d(out_ch))
        self.shortcut = (nn.Sequential(
            nn.Conv2d(in_ch, out_ch, 1, stride=stride, bias=False), nn.BatchNorm2d(out_ch))
            if in_ch != out_ch or stride != 1 else nn.Identity())
        self.relu = nn.ReLU(inplace=True)
    def forward(self, x): return self.relu(self.body(x) + self.shortcut(x))

def make_layer(in_ch, mid_ch, n_blocks, stride=1):
    layers = [Bottleneck(in_ch, mid_ch, stride)]
    out_ch = mid_ch * 4
    for _ in range(1, n_blocks):
        layers.append(Bottleneck(out_ch, mid_ch))
    return nn.Sequential(*layers)

class ResNet50(nn.Module):
    def __init__(self, num_classes=1000):
        super().__init__()
        self.stem   = nn.Sequential(
            nn.Conv2d(3, 64, 7, stride=2, padding=3, bias=False),
            nn.BatchNorm2d(64), nn.ReLU(inplace=True), nn.MaxPool2d(3, stride=2, padding=1))
        self.layer1 = make_layer(64,   64,  3)
        self.layer2 = make_layer(256,  128, 4, stride=2)
        self.layer3 = make_layer(512,  256, 6, stride=2)
        self.layer4 = make_layer(1024, 512, 3, stride=2)
        self.head   = nn.Sequential(nn.AdaptiveAvgPool2d(1), nn.Flatten(), nn.Linear(2048, num_classes))
    def forward(self, x):
        return self.head(self.layer4(self.layer3(self.layer2(self.layer1(self.stem(x))))))

model = ResNet50()
x = torch.randn(2, 3, 224, 224)
params = sum(p.numel() for p in model.parameters()) / 1e6
print('ResNet-50 output: {}  params: {:.1f}M'.format(model(x).shape, params))
```

## Width vs Depth: WideResNet

Zagoruyko & Komodakis (2016) showed that widening residual networks — increasing channels by a widening factor k — can outperform depth increases while being more computationally efficient. WRN-28-10 (28 layers, k=10) achieves 3.89% error on CIFAR-10, better than ResNet-1001. Wide networks benefit more from parallelism on modern GPUs than deep-but-thin networks whose sequential bottlenecks are hard to parallelise. The trade-off: WideResNet has more parameters for a given depth but fewer training steps to convergence. Dropout in wide blocks acts as effective regularisation when channels are large.

```python
import torch
import torch.nn as nn

class WideBlock(nn.Module):
    '''Wide ResNet block: pre-activation + dropout for regularisation.'''
    def __init__(self, in_ch, out_ch, stride=1, dropout=0.3):
        super().__init__()
        self.bn1  = nn.BatchNorm2d(in_ch)
        self.conv1 = nn.Conv2d(in_ch, out_ch, 3, stride=stride, padding=1, bias=False)
        self.drop  = nn.Dropout(dropout)
        self.bn2   = nn.BatchNorm2d(out_ch)
        self.conv2 = nn.Conv2d(out_ch, out_ch, 3, padding=1, bias=False)
        self.relu  = nn.ReLU(inplace=True)
        self.shortcut = (nn.Conv2d(in_ch, out_ch, 1, stride=stride, bias=False)
                         if in_ch != out_ch or stride != 1 else nn.Identity())

    def forward(self, x):
        out = self.conv1(self.relu(self.bn1(x)))
        out = self.conv2(self.drop(self.relu(self.bn2(out))))
        return out + self.shortcut(x)

def wrn(depth=16, k=10, num_classes=10):
    return nn.Sequential(
        nn.Conv2d(3, 16, 3, padding=1, bias=False),
        WideBlock(16, 16*k), WideBlock(16*k, 32*k, stride=2), WideBlock(32*k, 64*k, stride=2),
        nn.BatchNorm2d(64*k), nn.ReLU(inplace=True),
        nn.AdaptiveAvgPool2d(1), nn.Flatten(), nn.Linear(64*k, num_classes))

print('{:<12} {:>10} {:>14}'.format('Model', 'Params', 'GFLOPs (est)'))
for k in [1, 4, 8, 10]:
    m = wrn(k=k)
    p = sum(x.numel() for x in m.parameters()) / 1e6
    print('WRN-16-{:<4} {:>9.2f}M'.format(k, p))
```

## Why Skip Connections Work

Multiple theoretical perspectives explain the effectiveness of residual connections. The ensemble view (Veit et al.) shows that a ResNet with n blocks implicitly represents a 2^n-path ensemble, where gradients primarily flow through shorter paths early in training. The unrolled iterative estimation view interprets each residual block as one refinement step in an iterative estimation of the target representation. Information-theoretic analysis shows that skip connections provide an information superhighway that prevents bottlenecks in early layers. Empirically, residual networks with removed intermediate layers degrade gracefully, while plain networks fail catastrophically when layers are removed.

- Gradient flow: skip connection contributes +I to the Jacobian, ensuring non-vanishing gradients at all depths.
- Ensemble effect: 2^n implicit paths of varying depths — shorter paths dominate early training, longer paths refine later.
- Identity initialisation: at initialisation F(x) ≈ 0 (small weights), so the block is approximately identity — a sensible starting point.
- Shattered gradients (Balduzzi et al.): plain networks have near-zero gradient correlation between adjacent layers; residuals preserve it.
- Loss landscape (Li et al.): skip connections create smoother loss landscapes with fewer local minima and sharper global minima.

## ResNet Variants Comparison

| Model | Blocks | Params | GFLOPs | Top-1 Acc | Key Variant |
| --- | --- | --- | --- | --- | --- |
| ResNet-18 | 8 basic | 11M | 1.8 | 69.8% | Baseline, used as lightweight backbone |
| ResNet-34 | 16 basic | 21M | 3.7 | 73.3% | Larger basic-block network |
| ResNet-50 | 16 bottleneck | 25M | 4.1 | 76.1% | Standard bottleneck design |
| ResNet-101 | 33 bottleneck | 44M | 7.9 | 77.4% | Deeper backbone for segmentation |
| ResNet-152 | 50 bottleneck | 60M | 11.6 | 78.3% | ILSVRC 2015 winner |
| WideResNet-28-10 | 12 wide basic | 36M | 5.2 | 95.8% CIFAR | Wider, shallower, dropout |
| ResNeXt-50 (32×4d) | 16 grouped bottleneck | 25M | 4.3 | 77.8% | Grouped convolutions, multi-branch |

---

