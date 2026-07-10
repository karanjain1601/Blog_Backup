---
title: "StyleGAN: Disentangled Style Injection and AdaIN"
slug: "stylegan-style-injection"
description: ""
tags: ["stylegan", "generative-models", "adain", "disentanglement", "computer-vision"]
topic: ""
status: ""
updated: ""
blocks_json: "[{"type":"h2","content":"Overview"},{"type":"text","content":"StyleGAN, introduced by Karras et al. at NVIDIA, restructures the traditional GAN generator by separating style from content. Rather than feeding noise z directly to the generator, it first maps z through a learned mapping network to an intermediate latent w, which then injects style at each resolution level via Adaptive Instance Normalization."},{"type":"text","content":"This architecture yields a highly disentangled latent space where different style scales—coarse (pose, face shape), medium (facial features), and fine (color, texture)—are controlled independently. StyleGAN set a new FID record on FFHQ-1024 and remains foundational for controllable image generation research."},{"type":"h2","content":"Mapping Network"},{"type":"text","content":"The mapping network is an 8-layer MLP that transforms the initial noise z ∈ R^512 into an intermediate latent w ∈ R^512. Each layer applies a linear transformation followed by a LeakyReLU. The network learns to \u0027unentangle\u0027 the latent factors so that w-space has better disentanglement properties than z-space."},{"type":"code","lang":"python","content":"import torch.nn as nn\n\nclass MappingNetwork(nn.Module):\n    def __init__(self, z_dim=512, w_dim=512, n_layers=8):\n        super().__init__()\n        layers = []\n        for i in range(n_layers):\n            in_d  = z_dim if i == 0 else w_dim\n            layers += [nn.Linear(in_d, w_dim), nn.LeakyReLU(0.2)]\n        self.net = nn.Sequential(*layers)\n        self.n_style_blocks = 18   # log2(1024) * 2\n    def forward(self, z):\n        w = self.net(z)            # (B, w_dim)\n        return w.unsqueeze(1).repeat(1, self.n_style_blocks, 1)"},{"type":"text","content":"The w vector is repeated (or broadcast) to produce one style vector per synthesis block. In StyleGAN2, mixing regularization is applied: during training, two different w vectors are sometimes used—one for coarse layers and one for fine layers—encouraging the network to keep style scales separate."},{"type":"h2","content":"AdaIN Style Injection"},{"type":"text","content":"Adaptive Instance Normalization (AdaIN) is the mechanism by which style w controls each synthesis layer. The feature map is first normalized to zero mean and unit variance per channel, then rescaled and shifted by learned affine parameters derived from w. This allows w to set the \u0027style\u0027 of each layer independently."},{"type":"code","lang":"python","content":"import torch\nimport torch.nn as nn\n\nclass AdaIN(nn.Module):\n    def __init__(self, w_dim, channels):\n        super().__init__()\n        self.style_linear = nn.Linear(w_dim, channels * 2)\n    def forward(self, x, w):\n        # x: (B, C, H, W)  w: (B, w_dim)\n        y  = self.style_linear(w)          # (B, 2C)\n        y_s, y_b = y.chunk(2, dim=1)      # each (B, C)\n        y_s = y_s.unsqueeze(-1).unsqueeze(-1)\n        y_b = y_b.unsqueeze(-1).unsqueeze(-1)\n        mean = x.mean(dim=[2, 3], keepdim=True)\n        std  = x.std(dim=[2, 3], keepdim=True) + 1e-8\n        x_norm = (x - mean) / std\n        return y_s * x_norm + y_b"},{"type":"text","content":"Because AdaIN normalizes the content of each feature map before applying style, the generator\u0027s learned constant (a fixed 4x4 learned tensor) carries spatial structure while w carries only style information. This clean separation is what gives StyleGAN its superior disentanglement compared to earlier architectures."},{"type":"h2","content":"Stochastic Noise"},{"type":"text","content":"StyleGAN adds per-pixel stochastic noise to each synthesis layer, distinct from the latent z. This noise captures fine-grained stochastic variation—hair strand placement, skin pore detail, background texture—that does not need to be globally consistent. The noise is scaled by a learned per-channel scalar before being added to the feature map."},{"type":"code","lang":"python","content":"import torch\nimport torch.nn as nn\n\nclass NoiseInjection(nn.Module):\n    def __init__(self, channels):\n        super().__init__()\n        self.weight = nn.Parameter(torch.zeros(1, channels, 1, 1))\n    def forward(self, x, noise=None):\n        if noise is None:\n            B, C, H, W = x.shape\n            noise = torch.randn(B, 1, H, W, device=x.device)\n        return x + self.weight * noise"},{"type":"text","content":"To generate a new stochastic variant of the same face (same identity, same pose, different hair wisps), hold w constant but resample the noise tensors injected at each layer. This separates high-level semantic control (w) from low-level stochastic texture (noise), a design that strongly influenced subsequent architectures."},{"type":"h2","content":"Progressive Growing vs MSG"},{"type":"text","content":"StyleGAN v1 used progressive growing (ProGAN): training starts at 4x4 and new layers are faded in as resolution doubles. While effective, this caused texture-structure artifacts. StyleGAN2 replaced progressive growing with multi-scale gradients (MSG) and path-length regularization, achieving better global consistency and significantly lower FID."},{"type":"code","lang":"python","content":"import torch\n\ndef truncation_trick(w, w_bar, psi=0.7):\n    \"\"\"Apply truncation to w vectors for quality/diversity tradeoff.\n    w    : (B, n_blocks, w_dim) — sampled intermediate latents\n    w_bar: (1, n_blocks, w_dim) — EMA of w over training (mean face)\n    psi  : truncation strength in [0.5, 0.9]; lower = higher quality\n    \"\"\"\n    return w_bar + psi * (w - w_bar)\n\n# Update w_bar during training with EMA\n# w_bar = 0.995 * w_bar + 0.005 * w.mean(0, keepdim=True)"},{"type":"table","headers":["Version","Max Resolution","FID (FFHQ)","Key Innovation"],"rows":[["StyleGAN v1","1024x1024","4.40","Mapping network + AdaIN + stochastic noise"],["StyleGAN2","1024x1024","2.84","Weight demodulation, no prog. growing, path-length reg"],["StyleGAN3","1024x1024","2.79","Alias-free synthesis, equivariant to translation/rotation"],["StyleGAN-XL","1024x1024","2.30","Class-conditional, projected discriminator, multi-scale"]]},{"type":"callout","variant":"info","content":"The w-space (intermediate latent) is more disentangled than z-space because the mapping network learns to spread styles. Editing in w-space (e.g. age, expression) produces cleaner semantic changes than editing z directly."},{"type":"h2","content":"Key Takeaways"},{"type":"text","content":"StyleGAN\u0027s mapping network + AdaIN design cleanly separates identity (w) from stochastic texture (noise), enabling precise semantic editing in w-space. This has made StyleGAN the default backbone for GAN-based face editing, inversion, and interpolation research."},{"type":"text","content":"StyleGAN2 is the practical workhorse: weight demodulation fixes water-droplet artifacts from AdaIN, and removing progressive growing simplifies training. StyleGAN3 further eliminates texture sticking by ensuring the synthesis network is equivariant to subpixel translation."},{"type":"text","content":"For production use, prefer StyleGAN2-ADA (adaptive discriminator augmentation), which achieves strong performance with as few as 1,000 training images by augmenting discriminator inputs in a way that does not leak augmentation into generated samples."}]"
---
# StyleGAN: Disentangled Style Injection and AdaIN

StyleGAN, introduced by Karras et al. at NVIDIA, restructures the traditional GAN generator by separating style from content. Rather than feeding noise z directly to the generator, it first maps z through a learned mapping network to an intermediate latent w, which then injects style at each resolution level via Adaptive Instance Normalization.

This architecture yields a highly disentangled latent space where different style scales—coarse (pose, face shape), medium (facial features), and fine (color, texture)—are controlled independently. StyleGAN set a new FID record on FFHQ-1024 and remains foundational for controllable image generation research.

The mapping network is an 8-layer MLP that transforms the initial noise z ∈ R^512 into an intermediate latent w ∈ R^512. Each layer applies a linear transformation followed by a LeakyReLU. The network learns to 'unentangle' the latent factors so that w-space has better disentanglement properties than z-space.

```
import torch.nn as nn

class MappingNetwork(nn.Module):
    def __init__(self, z_dim=512, w_dim=512, n_layers=8):
        super().__init__()
        layers = []
        for i in range(n_layers):
            in_d  = z_dim if i == 0 else w_dim
            layers += [nn.Linear(in_d, w_dim), nn.LeakyReLU(0.2)]
        self.net = nn.Sequential(*layers)
        self.n_style_blocks = 18   # log2(1024) * 2
    def forward(self, z):
        w = self.net(z)            # (B, w_dim)
        return w.unsqueeze(1).repeat(1, self.n_style_blocks, 1)
```

The w vector is repeated (or broadcast) to produce one style vector per synthesis block. In StyleGAN2, mixing regularization is applied: during training, two different w vectors are sometimes used—one for coarse layers and one for fine layers—encouraging the network to keep style scales separate.

Adaptive Instance Normalization (AdaIN) is the mechanism by which style w controls each synthesis layer. The feature map is first normalized to zero mean and unit variance per channel, then rescaled and shifted by learned affine parameters derived from w. This allows w to set the 'style' of each layer independently.

```
import torch
import torch.nn as nn

class AdaIN(nn.Module):
    def __init__(self, w_dim, channels):
        super().__init__()
        self.style_linear = nn.Linear(w_dim, channels * 2)
    def forward(self, x, w):
        # x: (B, C, H, W)  w: (B, w_dim)
        y  = self.style_linear(w)          # (B, 2C)
        y_s, y_b = y.chunk(2, dim=1)      # each (B, C)
        y_s = y_s.unsqueeze(-1).unsqueeze(-1)
        y_b = y_b.unsqueeze(-1).unsqueeze(-1)
        mean = x.mean(dim=[2, 3], keepdim=True)
        std  = x.std(dim=[2, 3], keepdim=True) + 1e-8
        x_norm = (x - mean) / std
        return y_s * x_norm + y_b
```

Because AdaIN normalizes the content of each feature map before applying style, the generator's learned constant (a fixed 4x4 learned tensor) carries spatial structure while w carries only style information. This clean separation is what gives StyleGAN its superior disentanglement compared to earlier architectures.

StyleGAN adds per-pixel stochastic noise to each synthesis layer, distinct from the latent z. This noise captures fine-grained stochastic variation—hair strand placement, skin pore detail, background texture—that does not need to be globally consistent. The noise is scaled by a learned per-channel scalar before being added to the feature map.

```
import torch
import torch.nn as nn

class NoiseInjection(nn.Module):
    def __init__(self, channels):
        super().__init__()
        self.weight = nn.Parameter(torch.zeros(1, channels, 1, 1))
    def forward(self, x, noise=None):
        if noise is None:
            B, C, H, W = x.shape
            noise = torch.randn(B, 1, H, W, device=x.device)
        return x + self.weight * noise
```

To generate a new stochastic variant of the same face (same identity, same pose, different hair wisps), hold w constant but resample the noise tensors injected at each layer. This separates high-level semantic control (w) from low-level stochastic texture (noise), a design that strongly influenced subsequent architectures.

StyleGAN v1 used progressive growing (ProGAN): training starts at 4x4 and new layers are faded in as resolution doubles. While effective, this caused texture-structure artifacts. StyleGAN2 replaced progressive growing with multi-scale gradients (MSG) and path-length regularization, achieving better global consistency and significantly lower FID.

```
import torch

def truncation_trick(w, w_bar, psi=0.7):
    """Apply truncation to w vectors for quality/diversity tradeoff.
    w    : (B, n_blocks, w_dim) — sampled intermediate latents
    w_bar: (1, n_blocks, w_dim) — EMA of w over training (mean face)
    psi  : truncation strength in [0.5, 0.9]; lower = higher quality
    """
    return w_bar + psi * (w - w_bar)

# Update w_bar during training with EMA
# w_bar = 0.995 * w_bar + 0.005 * w.mean(0, keepdim=True)
```

| Version | Max Resolution | FID (FFHQ) | Key Innovation |
| --- | --- | --- | --- |
| StyleGAN v1 | 1024x1024 | 4.40 | Mapping network + AdaIN + stochastic noise |
| StyleGAN2 | 1024x1024 | 2.84 | Weight demodulation, no prog. growing, path-length reg |
| StyleGAN3 | 1024x1024 | 2.79 | Alias-free synthesis, equivariant to translation/rotation |
| StyleGAN-XL | 1024x1024 | 2.30 | Class-conditional, projected discriminator, multi-scale |

> **info**: The w-space (intermediate latent) is more disentangled than z-space because the mapping network learns to spread styles. Editing in w-space (e.g. age, expression) produces cleaner semantic changes than editing z directly.

StyleGAN's mapping network + AdaIN design cleanly separates identity (w) from stochastic texture (noise), enabling precise semantic editing in w-space. This has made StyleGAN the default backbone for GAN-based face editing, inversion, and interpolation research.

StyleGAN2 is the practical workhorse: weight demodulation fixes water-droplet artifacts from AdaIN, and removing progressive growing simplifies training. StyleGAN3 further eliminates texture sticking by ensuring the synthesis network is equivariant to subpixel translation.

For production use, prefer StyleGAN2-ADA (adaptive discriminator augmentation), which achieves strong performance with as few as 1,000 training images by augmenting discriminator inputs in a way that does not leak augmentation into generated samples.

