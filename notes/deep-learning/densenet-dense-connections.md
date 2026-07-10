---
title: "DenseNet — Dense Connections and Feature Reuse"
slug: "densenet-dense-connections"
description: "DenseNet (Huang et al., 2017) connects every layer to every subsequent layer within a dense block, maximising gradient flow and feature reuse. Growth rate k controls new feature maps per layer; bottleneck + compression (DenseNet-BC) reduces parameters; gradient checkpointing addresses O(n²) memory."
tags: ["deep-learning", "cnns", "architectures"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"DenseNet (Huang et al., 2017) takes the connectivity pattern of ResNet to its logical extreme: instead of connecting each layer to only the next layer (plain net) or adding a skip connection from the layer two levels back (ResNet), every layer receives feature maps from all preceding layers within a dense block. Layer l receives concatenated feature maps [x₀, x₁, ..., x_{l-1}] as input and produces k new feature maps (the growth rate). This dense connectivity maximises gradient flow, promotes feature reuse, and achieves state-of-the-art accuracy with significantly fewer parameters than ResNet — all at the cost of higher memory usage during training."},{"type":"heading","level":2,"content":"Dense Connectivity: Every Layer to Every Layer"},{"type":"text","content":"In a dense block with L layers and growth rate k, layer l has k₀ + k×(l−1) input channels (k₀ = initial channels entering the block). The total number of connections within a block is L(L+1)/2 — quadratic in depth. For L=6, k=32, k₀=64: layer 1 has 64 inputs, layer 2 has 96, ..., layer 6 has 224 inputs. Unlike ResNet\u0027s y = F(x) + x (addition), DenseNet uses y = H([x₀, x₁, ..., x_{l-1}]) (concatenation). Concatenation preserves all prior features explicitly — early edge detectors remain directly available to deep layers — while ResNet\u0027s addition mixes them irreversibly."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass DenseLayer(nn.Module):\n    \u0027\u0027\u0027Single DenseNet layer: BN-ReLU-Conv1x1(bottleneck)-BN-ReLU-Conv3x3.\u0027\u0027\u0027\n    def __init__(self, in_ch, growth_rate=32, bottleneck=True):\n        super().__init__()\n        mid_ch = 4 * growth_rate if bottleneck else in_ch\n        layers = []\n        if bottleneck:\n            layers += [nn.BatchNorm2d(in_ch), nn.ReLU(inplace=True),\n                       nn.Conv2d(in_ch, mid_ch, 1, bias=False)]\n        layers += [nn.BatchNorm2d(mid_ch), nn.ReLU(inplace=True),\n                   nn.Conv2d(mid_ch, growth_rate, 3, padding=1, bias=False)]\n        self.layer = nn.Sequential(*layers)\n\n    def forward(self, x):\n        return torch.cat([x, self.layer(x)], dim=1)  # concatenate, not add\n\nclass DenseBlock(nn.Module):\n    \u0027\u0027\u0027Dense block: each layer receives all preceding feature maps.\u0027\u0027\u0027\n    def __init__(self, in_ch, n_layers, growth_rate=32):\n        super().__init__()\n        layers, ch = [], in_ch\n        for _ in range(n_layers):\n            layers.append(DenseLayer(ch, growth_rate))\n            ch += growth_rate\n        self.layers = nn.Sequential(*layers)\n        self.out_channels = ch\n\n    def forward(self, x): return self.layers(x)\n\nblock = DenseBlock(in_ch=64, n_layers=6, growth_rate=32)\nx = torch.randn(2, 64, 56, 56)\nout = block(x)\nparams = sum(p.numel() for p in block.parameters()) / 1e3\nprint(\u0027DenseBlock input: {} -\u003e output: {}\u0027.format(x.shape, out.shape))\nprint(\u0027Output channels: 64 + 6*32 = {} (concat, not add)\u0027.format(64 + 6*32))\nprint(\u0027Parameters: {:.1f}K\u0027.format(params))"},{"type":"heading","level":2,"content":"Growth Rate and Feature Reuse"},{"type":"text","content":"The growth rate k is a key hyperparameter: it controls how many new feature maps each layer contributes to the collective knowledge. A small k (e.g., k=12 or k=32) is sufficient because each layer adds to all accumulated features rather than overwriting them. DenseNet-121 uses k=32 and achieves comparable accuracy to ResNet-50 with 8M vs 25M parameters. Huang et al. analysed filter activations and found that all layers within a dense block actively use features from all preceding layers — including the very first layer\u0027s edge detectors — confirming genuine feature reuse rather than redundant recomputation."},{"type":"heading","level":2,"content":"Bottleneck and Compression: DenseNet-BC"},{"type":"text","content":"DenseNet-B (Bottleneck): each layer uses a 1×1 conv before the 3×3 to reduce the growing input channels to 4k, preventing the parameter count from growing quadratically with depth. DenseNet-C (Compression): between dense blocks, a transition layer reduces channels by a factor θ (typically 0.5) before downsampling. DenseNet-BC combines both: DenseNet-BC-L-k denotes a network with L layers per block, growth rate k, bottlenecks, and θ=0.5 compression. DenseNet-BC-190-40 achieves 3.46% error on CIFAR-10 — state-of-the-art at the time — with 25M parameters."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass TransitionLayer(nn.Module):\n    \u0027\u0027\u0027DenseNet transition: 1x1 conv compression + 2x2 avg pool downsampling.\n    theta \u003c 1 compresses channels to reduce parameter growth between blocks.\n    \u0027\u0027\u0027\n    def __init__(self, in_ch, theta=0.5):\n        super().__init__()\n        out_ch = int(in_ch * theta)\n        self.transition = nn.Sequential(\n            nn.BatchNorm2d(in_ch), nn.ReLU(inplace=True),\n            nn.Conv2d(in_ch, out_ch, 1, bias=False),\n            nn.AvgPool2d(2, stride=2))\n        self.out_channels = out_ch\n\n    def forward(self, x): return self.transition(x)\n\n# Simulate DenseNet-121 after first dense block: 64 + 6*32 = 256 channels\nin_channels = 256\ntransition = TransitionLayer(in_channels, theta=0.5)\nx = torch.randn(2, in_channels, 56, 56)\nout = transition(x)\nprint(\u0027Transition input:  {}\u0027.format(x.shape))\nprint(\u0027Transition output: {}\u0027.format(out.shape))\nprint(\u0027Channels: {} -\u003e {}  (theta=0.5)\u0027.format(in_channels, transition.out_channels))\nprint(\u0027Spatial:  56x56 -\u003e 28x28  (2x2 avg pool)\u0027)\nparams = sum(p.numel() for p in transition.parameters()) / 1e3\nprint(\u0027Parameters: {:.1f}K\u0027.format(params))"},{"type":"callout","variant":"warning","title":"Memory Cost is O(n²) Without Optimisation","content":"A naive DenseNet implementation allocates separate tensors for all L(L+1)/2 intermediate feature maps and keeps them in GPU memory for the backward pass. For DenseNet-264 with L=64 layers per block, this is 64×65/2 = 2,080 tensor allocations per block. The PyTorch DenseNet implementation uses a shared memory allocation trick: all input concatenations reference the same pre-allocated memory buffer, reducing peak memory from O(n²) to near O(n). Gradient checkpointing (torch.utils.checkpoint) provides an alternative: recompute activations during the backward pass rather than storing them."},{"type":"heading","level":2,"content":"Memory-Efficient Implementation"},{"type":"text","content":"Gradient checkpointing trades compute for memory: instead of storing intermediate activations for the backward pass, they are recomputed on the fly during backpropagation. For DenseNet, where each layer\u0027s input is the concatenation of all prior outputs, checkpointing the concatenation operation is especially effective. torch.utils.checkpoint.checkpoint wraps a function and discards its intermediate activations, recomputing them during the backward pass. This typically doubles training time (since activations are computed twice) but reduces memory by up to 10× for deep DenseNets."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom torch.utils.checkpoint import checkpoint\n\nclass CheckpointedDenseLayer(nn.Module):\n    \u0027\u0027\u0027DenseNet layer using gradient checkpointing to trade memory for compute.\u0027\u0027\u0027\n    def __init__(self, in_ch, growth_rate=32):\n        super().__init__()\n        mid_ch = 4 * growth_rate\n        self.bn1   = nn.BatchNorm2d(in_ch)\n        self.conv1 = nn.Conv2d(in_ch, mid_ch, 1, bias=False)\n        self.bn2   = nn.BatchNorm2d(mid_ch)\n        self.conv2 = nn.Conv2d(mid_ch, growth_rate, 3, padding=1, bias=False)\n        self.relu  = nn.ReLU(inplace=True)\n\n    def _forward(self, x):\n        out = self.conv1(self.relu(self.bn1(x)))\n        return self.conv2(self.relu(self.bn2(out)))\n\n    def forward(self, x):\n        new_feat = checkpoint(self._forward, x, use_reentrant=False)\n        return torch.cat([x, new_feat], dim=1)\n\nclass MemEfficientDenseBlock(nn.Module):\n    def __init__(self, in_ch, n_layers, growth_rate=32):\n        super().__init__()\n        self.layers = nn.ModuleList()\n        ch = in_ch\n        for _ in range(n_layers):\n            self.layers.append(CheckpointedDenseLayer(ch, growth_rate))\n            ch += growth_rate\n        self.out_channels = ch\n\n    def forward(self, x):\n        for layer in self.layers:\n            x = layer(x)\n        return x\n\nblock = MemEfficientDenseBlock(in_ch=64, n_layers=12, growth_rate=32)\nx = torch.randn(2, 64, 28, 28)\nout = block(x)\nprint(\u0027Checkpointed DenseBlock: {} -\u003e {}\u0027.format(x.shape, out.shape))\nprint(\u0027Output channels: 64 + 12*32 = {}\u0027.format(64 + 12*32))"},{"type":"heading","level":2,"content":"Feature Reuse Visualisation"},{"type":"text","content":"Huang et al. visualised which source features each layer actually uses by analysing the absolute weight magnitudes in the 1×1 bottleneck convolutions. If layer l allocates high weight to features from layer j, it genuinely reuses them. The analysis revealed that all source layers contribute non-trivially — including the very first layer\u0027s low-level features at deep layers. This is in contrast to ResNets where early features are effectively forgotten (overwritten by addition) as the network deepens. DenseNet\u0027s feature reuse pattern is like a committee: every member (layer) always has access to all prior evidence."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport numpy as np\n\nclass AnalysisDenseLayer(nn.Module):\n    def __init__(self, in_ch, growth_rate=32):\n        super().__init__()\n        mid_ch = 4 * growth_rate\n        self.bn1   = nn.BatchNorm2d(in_ch)\n        self.conv1 = nn.Conv2d(in_ch, mid_ch, 1, bias=False)  # weights to analyse\n        self.bn2   = nn.BatchNorm2d(mid_ch)\n        self.conv2 = nn.Conv2d(mid_ch, growth_rate, 3, padding=1, bias=False)\n        self.relu  = nn.ReLU(inplace=True)\n    def forward(self, x):\n        out = self.conv1(self.relu(self.bn1(x)))\n        return torch.cat([x, self.conv2(self.relu(self.bn2(out)))], dim=1)\n\nn_layers, k, in_ch = 6, 32, 64\nlayers = [AnalysisDenseLayer(in_ch + i*k, k) for i in range(n_layers)]\n# Compute mean absolute weight per source feature block in conv1\nprint(\u0027Feature reuse matrix (rows=layer, cols=source contribution):\u0027)\nprint(\u0027{:\u003c10} \u0027.format(\u0027Layer\u0027) + \u0027  \u0027.join(\u0027src{}\u0027.format(i) for i in range(n_layers+1)))\nfor l_idx, layer in enumerate(layers):\n    w = layer.conv1.weight.data.abs()   # shape: (4k, in_ch + l_idx*k, 1, 1)\n    ch_ptr, contribs = 0, []\n    for src in range(l_idx + 1):\n        src_ch = in_ch if src == 0 else k\n        contribs.append(w[:, ch_ptr:ch_ptr+src_ch].mean().item())\n        ch_ptr += src_ch\n    row = \u0027  \u0027.join(\u0027{:.3f}\u0027.format(c) for c in contribs)\n    print(\u0027Layer {:\u003e2}:  {}\u0027.format(l_idx+1, row))"},{"type":"heading","level":2,"content":"Why Dense Connections Work"},{"type":"text","content":"Dense connectivity provides several orthogonal benefits: (1) implicit deep supervision — every layer receives gradient from the loss through multiple paths of varying lengths, similar to auxiliary classifiers but without extra parameters; (2) feature reuse — earlier layers\u0027 filters remain accessible throughout, so the network does not need to relearn low-level features; (3) regularisation — the shared feature map pool acts as a form of dropout in feature space, forcing layers to be complementary rather than redundant; (4) parameter efficiency — k new features per layer suffices because each layer builds on all accumulated context rather than starting from scratch. DenseNet achieves ResNet-level accuracy with 3× fewer parameters on ImageNet."},{"type":"list","ordered":false,"items":["Implicit deep supervision: gradients reach early layers through O(L) direct paths rather than the single chained path in plain networks.","Feature reuse: edge detectors learned in layer 1 are directly available to layer L without being diluted by repeated addition.","Complementary filters: each layer adds exactly k new feature maps, incentivising it to learn features distinct from all prior layers.","Collective knowledge: the concatenated feature map is a shared, ever-growing representation — analogous to an ensemble\u0027s prediction pool.","Connection to FPN: dense blocks are a form of all-to-all feature pyramid, whereas FPN builds a top-down pyramid of fixed resolution levels."]},{"type":"heading","level":2,"content":"DenseNet vs ResNet vs PlainNet"},{"type":"table","headers":["Property","PlainNet","ResNet","DenseNet"],"rows":[["Connection type","Sequential, layer to next","Skip: add x to F(x)","Dense: concat all prior to each"],["Feature reuse","None — overwritten each layer","Partial — addition mixes features","Full — all prior features always available"],["Gradient paths","1 path per layer","2 paths per block (main + skip)","O(L) paths per layer"],["Parameters","High (redundant relearning)","Medium","Low (k per layer suffices)"],["Memory (training)","O(L)","O(L)","O(L²) naive; O(L) with shared alloc"],["Depth scalability","Poor (vanishing gradients)","Excellent (1000+ layers)","Good (hundreds of layers practical)"]]},{"type":"text","content":"DenseNet is most effective when parameter efficiency matters more than inference speed: its dense connections create many small tensors that are cache-unfriendly on GPU, making it slower at inference than ResNet at equal accuracy. For deployment-constrained scenarios, MobileNet (depthwise separable + inverted residuals) and EfficientNet (compound scaling) typically dominate. DenseNet remains the architecture of choice for medical image segmentation (as the encoder in U-Net variants) and tasks where intermediate feature reuse is critical."},{"type":"divider"}]"
---
# DenseNet — Dense Connections and Feature Reuse

DenseNet (Huang et al., 2017) takes the connectivity pattern of ResNet to its logical extreme: instead of connecting each layer to only the next layer (plain net) or adding a skip connection from the layer two levels back (ResNet), every layer receives feature maps from all preceding layers within a dense block. Layer l receives concatenated feature maps [x₀, x₁, ..., x_{l-1}] as input and produces k new feature maps (the growth rate). This dense connectivity maximises gradient flow, promotes feature reuse, and achieves state-of-the-art accuracy with significantly fewer parameters than ResNet — all at the cost of higher memory usage during training.

## Dense Connectivity: Every Layer to Every Layer

In a dense block with L layers and growth rate k, layer l has k₀ + k×(l−1) input channels (k₀ = initial channels entering the block). The total number of connections within a block is L(L+1)/2 — quadratic in depth. For L=6, k=32, k₀=64: layer 1 has 64 inputs, layer 2 has 96, ..., layer 6 has 224 inputs. Unlike ResNet's y = F(x) + x (addition), DenseNet uses y = H([x₀, x₁, ..., x_{l-1}]) (concatenation). Concatenation preserves all prior features explicitly — early edge detectors remain directly available to deep layers — while ResNet's addition mixes them irreversibly.

```python
import torch
import torch.nn as nn

class DenseLayer(nn.Module):
    '''Single DenseNet layer: BN-ReLU-Conv1x1(bottleneck)-BN-ReLU-Conv3x3.'''
    def __init__(self, in_ch, growth_rate=32, bottleneck=True):
        super().__init__()
        mid_ch = 4 * growth_rate if bottleneck else in_ch
        layers = []
        if bottleneck:
            layers += [nn.BatchNorm2d(in_ch), nn.ReLU(inplace=True),
                       nn.Conv2d(in_ch, mid_ch, 1, bias=False)]
        layers += [nn.BatchNorm2d(mid_ch), nn.ReLU(inplace=True),
                   nn.Conv2d(mid_ch, growth_rate, 3, padding=1, bias=False)]
        self.layer = nn.Sequential(*layers)

    def forward(self, x):
        return torch.cat([x, self.layer(x)], dim=1)  # concatenate, not add

class DenseBlock(nn.Module):
    '''Dense block: each layer receives all preceding feature maps.'''
    def __init__(self, in_ch, n_layers, growth_rate=32):
        super().__init__()
        layers, ch = [], in_ch
        for _ in range(n_layers):
            layers.append(DenseLayer(ch, growth_rate))
            ch += growth_rate
        self.layers = nn.Sequential(*layers)
        self.out_channels = ch

    def forward(self, x): return self.layers(x)

block = DenseBlock(in_ch=64, n_layers=6, growth_rate=32)
x = torch.randn(2, 64, 56, 56)
out = block(x)
params = sum(p.numel() for p in block.parameters()) / 1e3
print('DenseBlock input: {} -> output: {}'.format(x.shape, out.shape))
print('Output channels: 64 + 6*32 = {} (concat, not add)'.format(64 + 6*32))
print('Parameters: {:.1f}K'.format(params))
```

## Growth Rate and Feature Reuse

The growth rate k is a key hyperparameter: it controls how many new feature maps each layer contributes to the collective knowledge. A small k (e.g., k=12 or k=32) is sufficient because each layer adds to all accumulated features rather than overwriting them. DenseNet-121 uses k=32 and achieves comparable accuracy to ResNet-50 with 8M vs 25M parameters. Huang et al. analysed filter activations and found that all layers within a dense block actively use features from all preceding layers — including the very first layer's edge detectors — confirming genuine feature reuse rather than redundant recomputation.

## Bottleneck and Compression: DenseNet-BC

DenseNet-B (Bottleneck): each layer uses a 1×1 conv before the 3×3 to reduce the growing input channels to 4k, preventing the parameter count from growing quadratically with depth. DenseNet-C (Compression): between dense blocks, a transition layer reduces channels by a factor θ (typically 0.5) before downsampling. DenseNet-BC combines both: DenseNet-BC-L-k denotes a network with L layers per block, growth rate k, bottlenecks, and θ=0.5 compression. DenseNet-BC-190-40 achieves 3.46% error on CIFAR-10 — state-of-the-art at the time — with 25M parameters.

```python
import torch
import torch.nn as nn

class TransitionLayer(nn.Module):
    '''DenseNet transition: 1x1 conv compression + 2x2 avg pool downsampling.
    theta < 1 compresses channels to reduce parameter growth between blocks.
    '''
    def __init__(self, in_ch, theta=0.5):
        super().__init__()
        out_ch = int(in_ch * theta)
        self.transition = nn.Sequential(
            nn.BatchNorm2d(in_ch), nn.ReLU(inplace=True),
            nn.Conv2d(in_ch, out_ch, 1, bias=False),
            nn.AvgPool2d(2, stride=2))
        self.out_channels = out_ch

    def forward(self, x): return self.transition(x)

# Simulate DenseNet-121 after first dense block: 64 + 6*32 = 256 channels
in_channels = 256
transition = TransitionLayer(in_channels, theta=0.5)
x = torch.randn(2, in_channels, 56, 56)
out = transition(x)
print('Transition input:  {}'.format(x.shape))
print('Transition output: {}'.format(out.shape))
print('Channels: {} -> {}  (theta=0.5)'.format(in_channels, transition.out_channels))
print('Spatial:  56x56 -> 28x28  (2x2 avg pool)')
params = sum(p.numel() for p in transition.parameters()) / 1e3
print('Parameters: {:.1f}K'.format(params))
```

> **Memory Cost is O(n²) Without Optimisation**: A naive DenseNet implementation allocates separate tensors for all L(L+1)/2 intermediate feature maps and keeps them in GPU memory for the backward pass. For DenseNet-264 with L=64 layers per block, this is 64×65/2 = 2,080 tensor allocations per block. The PyTorch DenseNet implementation uses a shared memory allocation trick: all input concatenations reference the same pre-allocated memory buffer, reducing peak memory from O(n²) to near O(n). Gradient checkpointing (torch.utils.checkpoint) provides an alternative: recompute activations during the backward pass rather than storing them.

## Memory-Efficient Implementation

Gradient checkpointing trades compute for memory: instead of storing intermediate activations for the backward pass, they are recomputed on the fly during backpropagation. For DenseNet, where each layer's input is the concatenation of all prior outputs, checkpointing the concatenation operation is especially effective. torch.utils.checkpoint.checkpoint wraps a function and discards its intermediate activations, recomputing them during the backward pass. This typically doubles training time (since activations are computed twice) but reduces memory by up to 10× for deep DenseNets.

```python
import torch
import torch.nn as nn
from torch.utils.checkpoint import checkpoint

class CheckpointedDenseLayer(nn.Module):
    '''DenseNet layer using gradient checkpointing to trade memory for compute.'''
    def __init__(self, in_ch, growth_rate=32):
        super().__init__()
        mid_ch = 4 * growth_rate
        self.bn1   = nn.BatchNorm2d(in_ch)
        self.conv1 = nn.Conv2d(in_ch, mid_ch, 1, bias=False)
        self.bn2   = nn.BatchNorm2d(mid_ch)
        self.conv2 = nn.Conv2d(mid_ch, growth_rate, 3, padding=1, bias=False)
        self.relu  = nn.ReLU(inplace=True)

    def _forward(self, x):
        out = self.conv1(self.relu(self.bn1(x)))
        return self.conv2(self.relu(self.bn2(out)))

    def forward(self, x):
        new_feat = checkpoint(self._forward, x, use_reentrant=False)
        return torch.cat([x, new_feat], dim=1)

class MemEfficientDenseBlock(nn.Module):
    def __init__(self, in_ch, n_layers, growth_rate=32):
        super().__init__()
        self.layers = nn.ModuleList()
        ch = in_ch
        for _ in range(n_layers):
            self.layers.append(CheckpointedDenseLayer(ch, growth_rate))
            ch += growth_rate
        self.out_channels = ch

    def forward(self, x):
        for layer in self.layers:
            x = layer(x)
        return x

block = MemEfficientDenseBlock(in_ch=64, n_layers=12, growth_rate=32)
x = torch.randn(2, 64, 28, 28)
out = block(x)
print('Checkpointed DenseBlock: {} -> {}'.format(x.shape, out.shape))
print('Output channels: 64 + 12*32 = {}'.format(64 + 12*32))
```

## Feature Reuse Visualisation

Huang et al. visualised which source features each layer actually uses by analysing the absolute weight magnitudes in the 1×1 bottleneck convolutions. If layer l allocates high weight to features from layer j, it genuinely reuses them. The analysis revealed that all source layers contribute non-trivially — including the very first layer's low-level features at deep layers. This is in contrast to ResNets where early features are effectively forgotten (overwritten by addition) as the network deepens. DenseNet's feature reuse pattern is like a committee: every member (layer) always has access to all prior evidence.

```python
import torch
import torch.nn as nn
import numpy as np

class AnalysisDenseLayer(nn.Module):
    def __init__(self, in_ch, growth_rate=32):
        super().__init__()
        mid_ch = 4 * growth_rate
        self.bn1   = nn.BatchNorm2d(in_ch)
        self.conv1 = nn.Conv2d(in_ch, mid_ch, 1, bias=False)  # weights to analyse
        self.bn2   = nn.BatchNorm2d(mid_ch)
        self.conv2 = nn.Conv2d(mid_ch, growth_rate, 3, padding=1, bias=False)
        self.relu  = nn.ReLU(inplace=True)
    def forward(self, x):
        out = self.conv1(self.relu(self.bn1(x)))
        return torch.cat([x, self.conv2(self.relu(self.bn2(out)))], dim=1)

n_layers, k, in_ch = 6, 32, 64
layers = [AnalysisDenseLayer(in_ch + i*k, k) for i in range(n_layers)]
# Compute mean absolute weight per source feature block in conv1
print('Feature reuse matrix (rows=layer, cols=source contribution):')
print('{:<10} '.format('Layer') + '  '.join('src{}'.format(i) for i in range(n_layers+1)))
for l_idx, layer in enumerate(layers):
    w = layer.conv1.weight.data.abs()   # shape: (4k, in_ch + l_idx*k, 1, 1)
    ch_ptr, contribs = 0, []
    for src in range(l_idx + 1):
        src_ch = in_ch if src == 0 else k
        contribs.append(w[:, ch_ptr:ch_ptr+src_ch].mean().item())
        ch_ptr += src_ch
    row = '  '.join('{:.3f}'.format(c) for c in contribs)
    print('Layer {:>2}:  {}'.format(l_idx+1, row))
```

## Why Dense Connections Work

Dense connectivity provides several orthogonal benefits: (1) implicit deep supervision — every layer receives gradient from the loss through multiple paths of varying lengths, similar to auxiliary classifiers but without extra parameters; (2) feature reuse — earlier layers' filters remain accessible throughout, so the network does not need to relearn low-level features; (3) regularisation — the shared feature map pool acts as a form of dropout in feature space, forcing layers to be complementary rather than redundant; (4) parameter efficiency — k new features per layer suffices because each layer builds on all accumulated context rather than starting from scratch. DenseNet achieves ResNet-level accuracy with 3× fewer parameters on ImageNet.

- Implicit deep supervision: gradients reach early layers through O(L) direct paths rather than the single chained path in plain networks.
- Feature reuse: edge detectors learned in layer 1 are directly available to layer L without being diluted by repeated addition.
- Complementary filters: each layer adds exactly k new feature maps, incentivising it to learn features distinct from all prior layers.
- Collective knowledge: the concatenated feature map is a shared, ever-growing representation — analogous to an ensemble's prediction pool.
- Connection to FPN: dense blocks are a form of all-to-all feature pyramid, whereas FPN builds a top-down pyramid of fixed resolution levels.

## DenseNet vs ResNet vs PlainNet

| Property | PlainNet | ResNet | DenseNet |
| --- | --- | --- | --- |
| Connection type | Sequential, layer to next | Skip: add x to F(x) | Dense: concat all prior to each |
| Feature reuse | None — overwritten each layer | Partial — addition mixes features | Full — all prior features always available |
| Gradient paths | 1 path per layer | 2 paths per block (main + skip) | O(L) paths per layer |
| Parameters | High (redundant relearning) | Medium | Low (k per layer suffices) |
| Memory (training) | O(L) | O(L) | O(L²) naive; O(L) with shared alloc |
| Depth scalability | Poor (vanishing gradients) | Excellent (1000+ layers) | Good (hundreds of layers practical) |

DenseNet is most effective when parameter efficiency matters more than inference speed: its dense connections create many small tensors that are cache-unfriendly on GPU, making it slower at inference than ResNet at equal accuracy. For deployment-constrained scenarios, MobileNet (depthwise separable + inverted residuals) and EfficientNet (compound scaling) typically dominate. DenseNet remains the architecture of choice for medical image segmentation (as the encoder in U-Net variants) and tasks where intermediate feature reuse is critical.

---

