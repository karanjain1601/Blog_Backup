---
title: "AlexNet and VGG — Early Deep CNN Architectures"
slug: "alexnet-vgg-architectures"
description: "AlexNet (2012) proved deep CNNs with ReLU, dropout, and GPU training can win ImageNet; VGG (2014) showed that uniform 3×3 convolutions stacked deeply outperform large-kernel shallow networks. Both remain foundational feature extractors."
tags: ["deep-learning", "cnns", "architectures"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Before 2012 the dominant computer vision approach was hand-crafted features (SIFT, HOG) combined with shallow classifiers. AlexNet (Krizhevsky, Sutskever, Hinton, 2012) shattered this paradigm by winning ImageNet LSVRC with a 10.9-point top-5 error improvement over the runner-up. It demonstrated that deep CNNs trained on GPUs with large datasets could learn far more powerful representations than any hand-engineered alternative. VGG (Simonyan \u0026 Zisserman, 2014) then showed that architectural simplicity — stacking many 3×3 convolutions — could push accuracy further while providing clean, reusable feature extractors."},{"type":"heading","level":2,"content":"AlexNet Architecture"},{"type":"text","content":"AlexNet consists of five convolutional layers followed by three fully-connected layers. The first conv layer uses 96 11×11 filters with stride 4 (large stride to quickly reduce the 224×224 input). Subsequent conv layers use 3×3 and 5×5 kernels. Max pooling follows layers 1, 2, and 5 to reduce spatial dimensions. Local Response Normalisation (LRN) — a now-deprecated layer that normalises across adjacent feature maps — follows layers 1 and 2. The three FC layers (4096 → 4096 → 1000) dominate the parameter count at 58M of the total 60M parameters."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass AlexNet(nn.Module):\n    \u0027\u0027\u0027AlexNet (Krizhevsky et al., 2012) — 5 conv + 3 FC layers.\u0027\u0027\u0027\n    def __init__(self, num_classes=1000, dropout=0.5):\n        super().__init__()\n        self.features = nn.Sequential(\n            nn.Conv2d(3, 96, 11, stride=4, padding=2), nn.ReLU(inplace=True),\n            nn.LocalResponseNorm(5, alpha=1e-4, beta=0.75, k=2.0),\n            nn.MaxPool2d(3, stride=2),\n            nn.Conv2d(96, 256, 5, padding=2), nn.ReLU(inplace=True),\n            nn.LocalResponseNorm(5, alpha=1e-4, beta=0.75, k=2.0),\n            nn.MaxPool2d(3, stride=2),\n            nn.Conv2d(256, 384, 3, padding=1), nn.ReLU(inplace=True),\n            nn.Conv2d(384, 384, 3, padding=1), nn.ReLU(inplace=True),\n            nn.Conv2d(384, 256, 3, padding=1), nn.ReLU(inplace=True),\n            nn.MaxPool2d(3, stride=2))\n        self.classifier = nn.Sequential(\n            nn.Dropout(dropout), nn.Linear(256 * 6 * 6, 4096), nn.ReLU(inplace=True),\n            nn.Dropout(dropout), nn.Linear(4096, 4096), nn.ReLU(inplace=True),\n            nn.Linear(4096, num_classes))\n\n    def forward(self, x):\n        return self.classifier(self.features(x).flatten(1))\n\nmodel = AlexNet()\nx = torch.randn(2, 3, 224, 224)\nparams = sum(p.numel() for p in model.parameters()) / 1e6\nprint(\u0027AlexNet output: {}\u0027.format(model(x).shape))\nprint(\u0027Parameters: {:.1f}M (58M in FC layers alone)\u0027.format(params))"},{"type":"heading","level":2,"content":"Training Innovations in AlexNet"},{"type":"text","content":"AlexNet introduced several training techniques that became standard: ReLU activations (instead of tanh or sigmoid) train 6× faster because they do not suffer from the vanishing gradient in the saturation region; dropout (p=0.5) in the two FC layers reduces co-adaptation of neurons and halves test error relative to no regularisation; data augmentation (random 224×224 crops and horizontal flips from 256×256 images, PCA colour jitter) effectively quintuples the training set. Training on two GTX 580 GPUs for six days was essential — the model split across GPUs, with cross-GPU communication only at specific layers."},{"type":"list","ordered":false,"items":["ReLU: f(x)=max(0,x) — no saturation for x\u003e0, gradient always 1 or 0, trains ~6x faster than sigmoid/tanh.","Dropout (p=0.5): applied to FC6 and FC7, forces neurons to learn redundant representations, acts as implicit ensemble of 2^n networks.","LRN: lateral inhibition across adjacent feature maps — normalises response relative to neighbours, mimics biological lateral inhibition. Dropped in later architectures.","Data augmentation: 224×224 crops from padded 256×256, horizontal flips, PCA colour jitter — critical for preventing overfitting with 60M parameters.","GPU training: split architecture across 2 GPUs, cross-GPU communication only at layers 3 and FC layers.","Weight initialisation: Gaussian(0, 0.01) for weights, constant 0 or 1 for biases (layer-dependent)."]},{"type":"heading","level":2,"content":"VGG: Depth Through Small Kernels"},{"type":"text","content":"VGG (Simonyan \u0026 Zisserman, 2014) makes one design choice and pursues it relentlessly: use only 3×3 convolutions with stride 1 and padding 1. Two stacked 3×3 convs have the same receptive field as one 5×5 conv but use 2×(3×3×C²) = 18C² parameters instead of 25C². Three stacked 3×3 convs match a 7×7 conv: 27C² vs 49C² params — a 44% saving — plus two extra ReLU nonlinearities which increase expressiveness. VGG is organised into five blocks with progressively doubling channels (64, 128, 256, 512, 512), each ending with a 2×2 max pool. VGG16 has 16 weight layers; VGG19 has 19."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom typing import List\n\ndef vgg_block(in_ch: int, out_ch: int, n_convs: int) -\u003e nn.Sequential:\n    \u0027\u0027\u0027VGG block: n_convs x (Conv 3x3 + BN + ReLU), then MaxPool 2x2.\u0027\u0027\u0027\n    layers: List[nn.Module] = []\n    for _ in range(n_convs):\n        layers += [nn.Conv2d(in_ch, out_ch, 3, padding=1, bias=False),\n                   nn.BatchNorm2d(out_ch), nn.ReLU(inplace=True)]\n        in_ch = out_ch\n    layers.append(nn.MaxPool2d(2, stride=2))\n    return nn.Sequential(*layers)\n\nclass VGG16(nn.Module):\n    \u0027\u0027\u0027VGG-16 with batch normalisation (Simonyan \u0026 Zisserman, 2014).\u0027\u0027\u0027\n    def __init__(self, num_classes=1000):\n        super().__init__()\n        self.features = nn.Sequential(\n            vgg_block(3, 64, 2),    # 224 -\u003e 112\n            vgg_block(64, 128, 2),  # 112 -\u003e 56\n            vgg_block(128, 256, 3), # 56  -\u003e 28\n            vgg_block(256, 512, 3), # 28  -\u003e 14\n            vgg_block(512, 512, 3)) # 14  -\u003e 7\n        self.head = nn.Sequential(\n            nn.Flatten(),\n            nn.Linear(512 * 7 * 7, 4096), nn.ReLU(inplace=True), nn.Dropout(0.5),\n            nn.Linear(4096, 4096),        nn.ReLU(inplace=True), nn.Dropout(0.5),\n            nn.Linear(4096, num_classes))\n\n    def forward(self, x): return self.head(self.features(x))\n\nmodel = VGG16()\nx = torch.randn(1, 3, 224, 224)\nparams = sum(p.numel() for p in model.parameters()) / 1e6\nprint(\u0027VGG-16 output: {}\u0027.format(model(x).shape))\nprint(\u0027Parameters: {:.1f}M\u0027.format(params))"},{"type":"heading","level":2,"content":"Receptive Field and Parameter Analysis"},{"type":"text","content":"The effective receptive field of stacked 3×3 convs grows linearly: one 3×3 gives RF=3; two give RF=5 (matching one 5×5); three give RF=7 (matching one 7×7). The parameter savings are significant: two 3×3 convs on C channels cost 2×9C² = 18C² parameters while a single 5×5 costs 25C² (28% more). Three 3×3 convs cost 27C² versus 49C² for a 7×7 (44% more). Additionally, each extra conv layer adds a ReLU nonlinearity, which increases the function class\u0027s expressiveness without extra spatial overhead."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ndef count_params(model):\n    return sum(p.numel() for p in model.parameters() if p.requires_grad)\n\ndef rf_of_stacked_3x3(n):\n    \u0027\u0027\u0027Effective receptive field of n stacked 3x3 convs.\u0027\u0027\u0027\n    return 1 + 2 * n\n\n# Parameter comparison: stacked 3x3 vs equivalent large kernel\nC = 256\nconfigs = [\n    (\u0027one 5x5\u0027, nn.Conv2d(C, C, 5, padding=2)),\n    (\u0027two 3x3\u0027, nn.Sequential(nn.Conv2d(C, C, 3, padding=1), nn.Conv2d(C, C, 3, padding=1))),\n    (\u0027one 7x7\u0027, nn.Conv2d(C, C, 7, padding=3)),\n    (\u0027three 3x3\u0027, nn.Sequential(\n        nn.Conv2d(C, C, 3, padding=1), nn.Conv2d(C, C, 3, padding=1),\n        nn.Conv2d(C, C, 3, padding=1)))\n]\nprint(\u0027{:\u003c14} {:\u003e12} {:\u003e8} {:\u003e12}\u0027.format(\u0027Config\u0027, \u0027Params\u0027, \u0027RF\u0027, \u0027Savings\u0027))\nref5 = count_params(configs[0][1])\nref7 = count_params(configs[2][1])\nfor name, module in configs:\n    p = count_params(module)\n    rf = rf_of_stacked_3x3(2 if \u00273x3\u0027 in name and \u0027two\u0027 in name\n                           else 3 if \u0027three\u0027 in name else 1)\n    ref = ref5 if \u00275x5\u0027 in name or \u0027two\u0027 in name else ref7\n    save = \u0027---\u0027 if name in (\u0027one 5x5\u0027, \u0027one 7x7\u0027) else \u0027-{:.0f}%\u0027.format(100*(1 - p/ref))\n    print(\u0027{:\u003c14} {:\u003e12,} {:\u003e8} {:\u003e12}\u0027.format(name, p, rf, save))"},{"type":"callout","variant":"warning","title":"VGG\u0027s FC Layer Bottleneck","content":"VGG16 has 138M parameters — but 123M (89%) live in the three FC layers (512×7×7→4096, 4096→4096, 4096→1000). The conv layers that do all the spatial feature extraction account for only 15M parameters. Modern architectures replace FC layers with global average pooling (GAP), eliminating this bottleneck: ResNet-50 has only 25M parameters and GoogLeNet has 5M — both more accurate than VGG."},{"type":"heading","level":2,"content":"VGG as Feature Extractor"},{"type":"text","content":"Despite being surpassed on ImageNet accuracy, VGG\u0027s feature representations remain powerful for transfer learning, perceptual loss in style transfer (Gatys et al., 2015), and as a backbone for downstream tasks. The uniform 3×3 conv structure makes it easy to extract features at any depth. Common extraction points: relu3_3 (256 channels, 28×28 for 224×224 input) for texture-rich features; relu4_3 (512 channels, 14×14) for semantic object features; relu5_3 (512 channels, 7×7) for the most abstract features."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom torchvision import models\n\nclass VGGFeatureExtractor(nn.Module):\n    \u0027\u0027\u0027VGG-16 pretrained backbone with a lightweight classification head.\u0027\u0027\u0027\n    def __init__(self, num_classes=10, feature_layer=30, freeze=True):\n        super().__init__()\n        vgg = models.vgg16_bn(weights=models.VGG16_BN_Weights.IMAGENET1K_V1)\n        self.backbone = nn.Sequential(*list(vgg.features.children())[:feature_layer])\n        if freeze:\n            for param in self.backbone.parameters():\n                param.requires_grad = False\n        self.head = nn.Sequential(\n            nn.AdaptiveAvgPool2d((4, 4)), nn.Flatten(),\n            nn.Linear(512 * 16, 512), nn.ReLU(inplace=True),\n            nn.Dropout(0.5), nn.Linear(512, num_classes))\n\n    def forward(self, x):\n        return self.head(self.backbone(x))\n\nmodel = VGGFeatureExtractor(num_classes=10, freeze=True)\ntotal = sum(p.numel() for p in model.parameters())\ntrainable = sum(p.numel() for p in model.parameters() if p.requires_grad)\nx = torch.randn(4, 3, 224, 224)\nout = model(x)\nprint(\u0027Output: {}\u0027.format(out.shape))\nprint(\u0027Trainable: {:,} / Total: {:,} ({:.1f}%)\u0027.format(\n    trainable, total, 100 * trainable / total))"},{"type":"heading","level":2,"content":"Limitations and the Path to ResNet"},{"type":"text","content":"Both AlexNet and VGG suffer from vanishing gradients when depth increases beyond ~20 layers. Simply stacking more layers degrades training accuracy — not test accuracy, indicating an optimisation problem rather than overfitting. VGG19 already shows diminishing returns over VGG16. This degradation problem led He et al. to hypothesise that learning identity mappings is hard, and to introduce explicit shortcut connections (residuals) in ResNet (2015). ResNet-152 outperforms VGG16 with 25M vs 138M parameters and enables networks hundreds of layers deep. LRN (used in AlexNet) was shown to provide negligible benefit by VGG and was dropped. Batch normalisation (Ioffe \u0026 Szegedy, 2015) superseded it as the standard normalisation technique."},{"type":"heading","level":2,"content":"Architecture Comparison"},{"type":"table","headers":["Model","Year","Depth","Params","GFLOPs","Key Innovation","Top-5 Error"],"rows":[["AlexNet","2012","8","60M","0.7","ReLU + dropout + GPU","15.3%"],["VGG-16","2014","16","138M","15.5","Uniform 3×3 conv stacking","7.3%"],["VGG-19","2014","19","144M","19.6","Deeper uniform 3×3 stacks","7.1%"],["GoogLeNet","2014","22","5M","1.5","Inception parallel branches","6.7%"],["ResNet-50","2015","50","25M","4.1","Residual skip connections","5.3%"]]},{"type":"divider"}]"
---
# AlexNet and VGG — Early Deep CNN Architectures

Before 2012 the dominant computer vision approach was hand-crafted features (SIFT, HOG) combined with shallow classifiers. AlexNet (Krizhevsky, Sutskever, Hinton, 2012) shattered this paradigm by winning ImageNet LSVRC with a 10.9-point top-5 error improvement over the runner-up. It demonstrated that deep CNNs trained on GPUs with large datasets could learn far more powerful representations than any hand-engineered alternative. VGG (Simonyan & Zisserman, 2014) then showed that architectural simplicity — stacking many 3×3 convolutions — could push accuracy further while providing clean, reusable feature extractors.

## AlexNet Architecture

AlexNet consists of five convolutional layers followed by three fully-connected layers. The first conv layer uses 96 11×11 filters with stride 4 (large stride to quickly reduce the 224×224 input). Subsequent conv layers use 3×3 and 5×5 kernels. Max pooling follows layers 1, 2, and 5 to reduce spatial dimensions. Local Response Normalisation (LRN) — a now-deprecated layer that normalises across adjacent feature maps — follows layers 1 and 2. The three FC layers (4096 → 4096 → 1000) dominate the parameter count at 58M of the total 60M parameters.

```python
import torch
import torch.nn as nn

class AlexNet(nn.Module):
    '''AlexNet (Krizhevsky et al., 2012) — 5 conv + 3 FC layers.'''
    def __init__(self, num_classes=1000, dropout=0.5):
        super().__init__()
        self.features = nn.Sequential(
            nn.Conv2d(3, 96, 11, stride=4, padding=2), nn.ReLU(inplace=True),
            nn.LocalResponseNorm(5, alpha=1e-4, beta=0.75, k=2.0),
            nn.MaxPool2d(3, stride=2),
            nn.Conv2d(96, 256, 5, padding=2), nn.ReLU(inplace=True),
            nn.LocalResponseNorm(5, alpha=1e-4, beta=0.75, k=2.0),
            nn.MaxPool2d(3, stride=2),
            nn.Conv2d(256, 384, 3, padding=1), nn.ReLU(inplace=True),
            nn.Conv2d(384, 384, 3, padding=1), nn.ReLU(inplace=True),
            nn.Conv2d(384, 256, 3, padding=1), nn.ReLU(inplace=True),
            nn.MaxPool2d(3, stride=2))
        self.classifier = nn.Sequential(
            nn.Dropout(dropout), nn.Linear(256 * 6 * 6, 4096), nn.ReLU(inplace=True),
            nn.Dropout(dropout), nn.Linear(4096, 4096), nn.ReLU(inplace=True),
            nn.Linear(4096, num_classes))

    def forward(self, x):
        return self.classifier(self.features(x).flatten(1))

model = AlexNet()
x = torch.randn(2, 3, 224, 224)
params = sum(p.numel() for p in model.parameters()) / 1e6
print('AlexNet output: {}'.format(model(x).shape))
print('Parameters: {:.1f}M (58M in FC layers alone)'.format(params))
```

## Training Innovations in AlexNet

AlexNet introduced several training techniques that became standard: ReLU activations (instead of tanh or sigmoid) train 6× faster because they do not suffer from the vanishing gradient in the saturation region; dropout (p=0.5) in the two FC layers reduces co-adaptation of neurons and halves test error relative to no regularisation; data augmentation (random 224×224 crops and horizontal flips from 256×256 images, PCA colour jitter) effectively quintuples the training set. Training on two GTX 580 GPUs for six days was essential — the model split across GPUs, with cross-GPU communication only at specific layers.

- ReLU: f(x)=max(0,x) — no saturation for x>0, gradient always 1 or 0, trains ~6x faster than sigmoid/tanh.
- Dropout (p=0.5): applied to FC6 and FC7, forces neurons to learn redundant representations, acts as implicit ensemble of 2^n networks.
- LRN: lateral inhibition across adjacent feature maps — normalises response relative to neighbours, mimics biological lateral inhibition. Dropped in later architectures.
- Data augmentation: 224×224 crops from padded 256×256, horizontal flips, PCA colour jitter — critical for preventing overfitting with 60M parameters.
- GPU training: split architecture across 2 GPUs, cross-GPU communication only at layers 3 and FC layers.
- Weight initialisation: Gaussian(0, 0.01) for weights, constant 0 or 1 for biases (layer-dependent).

## VGG: Depth Through Small Kernels

VGG (Simonyan & Zisserman, 2014) makes one design choice and pursues it relentlessly: use only 3×3 convolutions with stride 1 and padding 1. Two stacked 3×3 convs have the same receptive field as one 5×5 conv but use 2×(3×3×C²) = 18C² parameters instead of 25C². Three stacked 3×3 convs match a 7×7 conv: 27C² vs 49C² params — a 44% saving — plus two extra ReLU nonlinearities which increase expressiveness. VGG is organised into five blocks with progressively doubling channels (64, 128, 256, 512, 512), each ending with a 2×2 max pool. VGG16 has 16 weight layers; VGG19 has 19.

```python
import torch
import torch.nn as nn
from typing import List

def vgg_block(in_ch: int, out_ch: int, n_convs: int) -> nn.Sequential:
    '''VGG block: n_convs x (Conv 3x3 + BN + ReLU), then MaxPool 2x2.'''
    layers: List[nn.Module] = []
    for _ in range(n_convs):
        layers += [nn.Conv2d(in_ch, out_ch, 3, padding=1, bias=False),
                   nn.BatchNorm2d(out_ch), nn.ReLU(inplace=True)]
        in_ch = out_ch
    layers.append(nn.MaxPool2d(2, stride=2))
    return nn.Sequential(*layers)

class VGG16(nn.Module):
    '''VGG-16 with batch normalisation (Simonyan & Zisserman, 2014).'''
    def __init__(self, num_classes=1000):
        super().__init__()
        self.features = nn.Sequential(
            vgg_block(3, 64, 2),    # 224 -> 112
            vgg_block(64, 128, 2),  # 112 -> 56
            vgg_block(128, 256, 3), # 56  -> 28
            vgg_block(256, 512, 3), # 28  -> 14
            vgg_block(512, 512, 3)) # 14  -> 7
        self.head = nn.Sequential(
            nn.Flatten(),
            nn.Linear(512 * 7 * 7, 4096), nn.ReLU(inplace=True), nn.Dropout(0.5),
            nn.Linear(4096, 4096),        nn.ReLU(inplace=True), nn.Dropout(0.5),
            nn.Linear(4096, num_classes))

    def forward(self, x): return self.head(self.features(x))

model = VGG16()
x = torch.randn(1, 3, 224, 224)
params = sum(p.numel() for p in model.parameters()) / 1e6
print('VGG-16 output: {}'.format(model(x).shape))
print('Parameters: {:.1f}M'.format(params))
```

## Receptive Field and Parameter Analysis

The effective receptive field of stacked 3×3 convs grows linearly: one 3×3 gives RF=3; two give RF=5 (matching one 5×5); three give RF=7 (matching one 7×7). The parameter savings are significant: two 3×3 convs on C channels cost 2×9C² = 18C² parameters while a single 5×5 costs 25C² (28% more). Three 3×3 convs cost 27C² versus 49C² for a 7×7 (44% more). Additionally, each extra conv layer adds a ReLU nonlinearity, which increases the function class's expressiveness without extra spatial overhead.

```python
import torch
import torch.nn as nn

def count_params(model):
    return sum(p.numel() for p in model.parameters() if p.requires_grad)

def rf_of_stacked_3x3(n):
    '''Effective receptive field of n stacked 3x3 convs.'''
    return 1 + 2 * n

# Parameter comparison: stacked 3x3 vs equivalent large kernel
C = 256
configs = [
    ('one 5x5', nn.Conv2d(C, C, 5, padding=2)),
    ('two 3x3', nn.Sequential(nn.Conv2d(C, C, 3, padding=1), nn.Conv2d(C, C, 3, padding=1))),
    ('one 7x7', nn.Conv2d(C, C, 7, padding=3)),
    ('three 3x3', nn.Sequential(
        nn.Conv2d(C, C, 3, padding=1), nn.Conv2d(C, C, 3, padding=1),
        nn.Conv2d(C, C, 3, padding=1)))
]
print('{:<14} {:>12} {:>8} {:>12}'.format('Config', 'Params', 'RF', 'Savings'))
ref5 = count_params(configs[0][1])
ref7 = count_params(configs[2][1])
for name, module in configs:
    p = count_params(module)
    rf = rf_of_stacked_3x3(2 if '3x3' in name and 'two' in name
                           else 3 if 'three' in name else 1)
    ref = ref5 if '5x5' in name or 'two' in name else ref7
    save = '---' if name in ('one 5x5', 'one 7x7') else '-{:.0f}%'.format(100*(1 - p/ref))
    print('{:<14} {:>12,} {:>8} {:>12}'.format(name, p, rf, save))
```

> **VGG's FC Layer Bottleneck**: VGG16 has 138M parameters — but 123M (89%) live in the three FC layers (512×7×7→4096, 4096→4096, 4096→1000). The conv layers that do all the spatial feature extraction account for only 15M parameters. Modern architectures replace FC layers with global average pooling (GAP), eliminating this bottleneck: ResNet-50 has only 25M parameters and GoogLeNet has 5M — both more accurate than VGG.

## VGG as Feature Extractor

Despite being surpassed on ImageNet accuracy, VGG's feature representations remain powerful for transfer learning, perceptual loss in style transfer (Gatys et al., 2015), and as a backbone for downstream tasks. The uniform 3×3 conv structure makes it easy to extract features at any depth. Common extraction points: relu3_3 (256 channels, 28×28 for 224×224 input) for texture-rich features; relu4_3 (512 channels, 14×14) for semantic object features; relu5_3 (512 channels, 7×7) for the most abstract features.

```python
import torch
import torch.nn as nn
from torchvision import models

class VGGFeatureExtractor(nn.Module):
    '''VGG-16 pretrained backbone with a lightweight classification head.'''
    def __init__(self, num_classes=10, feature_layer=30, freeze=True):
        super().__init__()
        vgg = models.vgg16_bn(weights=models.VGG16_BN_Weights.IMAGENET1K_V1)
        self.backbone = nn.Sequential(*list(vgg.features.children())[:feature_layer])
        if freeze:
            for param in self.backbone.parameters():
                param.requires_grad = False
        self.head = nn.Sequential(
            nn.AdaptiveAvgPool2d((4, 4)), nn.Flatten(),
            nn.Linear(512 * 16, 512), nn.ReLU(inplace=True),
            nn.Dropout(0.5), nn.Linear(512, num_classes))

    def forward(self, x):
        return self.head(self.backbone(x))

model = VGGFeatureExtractor(num_classes=10, freeze=True)
total = sum(p.numel() for p in model.parameters())
trainable = sum(p.numel() for p in model.parameters() if p.requires_grad)
x = torch.randn(4, 3, 224, 224)
out = model(x)
print('Output: {}'.format(out.shape))
print('Trainable: {:,} / Total: {:,} ({:.1f}%)'.format(
    trainable, total, 100 * trainable / total))
```

## Limitations and the Path to ResNet

Both AlexNet and VGG suffer from vanishing gradients when depth increases beyond ~20 layers. Simply stacking more layers degrades training accuracy — not test accuracy, indicating an optimisation problem rather than overfitting. VGG19 already shows diminishing returns over VGG16. This degradation problem led He et al. to hypothesise that learning identity mappings is hard, and to introduce explicit shortcut connections (residuals) in ResNet (2015). ResNet-152 outperforms VGG16 with 25M vs 138M parameters and enables networks hundreds of layers deep. LRN (used in AlexNet) was shown to provide negligible benefit by VGG and was dropped. Batch normalisation (Ioffe & Szegedy, 2015) superseded it as the standard normalisation technique.

## Architecture Comparison

| Model | Year | Depth | Params | GFLOPs | Key Innovation | Top-5 Error |
| --- | --- | --- | --- | --- | --- | --- |
| AlexNet | 2012 | 8 | 60M | 0.7 | ReLU + dropout + GPU | 15.3% |
| VGG-16 | 2014 | 16 | 138M | 15.5 | Uniform 3×3 conv stacking | 7.3% |
| VGG-19 | 2014 | 19 | 144M | 19.6 | Deeper uniform 3×3 stacks | 7.1% |
| GoogLeNet | 2014 | 22 | 5M | 1.5 | Inception parallel branches | 6.7% |
| ResNet-50 | 2015 | 50 | 25M | 4.1 | Residual skip connections | 5.3% |

---

