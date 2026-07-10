---
title: "Stable Diffusion Architecture — VAE, U-Net, and CLIP"
slug: "stable-diffusion-architecture"
description: "A detailed walkthrough of Stable Diffusion's three core components — the KL-regularized VAE, the CLIP text encoder, and the time-conditioned U-Net denoiser — covering cross-attention conditioning, timestep embeddings, and ControlNet structural conditioning."
tags: ["deep-learning", "generative-models", "diffusion-models"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Stable Diffusion (Rombach et al. 2022) performs diffusion in a compressed latent space rather than pixel space, reducing computation by roughly 64×. The architecture couples three independently updateable components: a KL-regularized VAE that compresses images to a 4-channel latent grid at 1/8 resolution, a CLIP text encoder that converts prompts to sequence embeddings, and a time-conditioned U-Net that iteratively denoises the latent under text guidance. Understanding how cross-attention wires text into spatial features — and how ControlNet adds structural conditioning — is essential for adapting or extending Stable Diffusion."},{"type":"heading","level":2,"content":"Stable Diffusion Component Overview"},{"type":"text","content":"The inference pipeline flows: encode prompt with CLIP → sample Gaussian noise z_T in latent space → run denoiser U-Net for T steps with text conditioning → decode latent z_0 with VAE decoder. The VAE encoder is used only during training, not inference. CLIP produces per-token embeddings (not a single pooled vector) so that individual tokens can attend to different spatial regions via cross-attention. The U-Net operates entirely at 1/8 pixel resolution, making 512×512 generation feasible on consumer hardware."},{"type":"heading","level":2,"content":"VAE Encoder and Decoder"},{"type":"text","content":"The VAE uses a KL-divergence regularisation term with a small weight (λ=1e-6) to keep the latent distribution close to a standard Gaussian while prioritising reconstruction quality. The encoder E maps H×W×3 images to (H/8)×(W/8)×4 latents: a 512×512 image becomes 64×64×4. The four latent channels provide richer per-location representation than a single channel. At encode time σ≈0, so latents are nearly deterministic. The decoder D uses symmetric residual blocks with self-attention at the bottleneck to upsample 64×64×4 back to 512×512×3."},{"type":"heading","level":2,"content":"CLIP Text Encoder"},{"type":"text","content":"SD 1.x uses OpenAI CLIP ViT-L/14, producing 77×768 sequence embeddings. SD 2.x uses OpenCLIP ViT-H/14 (77×1024). SDXL concatenates embeddings from CLIP-L/14 and OpenCLIP-G/14 to produce 77×2048 conditioning with richer semantics. SD3 and FLUX additionally incorporate T5-XXL for better language understanding. The entire token sequence (not just the pooled CLS embedding) is passed to cross-attention so each text token can influence different spatial positions independently."},{"type":"heading","level":2,"content":"U-Net Denoiser and Cross-Attention"},{"type":"text","content":"The U-Net has three paths: a downsampling encoder (ResBlocks + self-attention at lower resolutions), a bottleneck (self + cross-attention), and an upsampling decoder that receives skip connections from the encoder. Cross-attention injects text: queries Q come from flattened spatial features, keys K and values V come from CLIP embeddings. Each spatial token attends to all 77 text tokens, allowing text to control which region shows which concept. The spatial dimension of the U-Net varies by resolution level — 64×64 at the first level to 8×8 at the bottleneck."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass CrossAttentionBlock(nn.Module):\n    \"\"\"Q from image latent features, K/V from CLIP text embeddings.\"\"\"\n    def __init__(self, dim_q, dim_kv, n_heads=8):\n        super().__init__()\n        self.n_heads = n_heads\n        self.head_dim = dim_q // n_heads\n        self.scale = self.head_dim ** -0.5\n        self.to_q = nn.Linear(dim_q, dim_q, bias=False)\n        self.to_k = nn.Linear(dim_kv, dim_q, bias=False)\n        self.to_v = nn.Linear(dim_kv, dim_q, bias=False)\n        self.proj = nn.Linear(dim_q, dim_q)\n        self.norm_q = nn.LayerNorm(dim_q)\n\n    def forward(self, x, context):\n        B, N, C = x.shape  # N = H*W spatial tokens\n        q = self.to_q(self.norm_q(x)).reshape(B, N, self.n_heads, self.head_dim).transpose(1, 2)\n        k = self.to_k(context).reshape(B, -1, self.n_heads, self.head_dim).transpose(1, 2)\n        v = self.to_v(context).reshape(B, -1, self.n_heads, self.head_dim).transpose(1, 2)\n        attn = torch.softmax(q @ k.transpose(-2, -1) * self.scale, dim=-1)\n        out = (attn @ v).transpose(1, 2).reshape(B, N, C)\n        return x + self.proj(out)\n\nblock = CrossAttentionBlock(dim_q=320, dim_kv=768, n_heads=8)\nx   = torch.randn(2, 64, 320)    # 8x8 spatial tokens, U-Net channels\nctx = torch.randn(2, 77, 768)   # CLIP text embeddings (SD 1.x, 768-dim)\nprint(\u0027Cross-attn output:\u0027, block(x, ctx).shape)  # (2, 64, 320)"},{"type":"heading","level":2,"content":"Timestep Embedding"},{"type":"text","content":"The U-Net must know the current noise level t to denoise appropriately. Timestep t ∈ {0,...,T} is first encoded with sinusoidal embeddings (identical to Transformer positional encodings) then projected through a 2-layer SiLU MLP. The resulting vector conditions each residual block via Adaptive Group Normalization (AdaGN): the timestep MLP predicts per-channel scale α(t) and shift δ(t) that modulate the normalised activations before the convolution, allowing the U-Net to behave differently at every noise level."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport math\n\nclass TimestepEmbedding(nn.Module):\n    \"\"\"Sinusoidal positional encoding -\u003e MLP -\u003e injected into ResBlocks via AdaGN.\"\"\"\n    def __init__(self, dim, out_dim=None):\n        super().__init__()\n        out_dim = out_dim or dim * 4\n        self.dim = dim\n        self.mlp = nn.Sequential(nn.Linear(dim, out_dim), nn.SiLU(), nn.Linear(out_dim, out_dim))\n\n    def forward(self, t):\n        half = self.dim // 2\n        freqs = torch.exp(-math.log(10000) * torch.arange(half, dtype=torch.float32, device=t.device) / half)\n        args = t[:, None].float() * freqs[None]\n        return self.mlp(torch.cat([args.sin(), args.cos()], dim=-1))\n\ndef ada_gn_forward(x, t_emb, norm, time_proj):\n    \"\"\"Apply Adaptive GroupNorm: t_emb -\u003e (scale, shift) modulate norm output.\"\"\"\n    scale, shift = time_proj(t_emb).chunk(2, dim=-1)\n    return norm(x) * (1 + scale[:, :, None, None]) + shift[:, :, None, None]\n\nts = TimestepEmbedding(dim=128, out_dim=512)\nt = torch.randint(0, 1000, (4,))\nt_emb = ts(t)\nprint(f\u0027Timestep {t.tolist()} -\u003e embedding shape: {t_emb.shape}\u0027)  # (4, 512)\n\nnorm = nn.GroupNorm(32, 256)\ntime_proj = nn.Linear(512, 512)  # predicts scale+shift for 256 channels\nx = torch.randn(4, 256, 16, 16)\nx_cond = ada_gn_forward(x, t_emb, norm, time_proj)\nprint(f\u0027After AdaGN: mean={x_cond.mean():.4f} std={x_cond.std():.4f}\u0027)"},{"type":"heading","level":2,"content":"SD Inference Pipeline"},{"type":"code","language":"python","content":"import torch\nfrom diffusers import StableDiffusionPipeline, DDIMScheduler\n\ndef run_sd_inference(prompt, neg_prompt=\u0027\u0027, n_steps=30, guidance_scale=7.5, seed=42):\n    \"\"\"Run SD 1.5: encode prompt -\u003e denoise latent -\u003e decode to image.\"\"\"\n    device = \u0027cuda\u0027 if torch.cuda.is_available() else \u0027cpu\u0027\n    dtype  = torch.float16 if device == \u0027cuda\u0027 else torch.float32\n    pipe = StableDiffusionPipeline.from_pretrained(\n        \u0027runwayml/stable-diffusion-v1-5\u0027,\n        scheduler=DDIMScheduler.from_pretrained(\n            \u0027runwayml/stable-diffusion-v1-5\u0027, subfolder=\u0027scheduler\u0027),\n        torch_dtype=dtype,\n    ).to(device)\n    pipe.safety_checker = None\n    generator = torch.Generator(device=device).manual_seed(seed)\n    with torch.inference_mode():\n        result = pipe(\n            prompt, negative_prompt=neg_prompt,\n            num_inference_steps=n_steps,\n            guidance_scale=guidance_scale,\n            generator=generator, height=512, width=512,\n        )\n    img = result.images[0]\n    print(f\u0027Generated {img.size} with {n_steps} DDIM steps, CFG={guidance_scale}\u0027)\n    return img\n\n# Pipeline stages in order:\nprint(\u00271. CLIP encodes prompt -\u003e 77x768 text embeddings\u0027)\nprint(\u00272. Sample z_T ~ N(0,I) in 64x64x4 latent space\u0027)\nprint(\u00273. U-Net denoises z_T -\u003e z_0 over 30 DDIM steps (CFG doubles each step)\u0027)\nprint(\u00274. VAE decoder maps z_0 (64x64x4) -\u003e image (512x512x3)\u0027)"},{"type":"heading","level":2,"content":"ControlNet Integration"},{"type":"text","content":"ControlNet (Zhang \u0026 Agrawala 2023) adds spatial conditioning — edge maps, depth maps, human pose skeletons — to a frozen SD U-Net without touching the original weights. It copies the U-Net encoder blocks, processes a conditioning image through those copied blocks, and injects the outputs into the original U-Net decoder via learned zero convolutions (1×1 conv initialised to zero weight and bias). Zero initialisation ensures that at training start the ControlNet branch contributes nothing, preserving the base model\u0027s behaviour and enabling stable fine-tuning from the pretrained checkpoint."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom diffusers import StableDiffusionControlNetPipeline, ControlNetModel, UniPCMultistepScheduler\nfrom PIL import Image\n\nclass ZeroConv2d(nn.Module):\n    \"\"\"1x1 conv initialised to zero — ControlNet injection layer.\"\"\"\n    def __init__(self, channels):\n        super().__init__()\n        self.conv = nn.Conv2d(channels, channels, 1)\n        nn.init.zeros_(self.conv.weight)\n        nn.init.zeros_(self.conv.bias)\n    def forward(self, x):\n        return self.conv(x)\n\ndef controlnet_injection(unet_feat, ctrl_feat, zero_conv):\n    \"\"\"Add ControlNet encoder output (after zero conv) to U-Net decoder feature.\"\"\"\n    return unet_feat + zero_conv(ctrl_feat)\n\n# Demonstrate zero conv starts as identity (contributes nothing)\nzc = ZeroConv2d(channels=64)\nx = torch.randn(2, 64, 32, 32)\nprint(f\u0027ZeroConv output max at init: {zc(x).abs().max().item():.6f}\u0027)  # ~0.0\n\n# Conceptual ControlNet pipeline\nprint(\u0027ControlNet pipeline:\u0027)\nprint(\u0027  1. Canny edge detector  -\u003e 512x512 edge map\u0027)\nprint(\u0027  2. Copied U-Net encoder -\u003e intermediate feature maps\u0027)\nprint(\u0027  3. Zero convolutions    -\u003e scale features to zero at init\u0027)\nprint(\u0027  4. Add to U-Net decoder -\u003e structural constraint on generation\u0027)"},{"type":"callout","variant":"tip","title":"Choosing the Right SD Version","content":"For general text-to-image with 8-16 GB VRAM: SD 1.5 runs at 512×512, supports the widest LoRA/ControlNet ecosystem, and fine-tunes in hours. SDXL gives best 1024×1024 quality with a two-stage refiner but needs 16+ GB. SD3 and FLUX have superior prompt adherence for complex scenes but require 24+ GB for full quality. Always match your LoRA or ControlNet adapter to the exact base model version."},{"type":"table","headers":["Version","Text Encoder","Latent Channels","Backbone Size","Default Resolution","Key Improvement"],"rows":[["SD 1.x","CLIP ViT-L/14 (768-dim, 77 tok)","4","860M U-Net","512×512","Foundation latent diffusion model"],["SD 2.x","OpenCLIP ViT-H (1024-dim)","4","865M U-Net","768×768","Better NSFW filtering, depth model, v-prediction"],["SDXL","CLIP-L + OpenCLIP-G (2048-dim)","4","2.6B (base+refiner)","1024×1024","Dual encoder, two-stage refiner pipeline"],["SD3","T5-XXL + CLIP-L + CLIP-G","16","MM-DiT 2B","1024×1024","Flow matching, multi-modal DiT, 16-channel latent"]]},{"type":"list","ordered":false,"items":["The VAE\u0027s 8× spatial compression reduces U-Net compute by 64× compared to pixel-space diffusion.","Cross-attention is asymmetric: Q dimension = U-Net channels; K/V dimension = text encoder output (768, 1024, or 2048).","Classifier-Free Guidance doubles the U-Net forward pass: conditional and unconditional runs combined as ε_cfg = ε_uncond + w·(ε_cond − ε_uncond).","ControlNet zero convolutions ensure the pretrained U-Net is not perturbed at training step 0 — the adapter branch starts as a no-op.","SDXL concatenates (not averages) two text encoder outputs so each encoder contributes independently to the 2048-dim conditioning."]},{"type":"divider"}]"
---
# Stable Diffusion Architecture — VAE, U-Net, and CLIP

Stable Diffusion (Rombach et al. 2022) performs diffusion in a compressed latent space rather than pixel space, reducing computation by roughly 64×. The architecture couples three independently updateable components: a KL-regularized VAE that compresses images to a 4-channel latent grid at 1/8 resolution, a CLIP text encoder that converts prompts to sequence embeddings, and a time-conditioned U-Net that iteratively denoises the latent under text guidance. Understanding how cross-attention wires text into spatial features — and how ControlNet adds structural conditioning — is essential for adapting or extending Stable Diffusion.

## Stable Diffusion Component Overview

The inference pipeline flows: encode prompt with CLIP → sample Gaussian noise z_T in latent space → run denoiser U-Net for T steps with text conditioning → decode latent z_0 with VAE decoder. The VAE encoder is used only during training, not inference. CLIP produces per-token embeddings (not a single pooled vector) so that individual tokens can attend to different spatial regions via cross-attention. The U-Net operates entirely at 1/8 pixel resolution, making 512×512 generation feasible on consumer hardware.

## VAE Encoder and Decoder

The VAE uses a KL-divergence regularisation term with a small weight (λ=1e-6) to keep the latent distribution close to a standard Gaussian while prioritising reconstruction quality. The encoder E maps H×W×3 images to (H/8)×(W/8)×4 latents: a 512×512 image becomes 64×64×4. The four latent channels provide richer per-location representation than a single channel. At encode time σ≈0, so latents are nearly deterministic. The decoder D uses symmetric residual blocks with self-attention at the bottleneck to upsample 64×64×4 back to 512×512×3.

## CLIP Text Encoder

SD 1.x uses OpenAI CLIP ViT-L/14, producing 77×768 sequence embeddings. SD 2.x uses OpenCLIP ViT-H/14 (77×1024). SDXL concatenates embeddings from CLIP-L/14 and OpenCLIP-G/14 to produce 77×2048 conditioning with richer semantics. SD3 and FLUX additionally incorporate T5-XXL for better language understanding. The entire token sequence (not just the pooled CLS embedding) is passed to cross-attention so each text token can influence different spatial positions independently.

## U-Net Denoiser and Cross-Attention

The U-Net has three paths: a downsampling encoder (ResBlocks + self-attention at lower resolutions), a bottleneck (self + cross-attention), and an upsampling decoder that receives skip connections from the encoder. Cross-attention injects text: queries Q come from flattened spatial features, keys K and values V come from CLIP embeddings. Each spatial token attends to all 77 text tokens, allowing text to control which region shows which concept. The spatial dimension of the U-Net varies by resolution level — 64×64 at the first level to 8×8 at the bottleneck.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class CrossAttentionBlock(nn.Module):
    """Q from image latent features, K/V from CLIP text embeddings."""
    def __init__(self, dim_q, dim_kv, n_heads=8):
        super().__init__()
        self.n_heads = n_heads
        self.head_dim = dim_q // n_heads
        self.scale = self.head_dim ** -0.5
        self.to_q = nn.Linear(dim_q, dim_q, bias=False)
        self.to_k = nn.Linear(dim_kv, dim_q, bias=False)
        self.to_v = nn.Linear(dim_kv, dim_q, bias=False)
        self.proj = nn.Linear(dim_q, dim_q)
        self.norm_q = nn.LayerNorm(dim_q)

    def forward(self, x, context):
        B, N, C = x.shape  # N = H*W spatial tokens
        q = self.to_q(self.norm_q(x)).reshape(B, N, self.n_heads, self.head_dim).transpose(1, 2)
        k = self.to_k(context).reshape(B, -1, self.n_heads, self.head_dim).transpose(1, 2)
        v = self.to_v(context).reshape(B, -1, self.n_heads, self.head_dim).transpose(1, 2)
        attn = torch.softmax(q @ k.transpose(-2, -1) * self.scale, dim=-1)
        out = (attn @ v).transpose(1, 2).reshape(B, N, C)
        return x + self.proj(out)

block = CrossAttentionBlock(dim_q=320, dim_kv=768, n_heads=8)
x   = torch.randn(2, 64, 320)    # 8x8 spatial tokens, U-Net channels
ctx = torch.randn(2, 77, 768)   # CLIP text embeddings (SD 1.x, 768-dim)
print('Cross-attn output:', block(x, ctx).shape)  # (2, 64, 320)
```

## Timestep Embedding

The U-Net must know the current noise level t to denoise appropriately. Timestep t ∈ {0,...,T} is first encoded with sinusoidal embeddings (identical to Transformer positional encodings) then projected through a 2-layer SiLU MLP. The resulting vector conditions each residual block via Adaptive Group Normalization (AdaGN): the timestep MLP predicts per-channel scale α(t) and shift δ(t) that modulate the normalised activations before the convolution, allowing the U-Net to behave differently at every noise level.

```python
import torch
import torch.nn as nn
import math

class TimestepEmbedding(nn.Module):
    """Sinusoidal positional encoding -> MLP -> injected into ResBlocks via AdaGN."""
    def __init__(self, dim, out_dim=None):
        super().__init__()
        out_dim = out_dim or dim * 4
        self.dim = dim
        self.mlp = nn.Sequential(nn.Linear(dim, out_dim), nn.SiLU(), nn.Linear(out_dim, out_dim))

    def forward(self, t):
        half = self.dim // 2
        freqs = torch.exp(-math.log(10000) * torch.arange(half, dtype=torch.float32, device=t.device) / half)
        args = t[:, None].float() * freqs[None]
        return self.mlp(torch.cat([args.sin(), args.cos()], dim=-1))

def ada_gn_forward(x, t_emb, norm, time_proj):
    """Apply Adaptive GroupNorm: t_emb -> (scale, shift) modulate norm output."""
    scale, shift = time_proj(t_emb).chunk(2, dim=-1)
    return norm(x) * (1 + scale[:, :, None, None]) + shift[:, :, None, None]

ts = TimestepEmbedding(dim=128, out_dim=512)
t = torch.randint(0, 1000, (4,))
t_emb = ts(t)
print(f'Timestep {t.tolist()} -> embedding shape: {t_emb.shape}')  # (4, 512)

norm = nn.GroupNorm(32, 256)
time_proj = nn.Linear(512, 512)  # predicts scale+shift for 256 channels
x = torch.randn(4, 256, 16, 16)
x_cond = ada_gn_forward(x, t_emb, norm, time_proj)
print(f'After AdaGN: mean={x_cond.mean():.4f} std={x_cond.std():.4f}')
```

## SD Inference Pipeline

```python
import torch
from diffusers import StableDiffusionPipeline, DDIMScheduler

def run_sd_inference(prompt, neg_prompt='', n_steps=30, guidance_scale=7.5, seed=42):
    """Run SD 1.5: encode prompt -> denoise latent -> decode to image."""
    device = 'cuda' if torch.cuda.is_available() else 'cpu'
    dtype  = torch.float16 if device == 'cuda' else torch.float32
    pipe = StableDiffusionPipeline.from_pretrained(
        'runwayml/stable-diffusion-v1-5',
        scheduler=DDIMScheduler.from_pretrained(
            'runwayml/stable-diffusion-v1-5', subfolder='scheduler'),
        torch_dtype=dtype,
    ).to(device)
    pipe.safety_checker = None
    generator = torch.Generator(device=device).manual_seed(seed)
    with torch.inference_mode():
        result = pipe(
            prompt, negative_prompt=neg_prompt,
            num_inference_steps=n_steps,
            guidance_scale=guidance_scale,
            generator=generator, height=512, width=512,
        )
    img = result.images[0]
    print(f'Generated {img.size} with {n_steps} DDIM steps, CFG={guidance_scale}')
    return img

# Pipeline stages in order:
print('1. CLIP encodes prompt -> 77x768 text embeddings')
print('2. Sample z_T ~ N(0,I) in 64x64x4 latent space')
print('3. U-Net denoises z_T -> z_0 over 30 DDIM steps (CFG doubles each step)')
print('4. VAE decoder maps z_0 (64x64x4) -> image (512x512x3)')
```

## ControlNet Integration

ControlNet (Zhang & Agrawala 2023) adds spatial conditioning — edge maps, depth maps, human pose skeletons — to a frozen SD U-Net without touching the original weights. It copies the U-Net encoder blocks, processes a conditioning image through those copied blocks, and injects the outputs into the original U-Net decoder via learned zero convolutions (1×1 conv initialised to zero weight and bias). Zero initialisation ensures that at training start the ControlNet branch contributes nothing, preserving the base model's behaviour and enabling stable fine-tuning from the pretrained checkpoint.

```python
import torch
import torch.nn as nn
from diffusers import StableDiffusionControlNetPipeline, ControlNetModel, UniPCMultistepScheduler
from PIL import Image

class ZeroConv2d(nn.Module):
    """1x1 conv initialised to zero — ControlNet injection layer."""
    def __init__(self, channels):
        super().__init__()
        self.conv = nn.Conv2d(channels, channels, 1)
        nn.init.zeros_(self.conv.weight)
        nn.init.zeros_(self.conv.bias)
    def forward(self, x):
        return self.conv(x)

def controlnet_injection(unet_feat, ctrl_feat, zero_conv):
    """Add ControlNet encoder output (after zero conv) to U-Net decoder feature."""
    return unet_feat + zero_conv(ctrl_feat)

# Demonstrate zero conv starts as identity (contributes nothing)
zc = ZeroConv2d(channels=64)
x = torch.randn(2, 64, 32, 32)
print(f'ZeroConv output max at init: {zc(x).abs().max().item():.6f}')  # ~0.0

# Conceptual ControlNet pipeline
print('ControlNet pipeline:')
print('  1. Canny edge detector  -> 512x512 edge map')
print('  2. Copied U-Net encoder -> intermediate feature maps')
print('  3. Zero convolutions    -> scale features to zero at init')
print('  4. Add to U-Net decoder -> structural constraint on generation')
```

> **Choosing the Right SD Version**: For general text-to-image with 8-16 GB VRAM: SD 1.5 runs at 512×512, supports the widest LoRA/ControlNet ecosystem, and fine-tunes in hours. SDXL gives best 1024×1024 quality with a two-stage refiner but needs 16+ GB. SD3 and FLUX have superior prompt adherence for complex scenes but require 24+ GB for full quality. Always match your LoRA or ControlNet adapter to the exact base model version.

| Version | Text Encoder | Latent Channels | Backbone Size | Default Resolution | Key Improvement |
| --- | --- | --- | --- | --- | --- |
| SD 1.x | CLIP ViT-L/14 (768-dim, 77 tok) | 4 | 860M U-Net | 512×512 | Foundation latent diffusion model |
| SD 2.x | OpenCLIP ViT-H (1024-dim) | 4 | 865M U-Net | 768×768 | Better NSFW filtering, depth model, v-prediction |
| SDXL | CLIP-L + OpenCLIP-G (2048-dim) | 4 | 2.6B (base+refiner) | 1024×1024 | Dual encoder, two-stage refiner pipeline |
| SD3 | T5-XXL + CLIP-L + CLIP-G | 16 | MM-DiT 2B | 1024×1024 | Flow matching, multi-modal DiT, 16-channel latent |

- The VAE's 8× spatial compression reduces U-Net compute by 64× compared to pixel-space diffusion.
- Cross-attention is asymmetric: Q dimension = U-Net channels; K/V dimension = text encoder output (768, 1024, or 2048).
- Classifier-Free Guidance doubles the U-Net forward pass: conditional and unconditional runs combined as ε_cfg = ε_uncond + w·(ε_cond − ε_uncond).
- ControlNet zero convolutions ensure the pretrained U-Net is not perturbed at training step 0 — the adapter branch starts as a no-op.
- SDXL concatenates (not averages) two text encoder outputs so each encoder contributes independently to the 2048-dim conditioning.

---

