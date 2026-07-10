---
title: "Squeeze-and-Excitation Networks"
slug: "squeeze-excitation-networks"
description: "Channel attention via global average pooling (squeeze) and two FC layers (excitation) — how SE blocks recalibrate channel-wise feature responses and improve accuracy with minimal parameter overhead."
tags: ["computer-vision"]
topic: "computer-vision"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"h2","content":"Overview"},{"type":"text","content":"Squeeze-and-Excitation (SE) Networks, introduced by Hu et al. at CVPR 2018, won the ImageNet ILSVRC classification challenge. The core idea is channel attention: learn which feature channels are most informative for a given input and recalibrate their responses accordingly. This is achieved through a lightweight gating mechanism that adds minimal parameters."},{"type":"text","content":"Standard CNNs treat all channels equally when combining feature maps. SE blocks address this by explicitly modeling channel interdependencies. Given a feature map of shape (H, W, C), SE blocks produce a vector of C weights — one per channel — that amplify useful features and suppress less relevant ones, improving representational power without changing spatial resolution."},{"type":"h2","content":"Squeeze: Global Context"},{"type":"text","content":"The squeeze operation compresses spatial information into a channel descriptor. Global Average Pooling (GAP) aggregates each channel\u0027s feature map into a single scalar by averaging over all H×W spatial positions. The result is a vector z ∈ ℝ^C, where z_c = (1/H×W) Σ u_c(i,j). This gives the network a global view of each channel\u0027s activation distribution."},{"type":"text","content":"GAP is chosen over more complex pooling strategies because it is differentiable, computationally free, and captures holistic channel-level statistics. It allows the subsequent excitation module to reason about channel relationships in a position-agnostic manner, focusing on what is present rather than where it appears in the spatial dimensions of the feature map."},{"type":"h2","content":"Excitation: Channel Recalibration"},{"type":"text","content":"The excitation operation transforms the squeezed descriptor z into channel weights s ∈ [0,1]^C. Two fully connected layers form a bottleneck: z is projected down from C to C/r neurons (r is the reduction ratio), then back up to C neurons. A sigmoid activation ensures each weight lies in [0,1], enabling soft, differentiable channel selection that recalibrates feature responses."},{"type":"code","language":"python","content":"import torch.nn as nn\nclass SEBlock(nn.Module):\n    def __init__(self, channels, reduction=16):\n        super().__init__()\n        self.pool = nn.AdaptiveAvgPool2d(1)\n        self.fc = nn.Sequential(\n            nn.Linear(channels, channels // reduction, bias=False),\n            nn.ReLU(),\n            nn.Linear(channels // reduction, channels, bias=False),\n            nn.Sigmoid()\n        )\n    def forward(self, x):\n        b, c = x.shape[:2]\n        s = self.fc(self.pool(x).view(b, c)).view(b, c, 1, 1)\n        return x * s"},{"type":"h2","content":"SE Block Implementation"},{"type":"text","content":"The reduction ratio r controls the bottleneck size, trading off accuracy against parameter efficiency. A smaller r (e.g., r=4) enables richer channel interactions but adds more parameters; a larger r (e.g., r=32) is more frugal but may lose representational capacity. The original paper recommends r=16 as a default, balancing accuracy gains and computational overhead."},{"type":"code","language":"python","content":"class SEResBlock(nn.Module):\n    def __init__(self, channels, reduction=16):\n        super().__init__()\n        self.conv1 = nn.Conv2d(channels, channels, 3, padding=1)\n        self.bn1   = nn.BatchNorm2d(channels)\n        self.conv2 = nn.Conv2d(channels, channels, 3, padding=1)\n        self.bn2   = nn.BatchNorm2d(channels)\n        self.se    = SEBlock(channels, reduction)\n        self.relu  = nn.ReLU(inplace=True)\n    def forward(self, x):\n        out = self.relu(self.bn1(self.conv1(x)))\n        out = self.bn2(self.conv2(out))\n        out = self.se(out)          # recalibrate channels\n        return self.relu(out + x)  # add skip connection"},{"type":"text","content":"SE blocks integrate seamlessly into existing architectures as drop-in modules. In ResNets, the SE block is inserted after the second convolution and before the residual addition. In VGG-style networks it follows each convolutional block. Placement before the skip connection ensures recalibration happens on transformed features, preserving the identity shortcut\u0027s gradient flow."},{"type":"code","language":"python","content":"def sweep_reduction_ratios(val_loader, ratios=[4, 8, 16, 32]):\n    results = {}\n    for r in ratios:\n        model = SEResNet50(reduction=r).cuda()\n        params = sum(p.numel() for p in model.parameters())\n        acc = evaluate(model, val_loader)\n        results[r] = {\n            \"params_M\": params / 1e6,\n            \"top1_acc\": acc\n        }\n        print(f\"r={r}: {params/1e6:.1f}M params, {acc:.2f}% top-1\")\n    return results"},{"type":"h2","content":"Integration and Overhead"},{"type":"text","content":"SE blocks are computationally efficient: the squeeze operation (GAP) is parameter-free, and the two FC layers add only 2(C²/r) parameters per block. For a ResNet-50 with ~25M parameters, adding SE blocks with r=16 increases parameter count by about 2.5M (~10%), yet consistently delivers 1–2% top-1 accuracy gains on ImageNet — a highly favorable trade-off."},{"type":"table","content":"| Model | SE Ratio | Extra Params % | Top-1 Gain | FLOPs Overhead |\n|---|---|---|---|---|\n| SE-ResNet-50 r=4 | 4 | 19.3% | +1.8% | \u003c0.1% |\n| SE-ResNet-50 r=8 | 8 | 9.7% | +1.7% | \u003c0.1% |\n| SE-ResNet-50 r=16 | 16 | 4.9% | +1.6% | \u003c0.1% |\n| SE-ResNet-50 r=32 | 32 | 2.5% | +1.3% | \u003c0.1% |\n| EfficientNet SE | 4 | 2.1% | +0.4% | \u003c0.1% |\n| MobileNetV3 SE | 4 | 3.2% | +1.0% | \u003c0.1% |"},{"type":"callout","calloutType":"info","content":"SE blocks add only ~2% extra parameters but consistently yield 1–2% top-1 accuracy gains — they are now standard in EfficientNet, MobileNetV3, and RegNet architectures."},{"type":"text","content":"FLOPs overhead from SE blocks is negligible because the FC layers operate on the channel vector (C values) rather than full feature maps (H×W×C values). For a 14×14×512 feature map, GAP reduces spatial dimensions entirely, so subsequent FC layers process only 512 values — orders of magnitude cheaper than the spatial convolution operations they accompany."},{"type":"code","language":"python","content":"import torch, matplotlib.pyplot as plt\ndef visualize_se_weights(model, x):\n    weights = {}\n    def hook(name):\n        def fn(m, inp, out):\n            weights[name] = out.detach().squeeze().cpu()\n        return fn\n    for name, m in model.named_modules():\n        if isinstance(m, SEBlock):\n            m.fc.register_forward_hook(hook(name))\n    with torch.no_grad():\n        model(x)\n    for name, w in weights.items():\n        plt.bar(range(len(w)), w.numpy())\n        plt.title(f\"SE weights: {name}\"); plt.show()"},{"type":"h2","content":"Key Takeaways"},{"type":"text","content":"SE Networks demonstrate that explicit channel attention is a powerful and general technique for improving CNN performance. The squeeze-excitation paradigm — aggregate global context, learn channel weights, recalibrate — is intuitive and effective. The original SE-ResNet-154 achieved 2.251% top-5 error on ImageNet, winning the ILSVRC 2017 classification challenge outright."},{"type":"text","content":"The reduction ratio r offers a direct knob for the accuracy-efficiency trade-off. Practitioners should benchmark r=8 and r=16 first; r=4 is worth exploring when accuracy is the priority and compute budget allows. SE blocks are particularly beneficial in depthwise-separable architectures such as MobileNets, where channel mixing is limited by the factored convolution design."},{"type":"text","content":"SE Networks inspired subsequent attention mechanisms: CBAM extends channel attention with spatial attention; ECA-Net replaces FC layers with 1D convolution over adjacent channels for lower overhead; GE-Nets use gather-excite to capture spatial context at multiple scales. Despite these advances, SE blocks remain a go-to choice due to their simplicity and strong empirical results."}]"
---
# Squeeze-and-Excitation Networks

Squeeze-and-Excitation (SE) Networks, introduced by Hu et al. at CVPR 2018, won the ImageNet ILSVRC classification challenge. The core idea is channel attention: learn which feature channels are most informative for a given input and recalibrate their responses accordingly. This is achieved through a lightweight gating mechanism that adds minimal parameters.

Standard CNNs treat all channels equally when combining feature maps. SE blocks address this by explicitly modeling channel interdependencies. Given a feature map of shape (H, W, C), SE blocks produce a vector of C weights — one per channel — that amplify useful features and suppress less relevant ones, improving representational power without changing spatial resolution.

The squeeze operation compresses spatial information into a channel descriptor. Global Average Pooling (GAP) aggregates each channel's feature map into a single scalar by averaging over all H×W spatial positions. The result is a vector z ∈ ℝ^C, where z_c = (1/H×W) Σ u_c(i,j). This gives the network a global view of each channel's activation distribution.

GAP is chosen over more complex pooling strategies because it is differentiable, computationally free, and captures holistic channel-level statistics. It allows the subsequent excitation module to reason about channel relationships in a position-agnostic manner, focusing on what is present rather than where it appears in the spatial dimensions of the feature map.

The excitation operation transforms the squeezed descriptor z into channel weights s ∈ [0,1]^C. Two fully connected layers form a bottleneck: z is projected down from C to C/r neurons (r is the reduction ratio), then back up to C neurons. A sigmoid activation ensures each weight lies in [0,1], enabling soft, differentiable channel selection that recalibrates feature responses.

```python
import torch.nn as nn
class SEBlock(nn.Module):
    def __init__(self, channels, reduction=16):
        super().__init__()
        self.pool = nn.AdaptiveAvgPool2d(1)
        self.fc = nn.Sequential(
            nn.Linear(channels, channels // reduction, bias=False),
            nn.ReLU(),
            nn.Linear(channels // reduction, channels, bias=False),
            nn.Sigmoid()
        )
    def forward(self, x):
        b, c = x.shape[:2]
        s = self.fc(self.pool(x).view(b, c)).view(b, c, 1, 1)
        return x * s
```

The reduction ratio r controls the bottleneck size, trading off accuracy against parameter efficiency. A smaller r (e.g., r=4) enables richer channel interactions but adds more parameters; a larger r (e.g., r=32) is more frugal but may lose representational capacity. The original paper recommends r=16 as a default, balancing accuracy gains and computational overhead.

```python
class SEResBlock(nn.Module):
    def __init__(self, channels, reduction=16):
        super().__init__()
        self.conv1 = nn.Conv2d(channels, channels, 3, padding=1)
        self.bn1   = nn.BatchNorm2d(channels)
        self.conv2 = nn.Conv2d(channels, channels, 3, padding=1)
        self.bn2   = nn.BatchNorm2d(channels)
        self.se    = SEBlock(channels, reduction)
        self.relu  = nn.ReLU(inplace=True)
    def forward(self, x):
        out = self.relu(self.bn1(self.conv1(x)))
        out = self.bn2(self.conv2(out))
        out = self.se(out)          # recalibrate channels
        return self.relu(out + x)  # add skip connection
```

SE blocks integrate seamlessly into existing architectures as drop-in modules. In ResNets, the SE block is inserted after the second convolution and before the residual addition. In VGG-style networks it follows each convolutional block. Placement before the skip connection ensures recalibration happens on transformed features, preserving the identity shortcut's gradient flow.

```python
def sweep_reduction_ratios(val_loader, ratios=[4, 8, 16, 32]):
    results = {}
    for r in ratios:
        model = SEResNet50(reduction=r).cuda()
        params = sum(p.numel() for p in model.parameters())
        acc = evaluate(model, val_loader)
        results[r] = {
            "params_M": params / 1e6,
            "top1_acc": acc
        }
        print(f"r={r}: {params/1e6:.1f}M params, {acc:.2f}% top-1")
    return results
```

SE blocks are computationally efficient: the squeeze operation (GAP) is parameter-free, and the two FC layers add only 2(C²/r) parameters per block. For a ResNet-50 with ~25M parameters, adding SE blocks with r=16 increases parameter count by about 2.5M (~10%), yet consistently delivers 1–2% top-1 accuracy gains on ImageNet — a highly favorable trade-off.

|  |
| --- |

> ****: SE blocks add only ~2% extra parameters but consistently yield 1–2% top-1 accuracy gains — they are now standard in EfficientNet, MobileNetV3, and RegNet architectures.

FLOPs overhead from SE blocks is negligible because the FC layers operate on the channel vector (C values) rather than full feature maps (H×W×C values). For a 14×14×512 feature map, GAP reduces spatial dimensions entirely, so subsequent FC layers process only 512 values — orders of magnitude cheaper than the spatial convolution operations they accompany.

```python
import torch, matplotlib.pyplot as plt
def visualize_se_weights(model, x):
    weights = {}
    def hook(name):
        def fn(m, inp, out):
            weights[name] = out.detach().squeeze().cpu()
        return fn
    for name, m in model.named_modules():
        if isinstance(m, SEBlock):
            m.fc.register_forward_hook(hook(name))
    with torch.no_grad():
        model(x)
    for name, w in weights.items():
        plt.bar(range(len(w)), w.numpy())
        plt.title(f"SE weights: {name}"); plt.show()
```

SE Networks demonstrate that explicit channel attention is a powerful and general technique for improving CNN performance. The squeeze-excitation paradigm — aggregate global context, learn channel weights, recalibrate — is intuitive and effective. The original SE-ResNet-154 achieved 2.251% top-5 error on ImageNet, winning the ILSVRC 2017 classification challenge outright.

The reduction ratio r offers a direct knob for the accuracy-efficiency trade-off. Practitioners should benchmark r=8 and r=16 first; r=4 is worth exploring when accuracy is the priority and compute budget allows. SE blocks are particularly beneficial in depthwise-separable architectures such as MobileNets, where channel mixing is limited by the factored convolution design.

SE Networks inspired subsequent attention mechanisms: CBAM extends channel attention with spatial attention; ECA-Net replaces FC layers with 1D convolution over adjacent channels for lower overhead; GE-Nets use gather-excite to capture spatial context at multiple scales. Despite these advances, SE blocks remain a go-to choice due to their simplicity and strong empirical results.

