---
title: "StyleGAN — Style-Based Generator and Adaptive Instance Norm"
slug: "stylegan"
description: "StyleGAN (Karras 2019) introduces a mapping network that disentangles the latent space, style injection via AdaIN at each resolution block, and per-pixel stochastic noise, enabling unprecedented control over coarse pose/shape and fine texture/colour attributes in high-resolution face synthesis."
tags: ["deep-learning", "generative-models", "gans"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"StyleGAN (Karras et al. 2019, NVIDIA) fundamentally rethinks the generator architecture of GANs. Rather than feeding a latent vector z directly into a convolutional stack, StyleGAN separates two concerns: a mapping network transforms z into an intermediate latent w, and w is then injected into every layer of a synthesis network via Adaptive Instance Normalisation (AdaIN). This separation disentangles the latent space — in W space, individual dimensions control semantically coherent attributes (pose, age, hair colour) without the entangled correlations seen in Z space. The result is a generator that supports intuitive style mixing, stochastic fine-detail control, and state-of-the-art image quality at 1024x1024 resolution."},{"type":"heading","level":2,"content":"Mapping Network: Z Space to W Space"},{"type":"text","content":"The mapping network f: Z → W is an 8-layer fully-connected MLP with LeakyReLU activations. The input z ~ N(0, I) is first pixel-normalised, then transformed into w ∈ R^512. The key insight is that Z is constrained to follow a standard Gaussian prior, which forces the generator to warp and entangle attributes to fit this fixed distribution. W has no such fixed prior — it is learned and can take whatever shape best represents the data manifold. This is why W is more disentangled: directions in W correspond more cleanly to individual semantic attributes. The disentanglement is measured by the Perceptual Path Length (PPL) metric — shorter, smoother paths through W space indicate better disentanglement."},{"type":"list","ordered":false,"items":["Z space entanglement: changing one dimension of z affects multiple attributes simultaneously because the prior is fixed Gaussian.","W space disentanglement: W is learned, so its geometry can match the true data manifold — one direction ≈ one attribute.","Truncation trick: sample w from a truncated distribution (||w - w_avg|| \u003c psi) to trade diversity for quality; psi=0.7 is typical.","Style transfer: given two images, invert to w1 and w2, then use w1 for coarse layers and w2 for fine layers to transfer fine-grained texture.","PPL measures the average perceptual change per unit step in W — lower PPL means W is more linearly organised with respect to perception."]},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass MappingNetwork(nn.Module):\n    \"\"\"StyleGAN mapping network: z -\u003e w via 8-layer MLP with LeakyReLU.\n\n    Input z is pixel-normalised before mapping.\n    Output w is the disentangled intermediate latent used for style injection.\n    \"\"\"\n    def __init__(self, z_dim=512, w_dim=512, n_layers=8, lr_mul=0.01):\n        super().__init__()\n        layers = []\n        for i in range(n_layers):\n            in_dim  = z_dim if i == 0 else w_dim\n            linear  = nn.Linear(in_dim, w_dim)\n            # Learning rate multiplier: scale weights down, scale gradients up\n            nn.init.normal_(linear.weight, std=1.0 / lr_mul)\n            nn.init.zeros_(linear.bias)\n            layers += [linear, nn.LeakyReLU(0.2)]\n        self.net = nn.Sequential(*layers)\n        self.lr_mul = lr_mul\n\n    def pixel_norm(self, z):\n        return z / (z.pow(2).mean(dim=1, keepdim=True).sqrt() + 1e-8)\n\n    def forward(self, z):\n        z = self.pixel_norm(z)\n        w = self.net(z) * self.lr_mul\n        return w\n\ntorch.manual_seed(0)\nmapping = MappingNetwork(z_dim=512, w_dim=512, n_layers=8)\nz = torch.randn(4, 512)\nw = mapping(z)\nprint(f\u0027z shape: {z.shape} -\u003e w shape: {w.shape}\u0027)  # (4, 512) -\u003e (4, 512)\nprint(f\u0027w mean: {w.mean():.4f}  std: {w.std():.4f}\u0027)"},{"type":"heading","level":2,"content":"Adaptive Instance Normalisation"},{"type":"text","content":"Style injection in StyleGAN uses Adaptive Instance Normalisation (AdaIN). At each convolutional layer in the synthesis network, the feature map x is first instance-normalised (zero mean, unit variance per spatial map per channel), then rescaled and shifted by style parameters derived from w: AdaIN(x, y) = y_s · (x - μ(x)) / σ(x) + y_b, where (y_s, y_b) = A(w) is an affine transform of the w vector (a learned linear layer). Each resolution block uses its own affine layer, so the style parameters differ at every level. This is fundamentally different from conditioning via concatenation — AdaIN injects style by controlling the statistical moments of each feature map, a much more expressive form of conditioning."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass AdaIN(nn.Module):\n    \"\"\"Adaptive Instance Normalisation: normalise x, then scale+shift from w.\n\n    AdaIN(x, w) = y_s * (x - mean(x)) / std(x) + y_b\n    where (y_s, y_b) = affine(w), each with shape (B, C).\n    Instance norm is per-sample per-channel over spatial dims.\n    \"\"\"\n    def __init__(self, n_channels, w_dim=512):\n        super().__init__()\n        self.instance_norm = nn.InstanceNorm2d(n_channels, affine=False)\n        # Affine projection: w -\u003e (scale, bias) per channel\n        self.affine = nn.Linear(w_dim, n_channels * 2)\n        nn.init.ones_(self.affine.weight[:n_channels])   # init scale to 1\n        nn.init.zeros_(self.affine.weight[n_channels:])  # init bias to 0\n        nn.init.zeros_(self.affine.bias)\n\n    def forward(self, x, w):\n        # x: (B, C, H, W), w: (B, w_dim)\n        style = self.affine(w)                     # (B, 2*C)\n        y_s, y_b = style.chunk(2, dim=1)           # each (B, C)\n        y_s = y_s.unsqueeze(-1).unsqueeze(-1)      # (B, C, 1, 1)\n        y_b = y_b.unsqueeze(-1).unsqueeze(-1)      # (B, C, 1, 1)\n        x_norm = self.instance_norm(x)             # zero mean, unit var per (B, C, H, W)\n        return y_s * x_norm + y_b                  # style-conditioned features\n\ntorch.manual_seed(0)\nadain = AdaIN(n_channels=256, w_dim=512)\nx = torch.randn(2, 256, 16, 16)  # feature map at 16x16 resolution\nw = torch.randn(2, 512)           # w vector from mapping network\nout = adain(x, w)\nprint(f\u0027AdaIN input:  mean={x.mean():.4f}  std={x.std():.4f}\u0027)\nprint(f\u0027AdaIN output: mean={out.mean():.4f}  std={out.std():.4f}\u0027)\nprint(f\u0027Output shape: {out.shape}\u0027)  # (2, 256, 16, 16)"},{"type":"heading","level":2,"content":"Stochastic Noise Injection"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass NoiseInjection(nn.Module):\n    \"\"\"Per-pixel Gaussian noise with learnable per-channel amplitude B.\n\n    x_out = x + B * noise  where noise ~ N(0, I) sampled fresh each forward pass.\n    B is a learnable scalar per channel, initialised to zero (no noise at start).\n    Captures stochastic variation: hair strand placement, freckles, pore detail.\n    This variation is NOT encoded in w — it is independent per image generation.\n    \"\"\"\n    def __init__(self, n_channels):\n        super().__init__()\n        self.B = nn.Parameter(torch.zeros(1, n_channels, 1, 1))\n\n    def forward(self, x, noise=None):\n        B_val, C, H, W = x.shape\n        if noise is None:\n            noise = torch.randn(B_val, 1, H, W, device=x.device)\n        return x + self.B * noise\n\nclass StyleConvBlock(nn.Module):\n    \"\"\"One StyleGAN synthesis block: Conv -\u003e NoiseInjection -\u003e AdaIN -\u003e Activation.\"\"\"\n    def __init__(self, in_ch, out_ch, w_dim=512):\n        super().__init__()\n        self.conv  = nn.Conv2d(in_ch, out_ch, 3, padding=1)\n        self.noise = NoiseInjection(out_ch)\n        self.adain = AdaIN(out_ch, w_dim)\n        self.act   = nn.LeakyReLU(0.2)\n\n    def forward(self, x, w, noise=None):\n        x = self.conv(x)\n        x = self.noise(x, noise)\n        x = self.adain(x, w)\n        return self.act(x)\n\ntorch.manual_seed(0)\nblock = StyleConvBlock(in_ch=256, out_ch=256, w_dim=512)\nx = torch.randn(2, 256, 16, 16)\nw = torch.randn(2, 512)\nout1 = block(x, w)\nout2 = block(x, w)  # different noise each call\nprint(f\u0027Output shape: {out1.shape}\u0027)\nprint(f\u0027Max diff between two runs (different noise): {(out1 - out2).abs().max():.4f}\u0027)"},{"type":"heading","level":2,"content":"Style Mixing and Coarse vs Fine Control"},{"type":"text","content":"StyleGAN\u0027s synthesis network maps resolution to semantic content: coarse layers (4-16px) control high-level attributes like pose, face shape, and hair style; fine layers (64-1024px) control colour palette, skin texture, and microstructure details. Style mixing exploits this by sampling two independent w vectors and using w₁ for coarse layers and w₂ for fine layers. The result is an image that has the pose and shape of w₁ but the colour and texture of w₂. This is also used as a regularisation technique during training: with probability 0.9, a random mixing point is chosen so the generator cannot use feature correlations across layers to cheat the Lipschitz constraint."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom typing import List\n\nclass StyleGANSynthesisNetwork(nn.Module):\n    \"\"\"Simplified StyleGAN synthesis network with style-mixing support.\n\n    Coarse resolutions (4-16px):  pose, face shape, hair style.\n    Fine   resolutions (32-1024px): colour palette, microstructure, textures.\n    Style mixing: use w1 for coarse layers, w2 for fine layers.\n    \"\"\"\n    RESOLUTIONS = [4, 8, 16, 32, 64]\n\n    def __init__(self, w_dim=512, channels=None):\n        super().__init__()\n        if channels is None:\n            channels = {4: 512, 8: 512, 16: 256, 32: 128, 64: 64}\n        self.const = nn.Parameter(torch.randn(1, channels[4], 4, 4))\n        self.blocks = nn.ModuleDict()\n        prev_ch = channels[4]\n        for res in self.RESOLUTIONS:\n            ch = channels[res]\n            self.blocks[f\u0027conv_{res}a\u0027] = StyleConvBlock(prev_ch, ch, w_dim)\n            self.blocks[f\u0027conv_{res}b\u0027] = StyleConvBlock(ch, ch, w_dim)\n            prev_ch = ch\n        self.to_rgb = nn.Conv2d(channels[64], 3, 1)\n\n    def forward(self, ws: List[torch.Tensor], mixing_cutoff: int = None):\n        \"\"\"ws: list of w vectors. If mixing_cutoff set, ws[0] for coarse, ws[1] for fine.\"\"\"\n        B = ws[0].size(0)\n        x = self.const.expand(B, -1, -1, -1)\n        layer_idx = 0\n        for i, res in enumerate(self.RESOLUTIONS):\n            w = ws[0] if (mixing_cutoff is None or layer_idx \u003c mixing_cutoff) else ws[1]\n            if res \u003e 4:\n                x = nn.functional.interpolate(x, scale_factor=2, mode=\u0027bilinear\u0027, align_corners=False)\n            x = self.blocks[f\u0027conv_{res}a\u0027](x, w)\n            x = self.blocks[f\u0027conv_{res}b\u0027](x, w)\n            layer_idx += 2\n        return self.to_rgb(x)\n\ntorch.manual_seed(0)\nnet = StyleGANSynthesisNetwork()\nw1 = torch.randn(2, 512)  # coarse style: controls pose, shape\nw2 = torch.randn(2, 512)  # fine style:   controls colour, texture\nimg_w1  = net([w1])\nprint(f\u0027Single style output: {img_w1.shape}\u0027)  # (2, 3, 64, 64)\nimg_mix = net([w1, w2], mixing_cutoff=4)\nprint(f\u0027Mixed style output:  {img_mix.shape}\u0027)"},{"type":"heading","level":2,"content":"StyleGAN2 Improvements"},{"type":"text","content":"StyleGAN2 (Karras et al. 2020) addressed two main artifacts from StyleGAN1. First, \u0027water droplet\u0027 artifacts appearing at fixed pixel positions were traced to AdaIN: instance normalisation allows the generator to hide information in feature map statistics rather than spatial content. StyleGAN2 replaces AdaIN with weight demodulation — instead of normalising the feature map, it normalises the convolution weights based on the expected unit-standard-deviation input, eliminating the artifact while preserving style injection. Second, progressive growing introduced phase artifacts at resolution boundaries. StyleGAN2 trains at full resolution from the start using skip connections to a series of RGB outputs that are summed during training."},{"type":"list","ordered":false,"items":["Weight demodulation: scale conv weights by w-derived style (modulation), then divide each output by the expected std (demodulation) — avoids operating on feature statistics.","No progressive growing: StyleGAN2 trains at full resolution with MSG-style skip connections — simpler and avoids phase-transition artifacts.","Path length regularisation (lazy, every 16 steps): encourage ||J^T a|| to be constant for random a ~ N(0,I), smoothing the W-space geometry.","R1 gradient penalty replaces WGAN-GP: simpler, compatible with BatchNorm in generator, standard for all GAN stabilisation.","FID improvement: FFHQ 1024px FID drops from 4.40 (StyleGAN) to 2.84 (StyleGAN2) with the same training data."]},{"type":"callout","variant":"tip","title":"W+ Space for GAN Inversion","content":"StyleGAN\u0027s W space has a single w vector broadcast to all layers. W+ space extends this to a separate w_i per layer (18 vectors for StyleGAN at 1024px), giving more degrees of freedom for GAN inversion — encoding a real photo back into a latent. W+ is used by e4e and PTI encoders. Edits in W space generalise better (same direction for all layers); edits in W+ allow layer-specific adjustments but are less semantically coherent. For attribute editing (age, smile), work in W; for faithful reconstruction of specific identities, use W+."},{"type":"heading","level":2,"content":"Progressive Growing and Training Stability"},{"type":"text","content":"Both StyleGAN and its predecessor ProgressiveGAN (Karras et al. 2018) grow the generator and discriminator resolution incrementally — starting at 4x4 and doubling every few hundred kimg until reaching the target resolution. New layers are faded in with a linear alpha blending schedule to avoid sudden capacity jumps. This technique dramatically reduces training time for high-resolution synthesis (1024x1024) because most training iterations are spent at lower resolutions where compute is cheap. StyleGAN1 inherited progressive growing directly; StyleGAN2 abandoned it in favour of skip-connection architectures that train at full resolution from the start, trading simplicity for the elimination of phase artifacts."},{"type":"heading","level":2,"content":"Architecture Comparison"},{"type":"table","headers":["Model","Key Innovation","FID at 1024px","Artifacts","Training Cost"],"rows":[["DCGAN","Deep conv generator/discriminator, BN, no FC layers","~35 (256px)","Checkerboard (transpose conv), mode collapse","Low — hours on 1 GPU"],["ProgressiveGAN","Grow resolution 4-\u003e1024 progressively, fade-in layers","8.04","Phase transition artifacts at resolution boundaries","High — days on 8 GPUs"],["StyleGAN","Mapping net + AdaIN style injection + noise + prog grow","4.40","Water droplet artifacts (AdaIN statistics), phase artifacts","Very high — weeks on 8 GPUs"],["StyleGAN2","Weight demodulation, no progressive grow, path length reg, R1","2.84","Significantly reduced — no droplets, no phase artifacts","Very high — weeks on 8 GPUs"]]},{"type":"list","ordered":false,"items":["The mapping network uses lr_mul=0.01 — the learning rate multiplier scales weights down at init and gradients up during optimisation, stabilising the MLP training.","Each resolution block in the synthesis network has its own affine layer A(w), giving 18 independent style vectors at 1024px resolution (2 per resolution from 4px to 1024px).","Stochastic noise amplitude B is initialised to zero, so noise has no effect at training start — it is learned gradually as the generator refines fine details.","Style mixing regularisation: during training, some samples use two different w vectors (coarse/fine split at a random layer) to prevent cross-layer dependencies.","StyleGAN2 weight demodulation is implemented as a fused layer that combines modulation, convolution, and demodulation in a single efficient CUDA kernel.","PPL (Perceptual Path Length) measures W-space disentanglement: lower PPL means traversals between w vectors produce smoother, more predictable image changes."]},{"type":"divider"}]"
---
# StyleGAN — Style-Based Generator and Adaptive Instance Norm

StyleGAN (Karras et al. 2019, NVIDIA) fundamentally rethinks the generator architecture of GANs. Rather than feeding a latent vector z directly into a convolutional stack, StyleGAN separates two concerns: a mapping network transforms z into an intermediate latent w, and w is then injected into every layer of a synthesis network via Adaptive Instance Normalisation (AdaIN). This separation disentangles the latent space — in W space, individual dimensions control semantically coherent attributes (pose, age, hair colour) without the entangled correlations seen in Z space. The result is a generator that supports intuitive style mixing, stochastic fine-detail control, and state-of-the-art image quality at 1024x1024 resolution.

## Mapping Network: Z Space to W Space

The mapping network f: Z → W is an 8-layer fully-connected MLP with LeakyReLU activations. The input z ~ N(0, I) is first pixel-normalised, then transformed into w ∈ R^512. The key insight is that Z is constrained to follow a standard Gaussian prior, which forces the generator to warp and entangle attributes to fit this fixed distribution. W has no such fixed prior — it is learned and can take whatever shape best represents the data manifold. This is why W is more disentangled: directions in W correspond more cleanly to individual semantic attributes. The disentanglement is measured by the Perceptual Path Length (PPL) metric — shorter, smoother paths through W space indicate better disentanglement.

- Z space entanglement: changing one dimension of z affects multiple attributes simultaneously because the prior is fixed Gaussian.
- W space disentanglement: W is learned, so its geometry can match the true data manifold — one direction ≈ one attribute.
- Truncation trick: sample w from a truncated distribution (||w - w_avg|| < psi) to trade diversity for quality; psi=0.7 is typical.
- Style transfer: given two images, invert to w1 and w2, then use w1 for coarse layers and w2 for fine layers to transfer fine-grained texture.
- PPL measures the average perceptual change per unit step in W — lower PPL means W is more linearly organised with respect to perception.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class MappingNetwork(nn.Module):
    """StyleGAN mapping network: z -> w via 8-layer MLP with LeakyReLU.

    Input z is pixel-normalised before mapping.
    Output w is the disentangled intermediate latent used for style injection.
    """
    def __init__(self, z_dim=512, w_dim=512, n_layers=8, lr_mul=0.01):
        super().__init__()
        layers = []
        for i in range(n_layers):
            in_dim  = z_dim if i == 0 else w_dim
            linear  = nn.Linear(in_dim, w_dim)
            # Learning rate multiplier: scale weights down, scale gradients up
            nn.init.normal_(linear.weight, std=1.0 / lr_mul)
            nn.init.zeros_(linear.bias)
            layers += [linear, nn.LeakyReLU(0.2)]
        self.net = nn.Sequential(*layers)
        self.lr_mul = lr_mul

    def pixel_norm(self, z):
        return z / (z.pow(2).mean(dim=1, keepdim=True).sqrt() + 1e-8)

    def forward(self, z):
        z = self.pixel_norm(z)
        w = self.net(z) * self.lr_mul
        return w

torch.manual_seed(0)
mapping = MappingNetwork(z_dim=512, w_dim=512, n_layers=8)
z = torch.randn(4, 512)
w = mapping(z)
print(f'z shape: {z.shape} -> w shape: {w.shape}')  # (4, 512) -> (4, 512)
print(f'w mean: {w.mean():.4f}  std: {w.std():.4f}')
```

## Adaptive Instance Normalisation

Style injection in StyleGAN uses Adaptive Instance Normalisation (AdaIN). At each convolutional layer in the synthesis network, the feature map x is first instance-normalised (zero mean, unit variance per spatial map per channel), then rescaled and shifted by style parameters derived from w: AdaIN(x, y) = y_s · (x - μ(x)) / σ(x) + y_b, where (y_s, y_b) = A(w) is an affine transform of the w vector (a learned linear layer). Each resolution block uses its own affine layer, so the style parameters differ at every level. This is fundamentally different from conditioning via concatenation — AdaIN injects style by controlling the statistical moments of each feature map, a much more expressive form of conditioning.

```python
import torch
import torch.nn as nn

class AdaIN(nn.Module):
    """Adaptive Instance Normalisation: normalise x, then scale+shift from w.

    AdaIN(x, w) = y_s * (x - mean(x)) / std(x) + y_b
    where (y_s, y_b) = affine(w), each with shape (B, C).
    Instance norm is per-sample per-channel over spatial dims.
    """
    def __init__(self, n_channels, w_dim=512):
        super().__init__()
        self.instance_norm = nn.InstanceNorm2d(n_channels, affine=False)
        # Affine projection: w -> (scale, bias) per channel
        self.affine = nn.Linear(w_dim, n_channels * 2)
        nn.init.ones_(self.affine.weight[:n_channels])   # init scale to 1
        nn.init.zeros_(self.affine.weight[n_channels:])  # init bias to 0
        nn.init.zeros_(self.affine.bias)

    def forward(self, x, w):
        # x: (B, C, H, W), w: (B, w_dim)
        style = self.affine(w)                     # (B, 2*C)
        y_s, y_b = style.chunk(2, dim=1)           # each (B, C)
        y_s = y_s.unsqueeze(-1).unsqueeze(-1)      # (B, C, 1, 1)
        y_b = y_b.unsqueeze(-1).unsqueeze(-1)      # (B, C, 1, 1)
        x_norm = self.instance_norm(x)             # zero mean, unit var per (B, C, H, W)
        return y_s * x_norm + y_b                  # style-conditioned features

torch.manual_seed(0)
adain = AdaIN(n_channels=256, w_dim=512)
x = torch.randn(2, 256, 16, 16)  # feature map at 16x16 resolution
w = torch.randn(2, 512)           # w vector from mapping network
out = adain(x, w)
print(f'AdaIN input:  mean={x.mean():.4f}  std={x.std():.4f}')
print(f'AdaIN output: mean={out.mean():.4f}  std={out.std():.4f}')
print(f'Output shape: {out.shape}')  # (2, 256, 16, 16)
```

## Stochastic Noise Injection

```python
import torch
import torch.nn as nn

class NoiseInjection(nn.Module):
    """Per-pixel Gaussian noise with learnable per-channel amplitude B.

    x_out = x + B * noise  where noise ~ N(0, I) sampled fresh each forward pass.
    B is a learnable scalar per channel, initialised to zero (no noise at start).
    Captures stochastic variation: hair strand placement, freckles, pore detail.
    This variation is NOT encoded in w — it is independent per image generation.
    """
    def __init__(self, n_channels):
        super().__init__()
        self.B = nn.Parameter(torch.zeros(1, n_channels, 1, 1))

    def forward(self, x, noise=None):
        B_val, C, H, W = x.shape
        if noise is None:
            noise = torch.randn(B_val, 1, H, W, device=x.device)
        return x + self.B * noise

class StyleConvBlock(nn.Module):
    """One StyleGAN synthesis block: Conv -> NoiseInjection -> AdaIN -> Activation."""
    def __init__(self, in_ch, out_ch, w_dim=512):
        super().__init__()
        self.conv  = nn.Conv2d(in_ch, out_ch, 3, padding=1)
        self.noise = NoiseInjection(out_ch)
        self.adain = AdaIN(out_ch, w_dim)
        self.act   = nn.LeakyReLU(0.2)

    def forward(self, x, w, noise=None):
        x = self.conv(x)
        x = self.noise(x, noise)
        x = self.adain(x, w)
        return self.act(x)

torch.manual_seed(0)
block = StyleConvBlock(in_ch=256, out_ch=256, w_dim=512)
x = torch.randn(2, 256, 16, 16)
w = torch.randn(2, 512)
out1 = block(x, w)
out2 = block(x, w)  # different noise each call
print(f'Output shape: {out1.shape}')
print(f'Max diff between two runs (different noise): {(out1 - out2).abs().max():.4f}')
```

## Style Mixing and Coarse vs Fine Control

StyleGAN's synthesis network maps resolution to semantic content: coarse layers (4-16px) control high-level attributes like pose, face shape, and hair style; fine layers (64-1024px) control colour palette, skin texture, and microstructure details. Style mixing exploits this by sampling two independent w vectors and using w₁ for coarse layers and w₂ for fine layers. The result is an image that has the pose and shape of w₁ but the colour and texture of w₂. This is also used as a regularisation technique during training: with probability 0.9, a random mixing point is chosen so the generator cannot use feature correlations across layers to cheat the Lipschitz constraint.

```python
import torch
import torch.nn as nn
from typing import List

class StyleGANSynthesisNetwork(nn.Module):
    """Simplified StyleGAN synthesis network with style-mixing support.

    Coarse resolutions (4-16px):  pose, face shape, hair style.
    Fine   resolutions (32-1024px): colour palette, microstructure, textures.
    Style mixing: use w1 for coarse layers, w2 for fine layers.
    """
    RESOLUTIONS = [4, 8, 16, 32, 64]

    def __init__(self, w_dim=512, channels=None):
        super().__init__()
        if channels is None:
            channels = {4: 512, 8: 512, 16: 256, 32: 128, 64: 64}
        self.const = nn.Parameter(torch.randn(1, channels[4], 4, 4))
        self.blocks = nn.ModuleDict()
        prev_ch = channels[4]
        for res in self.RESOLUTIONS:
            ch = channels[res]
            self.blocks[f'conv_{res}a'] = StyleConvBlock(prev_ch, ch, w_dim)
            self.blocks[f'conv_{res}b'] = StyleConvBlock(ch, ch, w_dim)
            prev_ch = ch
        self.to_rgb = nn.Conv2d(channels[64], 3, 1)

    def forward(self, ws: List[torch.Tensor], mixing_cutoff: int = None):
        """ws: list of w vectors. If mixing_cutoff set, ws[0] for coarse, ws[1] for fine."""
        B = ws[0].size(0)
        x = self.const.expand(B, -1, -1, -1)
        layer_idx = 0
        for i, res in enumerate(self.RESOLUTIONS):
            w = ws[0] if (mixing_cutoff is None or layer_idx < mixing_cutoff) else ws[1]
            if res > 4:
                x = nn.functional.interpolate(x, scale_factor=2, mode='bilinear', align_corners=False)
            x = self.blocks[f'conv_{res}a'](x, w)
            x = self.blocks[f'conv_{res}b'](x, w)
            layer_idx += 2
        return self.to_rgb(x)

torch.manual_seed(0)
net = StyleGANSynthesisNetwork()
w1 = torch.randn(2, 512)  # coarse style: controls pose, shape
w2 = torch.randn(2, 512)  # fine style:   controls colour, texture
img_w1  = net([w1])
print(f'Single style output: {img_w1.shape}')  # (2, 3, 64, 64)
img_mix = net([w1, w2], mixing_cutoff=4)
print(f'Mixed style output:  {img_mix.shape}')
```

## StyleGAN2 Improvements

StyleGAN2 (Karras et al. 2020) addressed two main artifacts from StyleGAN1. First, 'water droplet' artifacts appearing at fixed pixel positions were traced to AdaIN: instance normalisation allows the generator to hide information in feature map statistics rather than spatial content. StyleGAN2 replaces AdaIN with weight demodulation — instead of normalising the feature map, it normalises the convolution weights based on the expected unit-standard-deviation input, eliminating the artifact while preserving style injection. Second, progressive growing introduced phase artifacts at resolution boundaries. StyleGAN2 trains at full resolution from the start using skip connections to a series of RGB outputs that are summed during training.

- Weight demodulation: scale conv weights by w-derived style (modulation), then divide each output by the expected std (demodulation) — avoids operating on feature statistics.
- No progressive growing: StyleGAN2 trains at full resolution with MSG-style skip connections — simpler and avoids phase-transition artifacts.
- Path length regularisation (lazy, every 16 steps): encourage ||J^T a|| to be constant for random a ~ N(0,I), smoothing the W-space geometry.
- R1 gradient penalty replaces WGAN-GP: simpler, compatible with BatchNorm in generator, standard for all GAN stabilisation.
- FID improvement: FFHQ 1024px FID drops from 4.40 (StyleGAN) to 2.84 (StyleGAN2) with the same training data.

> **W+ Space for GAN Inversion**: StyleGAN's W space has a single w vector broadcast to all layers. W+ space extends this to a separate w_i per layer (18 vectors for StyleGAN at 1024px), giving more degrees of freedom for GAN inversion — encoding a real photo back into a latent. W+ is used by e4e and PTI encoders. Edits in W space generalise better (same direction for all layers); edits in W+ allow layer-specific adjustments but are less semantically coherent. For attribute editing (age, smile), work in W; for faithful reconstruction of specific identities, use W+.

## Progressive Growing and Training Stability

Both StyleGAN and its predecessor ProgressiveGAN (Karras et al. 2018) grow the generator and discriminator resolution incrementally — starting at 4x4 and doubling every few hundred kimg until reaching the target resolution. New layers are faded in with a linear alpha blending schedule to avoid sudden capacity jumps. This technique dramatically reduces training time for high-resolution synthesis (1024x1024) because most training iterations are spent at lower resolutions where compute is cheap. StyleGAN1 inherited progressive growing directly; StyleGAN2 abandoned it in favour of skip-connection architectures that train at full resolution from the start, trading simplicity for the elimination of phase artifacts.

## Architecture Comparison

| Model | Key Innovation | FID at 1024px | Artifacts | Training Cost |
| --- | --- | --- | --- | --- |
| DCGAN | Deep conv generator/discriminator, BN, no FC layers | ~35 (256px) | Checkerboard (transpose conv), mode collapse | Low — hours on 1 GPU |
| ProgressiveGAN | Grow resolution 4->1024 progressively, fade-in layers | 8.04 | Phase transition artifacts at resolution boundaries | High — days on 8 GPUs |
| StyleGAN | Mapping net + AdaIN style injection + noise + prog grow | 4.40 | Water droplet artifacts (AdaIN statistics), phase artifacts | Very high — weeks on 8 GPUs |
| StyleGAN2 | Weight demodulation, no progressive grow, path length reg, R1 | 2.84 | Significantly reduced — no droplets, no phase artifacts | Very high — weeks on 8 GPUs |

- The mapping network uses lr_mul=0.01 — the learning rate multiplier scales weights down at init and gradients up during optimisation, stabilising the MLP training.
- Each resolution block in the synthesis network has its own affine layer A(w), giving 18 independent style vectors at 1024px resolution (2 per resolution from 4px to 1024px).
- Stochastic noise amplitude B is initialised to zero, so noise has no effect at training start — it is learned gradually as the generator refines fine details.
- Style mixing regularisation: during training, some samples use two different w vectors (coarse/fine split at a random layer) to prevent cross-layer dependencies.
- StyleGAN2 weight demodulation is implemented as a fused layer that combines modulation, convolution, and demodulation in a single efficient CUDA kernel.
- PPL (Perceptual Path Length) measures W-space disentanglement: lower PPL means traversals between w vectors produce smoother, more predictable image changes.

---

