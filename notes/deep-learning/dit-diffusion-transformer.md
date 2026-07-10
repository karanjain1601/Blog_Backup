---
title: "DiT — Diffusion Transformer Replacing U-Net"
slug: "dit-diffusion-transformer"
description: "DiT replaces the U-Net backbone in latent diffusion with a scalable Vision Transformer, using patchified latent tokens, adaLN-Zero conditioning, and ViT-style scaling laws to achieve state-of-the-art FID on ImageNet while enabling the MM-DiT architectures used in SD3 and FLUX."
tags: ["deep-learning", "generative-models", "diffusion-models"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Diffusion Transformers (DiT, Peebles \u0026 Xie 2023) replace the U-Net backbone used in standard latent diffusion models with a Vision Transformer, processing the image latent as a sequence of flattened patches. This architectural swap is motivated by the observation that ViT performance scales reliably with compute (unlike U-Nets which show diminishing returns), and that transformers handle variable-length conditioning inputs more naturally via self-attention. DiT-XL/2 achieves FID 2.27 on ImageNet 256×256, surpassing the U-Net-based ADM model, and forms the backbone of SD3 and FLUX."},{"type":"heading","level":2,"content":"From U-Net to Vision Transformer"},{"type":"text","content":"The U-Net was the natural choice for diffusion: its encoder-decoder with skip connections mirrors the denoising process of refining features at multiple resolutions. However, U-Nets do not scale as cleanly as transformers — adding layers often requires hand-designed changes to the architecture. DiT treats the latent grid as a token sequence (like ViT), applies standard transformer blocks, and relies on the attention mechanism\u0027s global receptive field rather than hierarchical feature extraction. The conditioning on timestep t and class label (or text) is injected per-block via Adaptive LayerNorm."},{"type":"heading","level":2,"content":"Patchify Latent Input"},{"type":"text","content":"The VAE latent of shape (C, H/8, W/8) — typically (4, 32, 32) for a 256×256 image — is split into non-overlapping patches of size p×p (p=2 or p=4). Each patch is flattened and linearly projected to a d-dimensional token embedding. For a 32×32 latent with patch size 2, we get (32/2)² = 256 tokens. Smaller patches give more tokens and finer spatial resolution but increase sequence length quadratically. A learned positional embedding is added before the transformer blocks."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass PatchEmbed(nn.Module):\n    \"\"\"Patchify image latent into token sequence for DiT.\"\"\"\n    def __init__(self, in_channels=4, patch_size=2, embed_dim=1152):\n        super().__init__()\n        self.patch_size = patch_size\n        self.proj = nn.Conv2d(in_channels, embed_dim, kernel_size=patch_size, stride=patch_size)\n\n    def forward(self, x):\n        # x: (B, C, H, W) latent\n        B, C, H, W = x.shape\n        assert H % self.patch_size == 0 and W % self.patch_size == 0\n        tokens = self.proj(x)          # (B, embed_dim, H/p, W/p)\n        tokens = tokens.flatten(2)     # (B, embed_dim, N) where N=(H/p)*(W/p)\n        tokens = tokens.transpose(1, 2)  # (B, N, embed_dim)\n        return tokens\n\ndef add_positional_embedding(tokens, pos_embed):\n    return tokens + pos_embed[:, :tokens.shape[1], :]\n\n# Demo: 256x256 image -\u003e 32x32 VAE latent (4 channels) -\u003e 256 tokens\npatch_embed = PatchEmbed(in_channels=4, patch_size=2, embed_dim=1152)\nlatent = torch.randn(2, 4, 32, 32)  # batch of 2 latents\ntokens = patch_embed(latent)\nprint(f\u0027Latent: {latent.shape} -\u003e Tokens: {tokens.shape}\u0027)  # (2, 256, 1152)\n\n# For 512x512 image: 64x64 latent, patch=2 -\u003e 1024 tokens\nlatent_lg = torch.randn(1, 4, 64, 64)\ntokens_lg = patch_embed(latent_lg)\nprint(f\u002764x64 latent -\u003e {tokens_lg.shape[1]} tokens\u0027)  # 1024 tokens"},{"type":"heading","level":2,"content":"Adaptive LayerNorm Zero"},{"type":"text","content":"DiT conditions each transformer block on both the timestep t and the class label (or text embedding) via Adaptive Layer Normalization (adaLN). The condition is computed as: (α, β, γ, α\u0027, β\u0027, γ\u0027) = Linear(SiLU(cond)), where cond is the sum of timestep and class embeddings. The LayerNorm output is then modulated: adaLN(x) = γ·LayerNorm(x) + β, and the attention/FFN output is scaled by α before the residual addition. The Zero variant initialises the final linear layer of each adaLN to zero, so at training start each block acts as the identity — critical for training stability at scale."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass AdaLNZero(nn.Module):\n    \"\"\"Adaptive LayerNorm-Zero: conditioning via scale+shift, zero-init output.\"\"\"\n    def __init__(self, hidden_size, cond_dim):\n        super().__init__()\n        self.norm = nn.LayerNorm(hidden_size, elementwise_affine=False)\n        # 6 outputs: shift, scale for pre-attn; gate for attn; shift, scale, gate for FFN\n        self.adaLN_modulation = nn.Sequential(\n            nn.SiLU(),\n            nn.Linear(cond_dim, 6 * hidden_size)\n        )\n        nn.init.zeros_(self.adaLN_modulation[-1].weight)\n        nn.init.zeros_(self.adaLN_modulation[-1].bias)\n\n    def modulate(self, x, shift, scale):\n        return x * (1 + scale.unsqueeze(1)) + shift.unsqueeze(1)\n\n    def get_modulations(self, cond):\n        mods = self.adaLN_modulation(cond).chunk(6, dim=1)\n        return mods  # shift_attn, scale_attn, gate_attn, shift_ff, scale_ff, gate_ff\n\ntorch.manual_seed(0)\nad = AdaLNZero(hidden_size=1152, cond_dim=1152)\ncond = torch.randn(4, 1152)  # timestep + class condition\nmods = ad.get_modulations(cond)\nprint(f\u0027adaLN-Zero modulations at init (should be ~0): {[m.abs().max().item():.4f} for m in mods]}\u0027.replace(\"[\", \"[\").replace(\"]\", \"]\"))\nprint(f\u0027Blocks start as identity at init — stable training from scratch\u0027)"},{"type":"heading","level":2,"content":"DiT Block Architecture"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass DiTBlock(nn.Module):\n    \"\"\"DiT transformer block: ViT attention + FFN with adaLN-Zero conditioning.\"\"\"\n    def __init__(self, hidden_size=1152, n_heads=16, cond_dim=1152, mlp_ratio=4.0):\n        super().__init__()\n        self.norm1 = nn.LayerNorm(hidden_size, elementwise_affine=False)\n        self.norm2 = nn.LayerNorm(hidden_size, elementwise_affine=False)\n        self.attn = nn.MultiheadAttention(hidden_size, n_heads, batch_first=True)\n        mlp_dim = int(hidden_size * mlp_ratio)\n        self.mlp = nn.Sequential(\n            nn.Linear(hidden_size, mlp_dim), nn.GELU(),\n            nn.Linear(mlp_dim, hidden_size)\n        )\n        self.adaLN = nn.Sequential(nn.SiLU(), nn.Linear(cond_dim, 6 * hidden_size))\n        nn.init.zeros_(self.adaLN[-1].weight)\n        nn.init.zeros_(self.adaLN[-1].bias)\n\n    def forward(self, x, c):\n        mods = self.adaLN(c).chunk(6, dim=-1)  # 6 modulation vectors\n        shift_a, scale_a, gate_a, shift_m, scale_m, gate_m = mods\n        # Attention with adaLN conditioning\n        h = self.norm1(x) * (1 + scale_a[:, None]) + shift_a[:, None]\n        attn_out, _ = self.attn(h, h, h)\n        x = x + gate_a[:, None] * attn_out\n        # FFN with adaLN conditioning\n        h = self.norm2(x) * (1 + scale_m[:, None]) + shift_m[:, None]\n        x = x + gate_m[:, None] * self.mlp(h)\n        return x\n\nblock = DiTBlock(hidden_size=1152, n_heads=16, cond_dim=1152)\ntokens = torch.randn(2, 256, 1152)  # (batch, N_tokens, hidden)\ncond   = torch.randn(2, 1152)        # timestep + class condition\nout = block(tokens, cond)\nprint(f\u0027DiT block: {tokens.shape} -\u003e {out.shape}\u0027)"},{"type":"heading","level":2,"content":"Scaling Laws and FLOPs vs FID"},{"type":"text","content":"DiT follows the same scaling laws as ViT: FID decreases as a power law in compute (GFLOPs per sample). DiT-XL/2 uses 2000M GFLOPs per sample and achieves FID 2.27, while DiT-S/2 (33M params) achieves FID 68.4 — a 30× compute increase yields 30× better FID. Crucially, this relationship is smooth and predictable, making DiT amenable to compute-optimal training. The U-Net ADM model achieves FID 10.94 with comparable compute, confirming that DiT\u0027s transformer backbone is more compute-efficient for diffusion."},{"type":"code","language":"python","content":"import torch\nimport numpy as np\n\n# DiT scaling: approximate FID vs GFLOPs (from Peebles \u0026 Xie 2023 Table 1)\ndit_results = [\n    (\u0027DiT-S/2\u0027,  33,   6,    68.4),\n    (\u0027DiT-B/2\u0027,  130,  23,   43.5),\n    (\u0027DiT-L/2\u0027,  458,  80,   23.5),\n    (\u0027DiT-XL/2\u0027, 675,  119,  9.62),\n    (\u0027ADM (U-Net)\u0027, 554, 98, 10.94),\n]\nprint(f\u0027{\"Model\":\u003c15} {\"Params (M)\":\u003e12} {\"GFLOPs\":\u003e8} {\"FID\":\u003e8} {\"vs ADM\":\u003e10}\u0027)\nprint(\u0027-\u0027 * 58)\nadm_fid = 10.94\nfor name, params, gflops, fid in dit_results:\n    delta = f\u0027{fid - adm_fid:+.2f}\u0027 if name != \u0027ADM (U-Net)\u0027 else \u0027(baseline)\u0027\n    print(f\u0027{name:\u003c15} {params:\u003e12} {gflops:\u003e8} {fid:\u003e8.2f} {delta:\u003e10}\u0027)\n\nprint()\n# Scaling law: log-log relationship\ngflops = np.array([6, 23, 80, 119])\nfids = np.array([68.4, 43.5, 23.5, 9.62])\ncoef = np.polyfit(np.log(gflops), np.log(fids), 1)\nprint(f\u0027Power law fit: FID ~ GFLOPs^{coef[0]:.2f} (exponent \u003c 0 = improvement with scale)\u0027)"},{"type":"heading","level":2,"content":"MM-DiT in SD3 and FLUX"},{"type":"text","content":"SD3 introduces Multi-Modal DiT (MM-DiT), where image tokens and text tokens are processed jointly in the same transformer blocks with separate weights for each modality. Each MM-DiT block has two independent sets of attention projections — one for image tokens and one for text tokens — but the attention itself is computed over the concatenated sequence, allowing full bidirectional cross-modal attention. This is more powerful than the cross-attention mechanism in SD 1.x U-Net because text tokens can also attend to image tokens. SD3 uses 16-channel latents (vs 4 in SD 1.x), tripling the information capacity of the compressed representation."},{"type":"callout","variant":"info","title":"FLUX: SoTA DiT Text-to-Image","content":"FLUX.1 (Black Forest Labs, 2024) is a DiT-based model that achieves state-of-the-art text-to-image quality on human preference benchmarks. FLUX uses a hybrid architecture combining MM-DiT blocks (for joint image-text attention) and single-stream DiT blocks (for image-only refinement), with flow matching as the training objective. FLUX.1-dev (12B parameters) is publicly available and outperforms Midjourney v6 on prompt adherence while FLUX.1-schnell requires only 4 NFE."},{"type":"table","headers":["Architecture","Params","GFLOPs/sample","ImageNet 256 FID","Training Compute","Architecture Type"],"rows":[["ADM (U-Net, class-cond)","554M","~98","10.94","~1000 A100 GPU-days","U-Net with self+cross-attn"],["DiT-S/2","33M","6","68.4","~7 A100 GPU-days","Shallow ViT, patch=2"],["DiT-B/2","130M","23","43.5","~28 A100 GPU-days","BERT-scale ViT, patch=2"],["DiT-XL/2","675M","119","2.27 (w/ CFG)","~1000 A100 GPU-days","Large ViT, patch=2, SoTA"],["FLUX.1 (approx)","12B","\u003e1000","N/A (T2I)","\u003e\u003e10k GPU-days","MM-DiT + single-stream DiT"]]},{"type":"list","ordered":false,"items":["Patch size p=2 gives 4× more tokens than p=4 for the same latent — better spatial detail but 4× more compute.","adaLN-Zero\u0027s zero-init ensures blocks start as identity — without this, deep DiTs diverge at the start of training.","DiT-XL/2 uses 28 transformer blocks with hidden size 1152 and 16 attention heads — the same scale as ViT-L.","MM-DiT enables text tokens to attend to image tokens, giving text stronger control than cross-attention alone.","FLUX.1-schnell achieves 4-step generation via guidance distillation — the DiT architecture is compatible with all distillation methods."]},{"type":"heading","level":2,"content":"Key Design Principles"},{"type":"text","content":"Three design decisions define DiT\u0027s success: (1) Patchify-then-transformer: treating the latent as a token sequence gives global receptive field from layer 1, unlike U-Net\u0027s limited kernel sizes. (2) adaLN-Zero: conditioning via scale+shift+gate with zero initialisation is more expressive than in-context conditioning (prepending condition tokens) and more stable than cross-attention conditioning. (3) Predict ε or v: DiT uses the same noise prediction objective as DDPM but gains from the transformer\u0027s better capacity. The key lesson is that architectural improvements compound with scale — DiT benefits more from 10× more compute than U-Net does."},{"type":"divider"}]"
---
# DiT — Diffusion Transformer Replacing U-Net

Diffusion Transformers (DiT, Peebles & Xie 2023) replace the U-Net backbone used in standard latent diffusion models with a Vision Transformer, processing the image latent as a sequence of flattened patches. This architectural swap is motivated by the observation that ViT performance scales reliably with compute (unlike U-Nets which show diminishing returns), and that transformers handle variable-length conditioning inputs more naturally via self-attention. DiT-XL/2 achieves FID 2.27 on ImageNet 256×256, surpassing the U-Net-based ADM model, and forms the backbone of SD3 and FLUX.

## From U-Net to Vision Transformer

The U-Net was the natural choice for diffusion: its encoder-decoder with skip connections mirrors the denoising process of refining features at multiple resolutions. However, U-Nets do not scale as cleanly as transformers — adding layers often requires hand-designed changes to the architecture. DiT treats the latent grid as a token sequence (like ViT), applies standard transformer blocks, and relies on the attention mechanism's global receptive field rather than hierarchical feature extraction. The conditioning on timestep t and class label (or text) is injected per-block via Adaptive LayerNorm.

## Patchify Latent Input

The VAE latent of shape (C, H/8, W/8) — typically (4, 32, 32) for a 256×256 image — is split into non-overlapping patches of size p×p (p=2 or p=4). Each patch is flattened and linearly projected to a d-dimensional token embedding. For a 32×32 latent with patch size 2, we get (32/2)² = 256 tokens. Smaller patches give more tokens and finer spatial resolution but increase sequence length quadratically. A learned positional embedding is added before the transformer blocks.

```python
import torch
import torch.nn as nn

class PatchEmbed(nn.Module):
    """Patchify image latent into token sequence for DiT."""
    def __init__(self, in_channels=4, patch_size=2, embed_dim=1152):
        super().__init__()
        self.patch_size = patch_size
        self.proj = nn.Conv2d(in_channels, embed_dim, kernel_size=patch_size, stride=patch_size)

    def forward(self, x):
        # x: (B, C, H, W) latent
        B, C, H, W = x.shape
        assert H % self.patch_size == 0 and W % self.patch_size == 0
        tokens = self.proj(x)          # (B, embed_dim, H/p, W/p)
        tokens = tokens.flatten(2)     # (B, embed_dim, N) where N=(H/p)*(W/p)
        tokens = tokens.transpose(1, 2)  # (B, N, embed_dim)
        return tokens

def add_positional_embedding(tokens, pos_embed):
    return tokens + pos_embed[:, :tokens.shape[1], :]

# Demo: 256x256 image -> 32x32 VAE latent (4 channels) -> 256 tokens
patch_embed = PatchEmbed(in_channels=4, patch_size=2, embed_dim=1152)
latent = torch.randn(2, 4, 32, 32)  # batch of 2 latents
tokens = patch_embed(latent)
print(f'Latent: {latent.shape} -> Tokens: {tokens.shape}')  # (2, 256, 1152)

# For 512x512 image: 64x64 latent, patch=2 -> 1024 tokens
latent_lg = torch.randn(1, 4, 64, 64)
tokens_lg = patch_embed(latent_lg)
print(f'64x64 latent -> {tokens_lg.shape[1]} tokens')  # 1024 tokens
```

## Adaptive LayerNorm Zero

DiT conditions each transformer block on both the timestep t and the class label (or text embedding) via Adaptive Layer Normalization (adaLN). The condition is computed as: (α, β, γ, α', β', γ') = Linear(SiLU(cond)), where cond is the sum of timestep and class embeddings. The LayerNorm output is then modulated: adaLN(x) = γ·LayerNorm(x) + β, and the attention/FFN output is scaled by α before the residual addition. The Zero variant initialises the final linear layer of each adaLN to zero, so at training start each block acts as the identity — critical for training stability at scale.

```python
import torch
import torch.nn as nn

class AdaLNZero(nn.Module):
    """Adaptive LayerNorm-Zero: conditioning via scale+shift, zero-init output."""
    def __init__(self, hidden_size, cond_dim):
        super().__init__()
        self.norm = nn.LayerNorm(hidden_size, elementwise_affine=False)
        # 6 outputs: shift, scale for pre-attn; gate for attn; shift, scale, gate for FFN
        self.adaLN_modulation = nn.Sequential(
            nn.SiLU(),
            nn.Linear(cond_dim, 6 * hidden_size)
        )
        nn.init.zeros_(self.adaLN_modulation[-1].weight)
        nn.init.zeros_(self.adaLN_modulation[-1].bias)

    def modulate(self, x, shift, scale):
        return x * (1 + scale.unsqueeze(1)) + shift.unsqueeze(1)

    def get_modulations(self, cond):
        mods = self.adaLN_modulation(cond).chunk(6, dim=1)
        return mods  # shift_attn, scale_attn, gate_attn, shift_ff, scale_ff, gate_ff

torch.manual_seed(0)
ad = AdaLNZero(hidden_size=1152, cond_dim=1152)
cond = torch.randn(4, 1152)  # timestep + class condition
mods = ad.get_modulations(cond)
print(f'adaLN-Zero modulations at init (should be ~0): {[m.abs().max().item():.4f} for m in mods]}'.replace("[", "[").replace("]", "]"))
print(f'Blocks start as identity at init — stable training from scratch')
```

## DiT Block Architecture

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class DiTBlock(nn.Module):
    """DiT transformer block: ViT attention + FFN with adaLN-Zero conditioning."""
    def __init__(self, hidden_size=1152, n_heads=16, cond_dim=1152, mlp_ratio=4.0):
        super().__init__()
        self.norm1 = nn.LayerNorm(hidden_size, elementwise_affine=False)
        self.norm2 = nn.LayerNorm(hidden_size, elementwise_affine=False)
        self.attn = nn.MultiheadAttention(hidden_size, n_heads, batch_first=True)
        mlp_dim = int(hidden_size * mlp_ratio)
        self.mlp = nn.Sequential(
            nn.Linear(hidden_size, mlp_dim), nn.GELU(),
            nn.Linear(mlp_dim, hidden_size)
        )
        self.adaLN = nn.Sequential(nn.SiLU(), nn.Linear(cond_dim, 6 * hidden_size))
        nn.init.zeros_(self.adaLN[-1].weight)
        nn.init.zeros_(self.adaLN[-1].bias)

    def forward(self, x, c):
        mods = self.adaLN(c).chunk(6, dim=-1)  # 6 modulation vectors
        shift_a, scale_a, gate_a, shift_m, scale_m, gate_m = mods
        # Attention with adaLN conditioning
        h = self.norm1(x) * (1 + scale_a[:, None]) + shift_a[:, None]
        attn_out, _ = self.attn(h, h, h)
        x = x + gate_a[:, None] * attn_out
        # FFN with adaLN conditioning
        h = self.norm2(x) * (1 + scale_m[:, None]) + shift_m[:, None]
        x = x + gate_m[:, None] * self.mlp(h)
        return x

block = DiTBlock(hidden_size=1152, n_heads=16, cond_dim=1152)
tokens = torch.randn(2, 256, 1152)  # (batch, N_tokens, hidden)
cond   = torch.randn(2, 1152)        # timestep + class condition
out = block(tokens, cond)
print(f'DiT block: {tokens.shape} -> {out.shape}')
```

## Scaling Laws and FLOPs vs FID

DiT follows the same scaling laws as ViT: FID decreases as a power law in compute (GFLOPs per sample). DiT-XL/2 uses 2000M GFLOPs per sample and achieves FID 2.27, while DiT-S/2 (33M params) achieves FID 68.4 — a 30× compute increase yields 30× better FID. Crucially, this relationship is smooth and predictable, making DiT amenable to compute-optimal training. The U-Net ADM model achieves FID 10.94 with comparable compute, confirming that DiT's transformer backbone is more compute-efficient for diffusion.

```python
import torch
import numpy as np

# DiT scaling: approximate FID vs GFLOPs (from Peebles & Xie 2023 Table 1)
dit_results = [
    ('DiT-S/2',  33,   6,    68.4),
    ('DiT-B/2',  130,  23,   43.5),
    ('DiT-L/2',  458,  80,   23.5),
    ('DiT-XL/2', 675,  119,  9.62),
    ('ADM (U-Net)', 554, 98, 10.94),
]
print(f'{"Model":<15} {"Params (M)":>12} {"GFLOPs":>8} {"FID":>8} {"vs ADM":>10}')
print('-' * 58)
adm_fid = 10.94
for name, params, gflops, fid in dit_results:
    delta = f'{fid - adm_fid:+.2f}' if name != 'ADM (U-Net)' else '(baseline)'
    print(f'{name:<15} {params:>12} {gflops:>8} {fid:>8.2f} {delta:>10}')

print()
# Scaling law: log-log relationship
gflops = np.array([6, 23, 80, 119])
fids = np.array([68.4, 43.5, 23.5, 9.62])
coef = np.polyfit(np.log(gflops), np.log(fids), 1)
print(f'Power law fit: FID ~ GFLOPs^{coef[0]:.2f} (exponent < 0 = improvement with scale)')
```

## MM-DiT in SD3 and FLUX

SD3 introduces Multi-Modal DiT (MM-DiT), where image tokens and text tokens are processed jointly in the same transformer blocks with separate weights for each modality. Each MM-DiT block has two independent sets of attention projections — one for image tokens and one for text tokens — but the attention itself is computed over the concatenated sequence, allowing full bidirectional cross-modal attention. This is more powerful than the cross-attention mechanism in SD 1.x U-Net because text tokens can also attend to image tokens. SD3 uses 16-channel latents (vs 4 in SD 1.x), tripling the information capacity of the compressed representation.

> **FLUX: SoTA DiT Text-to-Image**: FLUX.1 (Black Forest Labs, 2024) is a DiT-based model that achieves state-of-the-art text-to-image quality on human preference benchmarks. FLUX uses a hybrid architecture combining MM-DiT blocks (for joint image-text attention) and single-stream DiT blocks (for image-only refinement), with flow matching as the training objective. FLUX.1-dev (12B parameters) is publicly available and outperforms Midjourney v6 on prompt adherence while FLUX.1-schnell requires only 4 NFE.

| Architecture | Params | GFLOPs/sample | ImageNet 256 FID | Training Compute | Architecture Type |
| --- | --- | --- | --- | --- | --- |
| ADM (U-Net, class-cond) | 554M | ~98 | 10.94 | ~1000 A100 GPU-days | U-Net with self+cross-attn |
| DiT-S/2 | 33M | 6 | 68.4 | ~7 A100 GPU-days | Shallow ViT, patch=2 |
| DiT-B/2 | 130M | 23 | 43.5 | ~28 A100 GPU-days | BERT-scale ViT, patch=2 |
| DiT-XL/2 | 675M | 119 | 2.27 (w/ CFG) | ~1000 A100 GPU-days | Large ViT, patch=2, SoTA |
| FLUX.1 (approx) | 12B | >1000 | N/A (T2I) | >>10k GPU-days | MM-DiT + single-stream DiT |

- Patch size p=2 gives 4× more tokens than p=4 for the same latent — better spatial detail but 4× more compute.
- adaLN-Zero's zero-init ensures blocks start as identity — without this, deep DiTs diverge at the start of training.
- DiT-XL/2 uses 28 transformer blocks with hidden size 1152 and 16 attention heads — the same scale as ViT-L.
- MM-DiT enables text tokens to attend to image tokens, giving text stronger control than cross-attention alone.
- FLUX.1-schnell achieves 4-step generation via guidance distillation — the DiT architecture is compatible with all distillation methods.

## Key Design Principles

Three design decisions define DiT's success: (1) Patchify-then-transformer: treating the latent as a token sequence gives global receptive field from layer 1, unlike U-Net's limited kernel sizes. (2) adaLN-Zero: conditioning via scale+shift+gate with zero initialisation is more expressive than in-context conditioning (prepending condition tokens) and more stable than cross-attention conditioning. (3) Predict ε or v: DiT uses the same noise prediction objective as DDPM but gains from the transformer's better capacity. The key lesson is that architectural improvements compound with scale — DiT benefits more from 10× more compute than U-Net does.

---

