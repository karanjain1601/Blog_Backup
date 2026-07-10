---
title: "VQ-VAE-2 — Hierarchical Discrete Latents for High-Resolution Generation"
slug: "vq-vae-2"
description: "VQ-VAE-2 extends vector-quantized autoencoders to 256x256 generation via two hierarchical codebook levels: an 8x8 top level capturing global structure and a 32x32 bottom level capturing local details, with bottom encoding conditioned on top codes and a two-stage PixelSnail prior for high-fidelity class-conditional generation."
tags: ["deep-learning", "generative-models"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"VQ-VAE-2 (Razavi et al. 2019) extends the original VQ-VAE to high-resolution image synthesis by introducing a hierarchy of discrete latent codes. A single codebook at one resolution cannot simultaneously capture both global image structure (object layout, colour palette) and local fine details (textures, edges). Two levels solve this: a top level at 8x8 encodes coarse global information, and a bottom level at 32x32 encodes local detail conditioned on the already-quantized top representation. The result is 256x256 class-conditional generation at FID ~2.5 on ImageNet — competitive with BigGAN at the time — using a two-stage discrete autoregressive prior."},{"type":"heading","level":2,"content":"Introduction: Hierarchical Motivation"},{"type":"text","content":"The original VQ-VAE used a single-level codebook and was limited to 32x32 or 64x64 generation. Scaling to 256x256 with one codebook forces a tradeoff: a large spatial grid preserves local detail but the codebook must span the entire space of image patches; a small grid loses spatial resolution. Hierarchical representation solves this by factorising image information across levels. The top level need only describe scene-level structure — which regions contain foreground objects, approximate colour distribution, dominant shapes — while the bottom level fills in local texture conditioned on that global context. This mirrors how humans perceive images: global scene understanding precedes local detail."},{"type":"heading","level":2,"content":"Two-Level Architecture"},{"type":"text","content":"The VQ-VAE-2 encoder-decoder pair has two quantization stages with separate codebooks. The bottom encoder maps 256x256 images to 32x32 feature maps capturing local detail. The top encoder further compresses 32x32 features to 8x8, capturing global structure. Each level has its own codebook (typically 512 entries each, embedding dimension 64). During encoding, top features are quantized first; the quantized top codes are then upsampled and concatenated to the bottom features before bottom quantization, so the bottom codebook only needs to represent residual local information not already explained by the top. The decoder reverses this process top-down."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass VectorQuantize(nn.Module):\n    def __init__(self, codebook_size=512, embed_dim=64):\n        super().__init__()\n        self.codebook = nn.Embedding(codebook_size, embed_dim)\n\n    def forward(self, z):\n        B, C, H, W = z.shape\n        z_flat = z.permute(0, 2, 3, 1).reshape(-1, C)\n        dist = (z_flat.unsqueeze(1) - self.codebook.weight.unsqueeze(0)).pow(2).sum(-1)\n        indices = dist.argmin(dim=1)\n        z_q = self.codebook(indices).reshape(B, H, W, C).permute(0, 3, 1, 2)\n        z_q = z + (z_q - z).detach()   # straight-through estimator\n        return z_q, indices.reshape(B, H, W)\n\nclass HierarchicalVQVAE(nn.Module):\n    def __init__(self, in_ch=3, hidden=128, codebook_size=512, embed_dim=64):\n        super().__init__()\n        self.bottom_enc = nn.Sequential(\n            nn.Conv2d(in_ch, hidden, 4, 2, 1), nn.ReLU(),\n            nn.Conv2d(hidden, hidden, 4, 2, 1), nn.ReLU(),\n            nn.Conv2d(hidden, hidden, 4, 2, 1), nn.ReLU(),\n            nn.Conv2d(hidden, embed_dim, 1)        # 256-\u003e32 (3 strides of 2)\n        )\n        self.top_enc = nn.Sequential(\n            nn.Conv2d(embed_dim, hidden, 4, 2, 1), nn.ReLU(),\n            nn.Conv2d(hidden, hidden, 4, 2, 1), nn.ReLU(),\n            nn.Conv2d(hidden, embed_dim, 1)        # 32-\u003e8 (2 strides of 2)\n        )\n        self.vq_top    = VectorQuantize(codebook_size, embed_dim)\n        self.vq_bottom = VectorQuantize(codebook_size, embed_dim)\n\ntorch.manual_seed(0)\nmodel = HierarchicalVQVAE()\nx = torch.randn(2, 3, 256, 256)\nb_feat = model.bottom_enc(x)        # (2, 64, 32, 32)\nt_feat = model.top_enc(b_feat)      # (2, 64,  8,  8)\nt_q, t_idx = model.vq_top(t_feat)\nprint(f\u0027Top quantized: {t_q.shape}, indices: {t_idx.shape}\u0027)  # (2,64,8,8), (2,8,8)"},{"type":"heading","level":2,"content":"Top-Level Encoding"},{"type":"text","content":"The top encoder takes the 32x32 bottom feature map as input and applies two further stride-2 convolutions to reach 8x8. This 8x8 top representation is quantized against the top codebook using nearest-neighbor lookup in embedding space (512 entries). The result is 64 discrete tokens per image — enough to represent coarse semantic layout without redundancy. Because the top codebook is small (8x8 = 64 tokens), PixelSnail can model its prior autoregressively in reasonable time: a 64-token sequence is tractable for a convolutional autoregressive model with masking."},{"type":"heading","level":2,"content":"Bottom-Level Conditioning"},{"type":"text","content":"The key innovation in VQ-VAE-2 is that bottom quantization is conditioned on the top codes. After computing the top quantized codes t_q at 8x8, they are upsampled (via nearest-neighbor interpolation) to 32x32 and concatenated channel-wise with the raw bottom encoder features. A learned projection then maps the combined representation to the embedding space before bottom VQ lookup. This means the bottom codebook only needs to encode residual local information not already captured by the top level — a much easier task than encoding everything from scratch. The bottom codes carry local textures, edge orientations, and fine colour variations."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass BottomConditionedEncoder(nn.Module):\n    \"\"\"Encodes bottom features conditioned on upsampled top quantized codes.\"\"\"\n    def __init__(self, embed_dim=64, hidden=128):\n        super().__init__()\n        self.condition_proj = nn.Sequential(\n            nn.Conv2d(embed_dim * 2, hidden, 3, 1, 1), nn.ReLU(),\n            nn.Conv2d(hidden, embed_dim, 1)\n        )\n\n    def forward(self, bottom_feat, top_q):\n        # Upsample 8x8 top codes to match 32x32 bottom resolution\n        top_up = F.interpolate(top_q, size=bottom_feat.shape[-2:], mode=\u0027nearest\u0027)\n        combined = torch.cat([bottom_feat, top_up], dim=1)  # (B, 2*C, 32, 32)\n        return self.condition_proj(combined)                # (B, C,   32, 32)\n\ntorch.manual_seed(0)\nenc   = BottomConditionedEncoder(embed_dim=64, hidden=128)\nb_raw = torch.randn(2, 64, 32, 32)  # raw bottom encoder output\nt_q   = torch.randn(2, 64,  8,  8)  # quantized top codes\nconditioned = enc(b_raw, t_q)       # (2, 64, 32, 32)\nprint(f\u0027Bottom raw:       {b_raw.shape}\u0027)\nprint(f\u0027Top upsampled to: {F.interpolate(t_q, size=(32,32)).shape}\u0027)\nprint(f\u0027Conditioned feat: {conditioned.shape}\u0027)  # ready for VQ lookup"},{"type":"heading","level":2,"content":"Decoder Path"},{"type":"text","content":"The VQ-VAE-2 decoder reconstructs images top-down. The 8x8 top quantized codes are first decoded by a small network that upsamples them to 32x32 feature maps. These decoded top features are then concatenated with the 32x32 bottom quantized codes, and a final decoder network upsamples the combined representation from 32x32 back to 256x256 RGB. The top-decoded features provide global structure guidance; the bottom codes inject local detail. This two-path merge allows the decoder to benefit from both levels of abstraction simultaneously."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass TopDownDecoder(nn.Module):\n    \"\"\"Decodes: top codes (8x8) -\u003e upsample -\u003e merge with bottom codes (32x32) -\u003e image.\"\"\"\n    def __init__(self, embed_dim=64, hidden=128, out_ch=3):\n        super().__init__()\n        self.top_dec = nn.Sequential(\n            nn.Conv2d(embed_dim, hidden, 3, 1, 1), nn.ReLU(),\n            nn.Upsample(scale_factor=4, mode=\u0027nearest\u0027),  # 8x8  -\u003e 32x32\n            nn.Conv2d(hidden, embed_dim, 3, 1, 1), nn.ReLU()\n        )\n        self.final_dec = nn.Sequential(\n            nn.Conv2d(embed_dim * 2, hidden, 3, 1, 1), nn.ReLU(),\n            nn.Upsample(scale_factor=4, mode=\u0027nearest\u0027),  # 32x32 -\u003e 128x128\n            nn.Conv2d(hidden, hidden, 3, 1, 1), nn.ReLU(),\n            nn.Upsample(scale_factor=2, mode=\u0027nearest\u0027),  # 128x128 -\u003e 256x256\n            nn.Conv2d(hidden, out_ch, 3, 1, 1), nn.Tanh()\n        )\n\n    def forward(self, top_q, bottom_q):\n        top_decoded = self.top_dec(top_q)                      # (B, C, 32, 32)\n        combined    = torch.cat([top_decoded, bottom_q], dim=1) # (B, 2C, 32, 32)\n        return self.final_dec(combined)                        # (B, 3, 256, 256)\n\ntorch.manual_seed(0)\ndecoder  = TopDownDecoder()\ntop_q    = torch.randn(2, 64,  8,  8)\nbottom_q = torch.randn(2, 64, 32, 32)\nrecon    = decoder(top_q, bottom_q)\nprint(f\u0027Top codes:   {top_q.shape}\u0027)     # (2, 64, 8, 8)\nprint(f\u0027Bottom codes:{bottom_q.shape}\u0027)  # (2, 64, 32, 32)\nprint(f\u0027Reconstruction: {recon.shape}\u0027)  # (2, 3, 256, 256)"},{"type":"heading","level":2,"content":"Two-Stage Prior Models"},{"type":"text","content":"Generation with VQ-VAE-2 requires sampling discrete codes and decoding them — the VQ-VAE itself provides no generative prior. VQ-VAE-2 uses PixelSnail, a convolutional autoregressive model with attention, as a prior at each level. Stage 1: a PixelSnail top prior models p(z_top | class) autoregressively over the 8x8 = 64 top tokens. Stage 2: a conditioned PixelSnail bottom prior models p(z_bottom | z_top, class) autoregressively over the 1024 bottom tokens at 32x32, conditioned on the fully sampled top codes. Once both code maps are sampled, the VQ-VAE-2 decoder produces the final 256x256 image. The two-stage approach allows the top prior to establish global coherence before the bottom prior fills in local details."},{"type":"list","ordered":false,"items":["Top prior: PixelSnail over 8x8=64 discrete tokens; receptive field covers the full 8x8 grid via global self-attention.","Bottom prior: conditioned PixelSnail over 32x32=1024 tokens; top codes are embedded and used as context via cross-attention.","Sampling order: sample all 64 top tokens first (row-major autoregressive), then sample all 1024 bottom tokens conditioned on sampled top.","Class conditioning: class label embedding is added to both top and bottom PixelSnail inputs, enabling class-conditional generation.","FID ~2.5 on class-conditional ImageNet 256x256, competitive with BigGAN while using a fundamentally different (non-adversarial) training objective."]},{"type":"heading","level":2,"content":"VQGAN and Beyond"},{"type":"text","content":"VQGAN (Esser et al. 2021) upgrades the VQ-VAE reconstruction quality by adding a PatchGAN adversarial discriminator and a VGG perceptual loss to the standard commitment + reconstruction objective. The discriminator pushes the decoder to produce perceptually sharp outputs rather than blurry MSE-optimal reconstructions. Critically, VQGAN also replaces PixelSnail with a GPT-style Transformer as the prior — the discrete tokens produced by the VQGAN encoder become a sequence modeled by a causal Transformer, enabling much longer-range dependencies. DALL-E v1 used exactly this architecture: a VQGAN tokenizer (256 image tokens at 32x32 from a 256x256 image) paired with a GPT-style Transformer conditioned on text tokens. Modern systems extend further: MAGVIT-v2 uses improved lookup-free quantization and an LLM-style masked prior, while LlamaGen applies LLaMA-style autoregressive Transformers to VQ image tokens with competitive FID."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\nfrom torchvision.models import vgg16\n\nclass PatchGANDiscriminator(nn.Module):\n    \"\"\"70x70 PatchGAN: classifies overlapping image patches as real/fake.\"\"\"\n    def __init__(self, in_ch=3, ndf=64):\n        super().__init__()\n        self.net = nn.Sequential(\n            nn.Conv2d(in_ch,    ndf,   4, 2, 1), nn.LeakyReLU(0.2, True),\n            nn.Conv2d(ndf,   ndf*2, 4, 2, 1, bias=False), nn.BatchNorm2d(ndf*2), nn.LeakyReLU(0.2, True),\n            nn.Conv2d(ndf*2, ndf*4, 4, 2, 1, bias=False), nn.BatchNorm2d(ndf*4), nn.LeakyReLU(0.2, True),\n            nn.Conv2d(ndf*4, ndf*8, 4, 1, 1, bias=False), nn.BatchNorm2d(ndf*8), nn.LeakyReLU(0.2, True),\n            nn.Conv2d(ndf*8, 1, 4, 1, 1)  # patch-level logits\n        )\n    def forward(self, x):\n        return self.net(x)\n\ndef perceptual_loss(vgg_feats, recon, target, layers=(3, 8, 15)):\n    loss, x, y = 0.0, recon, target\n    for i, layer in enumerate(vgg_feats):\n        x, y = layer(x), layer(y)\n        if i in layers:\n            loss = loss + F.mse_loss(x, y)\n    return loss\n\ndef vqgan_loss(recon, target, disc, vgg_feats, cb_loss, lam_d=0.8, lam_p=1.0):\n    rec   = F.l1_loss(recon, target)\n    perc  = perceptual_loss(vgg_feats, recon.detach(), target.detach())\n    fake  = disc(recon)\n    adv   = F.binary_cross_entropy_with_logits(fake, torch.ones_like(fake))\n    return rec + lam_p * perc + lam_d * adv + cb_loss\n\ndisc = PatchGANDiscriminator()\nvgg  = vgg16(weights=None)\nrecon, target = torch.randn(2, 3, 256, 256), torch.randn(2, 3, 256, 256)\nloss = vqgan_loss(recon, target, disc, vgg.features, cb_loss=torch.tensor(0.05))\nprint(f\u0027VQGAN total loss: {loss.item():.4f}\u0027)\nprint(\u0027L1 + VGG perceptual + PatchGAN adversarial + codebook commitment\u0027)"},{"type":"table","headers":["Model","Levels","Prior","Resolution","FID (ImageNet 256)","Tokens / Image"],"rows":[["VQ-VAE","1","PixelCNN","32x32 native (upsampled)","~67 (32x32)","32x32 = 1024"],["VQ-VAE-2","2 (8x8 + 32x32)","PixelSnail (two-stage)","256x256","~2.5 (class-cond)","64 top + 1024 bottom"],["VQGAN","1","GPT Transformer","256x256","~7.9 (unconditional)","16x16 = 256"],["DALL-E v1","1 (VQGAN tokens)","GPT-3 style Transformer (text-cond)","256x256","~17.9 (zero-shot)","32x32 = 1024"],["MAGVIT-v2","1 (lookup-free VQ)","MaskGIT / LLM masked prior","256x256","~1.78 (class-cond)","16x16 = 256"]]},{"type":"callout","variant":"tip","title":"Training Order Matters","content":"Train the VQ-VAE reconstruction model completely before training the PixelSnail priors — the prior quality depends on stable, well-utilized codebooks. If you train the prior on a still-evolving codebook, the token distribution shifts under the prior and you must retrain from scratch. Monitor codebook utilization (fraction of active codes) during VQ-VAE training; utilization below 50% signals codebook collapse and requires a reset or EMA updates before proceeding to prior training."},{"type":"heading","level":2,"content":"Practical Guidance"},{"type":"text","content":"VQ-VAE-2 training has several failure modes to watch for. Codebook collapse — where most codes are never selected — is the most common issue. It occurs when the encoder variance is much smaller than the codebook spread, causing the same small subset of codes to win every nearest-neighbor lookup. Remedies include exponential moving average (EMA) codebook updates (instead of gradient-based), codebook reset (reinitialize dead codes to random encoder outputs), and reducing the commitment loss weight. The straight-through estimator gradient only approximates the true gradient; reparameterization-free quantization methods (MAGVIT-v2\u0027s lookup-free quantization) avoid this approximation entirely."},{"type":"list","ordered":false,"items":["Use EMA codebook updates: e_i \u003c- decay * e_i + (1-decay) * mean(assigned z) gives smoother utilization than gradient-based commitment loss.","Monitor codebook perplexity per level: healthy utilization targets ~70-80% of codes active; collapse shows perplexity \u003c 10 out of 512.","Bottom prior is the bottleneck: 1024 tokens autoregressively requires O(1024^2) attention; use local/dilated attention or Transformers with linear complexity.","Separate learning rates: VQ-VAE encoder/decoder benefit from 1e-4; PixelSnail priors train stably at 3e-4 with gradient clipping at 1.0.","For VQGAN: apply adaptive discriminator weighting — scale the adversarial loss by ||grad_last_dec(L_rec)|| / ||grad_last_dec(L_adv)||, preventing the GAN term from dominating early training."]},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"VQ-VAE-2 demonstrates that hierarchical discrete representations can match or exceed continuous latent models at high resolution without adversarial training in the reconstruction stage. The separation of global structure (top level, 8x8) from local detail (bottom level, 32x32) — with bottom encoding conditioned on top codes — is the architectural insight that makes 256x256 generation feasible. The two-stage prior training (top PixelSnail first, then conditioned bottom PixelSnail) is the generative mechanism. Subsequent work (VQGAN, DALL-E v1, MAGVIT-v2, LlamaGen) all follow the same paradigm of discrete image tokenization followed by a powerful sequence prior, with improvements in tokenizer quality (perceptual loss, adversarial training, lookup-free quantization) and prior expressiveness (Transformers over PixelCNNs)."},{"type":"list","ordered":false,"items":["Two codebook levels with conditioning: bottom quantization conditioned on top codes means each level has a well-defined, non-overlapping role.","Straight-through estimator makes discrete quantization end-to-end differentiable by passing gradients through the argmin as if it were identity.","Two-stage autoregressive prior: sample top 8x8 tokens first (global), then bottom 32x32 tokens conditioned on top (local detail).","VQGAN upgrade: replacing MSE/commitment loss with perceptual + adversarial loss dramatically sharpens reconstruction quality with no change to the discrete bottleneck.","Modern trajectory: VQ-VAE-2 -\u003e VQGAN -\u003e DALL-E v1 -\u003e MAGVIT-v2 / LlamaGen; all share discrete tokenization + sequence prior, differing in tokenizer quality and prior architecture."]},{"type":"divider"}]"
---
# VQ-VAE-2 — Hierarchical Discrete Latents for High-Resolution Generation

VQ-VAE-2 (Razavi et al. 2019) extends the original VQ-VAE to high-resolution image synthesis by introducing a hierarchy of discrete latent codes. A single codebook at one resolution cannot simultaneously capture both global image structure (object layout, colour palette) and local fine details (textures, edges). Two levels solve this: a top level at 8x8 encodes coarse global information, and a bottom level at 32x32 encodes local detail conditioned on the already-quantized top representation. The result is 256x256 class-conditional generation at FID ~2.5 on ImageNet — competitive with BigGAN at the time — using a two-stage discrete autoregressive prior.

## Introduction: Hierarchical Motivation

The original VQ-VAE used a single-level codebook and was limited to 32x32 or 64x64 generation. Scaling to 256x256 with one codebook forces a tradeoff: a large spatial grid preserves local detail but the codebook must span the entire space of image patches; a small grid loses spatial resolution. Hierarchical representation solves this by factorising image information across levels. The top level need only describe scene-level structure — which regions contain foreground objects, approximate colour distribution, dominant shapes — while the bottom level fills in local texture conditioned on that global context. This mirrors how humans perceive images: global scene understanding precedes local detail.

## Two-Level Architecture

The VQ-VAE-2 encoder-decoder pair has two quantization stages with separate codebooks. The bottom encoder maps 256x256 images to 32x32 feature maps capturing local detail. The top encoder further compresses 32x32 features to 8x8, capturing global structure. Each level has its own codebook (typically 512 entries each, embedding dimension 64). During encoding, top features are quantized first; the quantized top codes are then upsampled and concatenated to the bottom features before bottom quantization, so the bottom codebook only needs to represent residual local information not already explained by the top. The decoder reverses this process top-down.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class VectorQuantize(nn.Module):
    def __init__(self, codebook_size=512, embed_dim=64):
        super().__init__()
        self.codebook = nn.Embedding(codebook_size, embed_dim)

    def forward(self, z):
        B, C, H, W = z.shape
        z_flat = z.permute(0, 2, 3, 1).reshape(-1, C)
        dist = (z_flat.unsqueeze(1) - self.codebook.weight.unsqueeze(0)).pow(2).sum(-1)
        indices = dist.argmin(dim=1)
        z_q = self.codebook(indices).reshape(B, H, W, C).permute(0, 3, 1, 2)
        z_q = z + (z_q - z).detach()   # straight-through estimator
        return z_q, indices.reshape(B, H, W)

class HierarchicalVQVAE(nn.Module):
    def __init__(self, in_ch=3, hidden=128, codebook_size=512, embed_dim=64):
        super().__init__()
        self.bottom_enc = nn.Sequential(
            nn.Conv2d(in_ch, hidden, 4, 2, 1), nn.ReLU(),
            nn.Conv2d(hidden, hidden, 4, 2, 1), nn.ReLU(),
            nn.Conv2d(hidden, hidden, 4, 2, 1), nn.ReLU(),
            nn.Conv2d(hidden, embed_dim, 1)        # 256->32 (3 strides of 2)
        )
        self.top_enc = nn.Sequential(
            nn.Conv2d(embed_dim, hidden, 4, 2, 1), nn.ReLU(),
            nn.Conv2d(hidden, hidden, 4, 2, 1), nn.ReLU(),
            nn.Conv2d(hidden, embed_dim, 1)        # 32->8 (2 strides of 2)
        )
        self.vq_top    = VectorQuantize(codebook_size, embed_dim)
        self.vq_bottom = VectorQuantize(codebook_size, embed_dim)

torch.manual_seed(0)
model = HierarchicalVQVAE()
x = torch.randn(2, 3, 256, 256)
b_feat = model.bottom_enc(x)        # (2, 64, 32, 32)
t_feat = model.top_enc(b_feat)      # (2, 64,  8,  8)
t_q, t_idx = model.vq_top(t_feat)
print(f'Top quantized: {t_q.shape}, indices: {t_idx.shape}')  # (2,64,8,8), (2,8,8)
```

## Top-Level Encoding

The top encoder takes the 32x32 bottom feature map as input and applies two further stride-2 convolutions to reach 8x8. This 8x8 top representation is quantized against the top codebook using nearest-neighbor lookup in embedding space (512 entries). The result is 64 discrete tokens per image — enough to represent coarse semantic layout without redundancy. Because the top codebook is small (8x8 = 64 tokens), PixelSnail can model its prior autoregressively in reasonable time: a 64-token sequence is tractable for a convolutional autoregressive model with masking.

## Bottom-Level Conditioning

The key innovation in VQ-VAE-2 is that bottom quantization is conditioned on the top codes. After computing the top quantized codes t_q at 8x8, they are upsampled (via nearest-neighbor interpolation) to 32x32 and concatenated channel-wise with the raw bottom encoder features. A learned projection then maps the combined representation to the embedding space before bottom VQ lookup. This means the bottom codebook only needs to encode residual local information not already captured by the top level — a much easier task than encoding everything from scratch. The bottom codes carry local textures, edge orientations, and fine colour variations.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class BottomConditionedEncoder(nn.Module):
    """Encodes bottom features conditioned on upsampled top quantized codes."""
    def __init__(self, embed_dim=64, hidden=128):
        super().__init__()
        self.condition_proj = nn.Sequential(
            nn.Conv2d(embed_dim * 2, hidden, 3, 1, 1), nn.ReLU(),
            nn.Conv2d(hidden, embed_dim, 1)
        )

    def forward(self, bottom_feat, top_q):
        # Upsample 8x8 top codes to match 32x32 bottom resolution
        top_up = F.interpolate(top_q, size=bottom_feat.shape[-2:], mode='nearest')
        combined = torch.cat([bottom_feat, top_up], dim=1)  # (B, 2*C, 32, 32)
        return self.condition_proj(combined)                # (B, C,   32, 32)

torch.manual_seed(0)
enc   = BottomConditionedEncoder(embed_dim=64, hidden=128)
b_raw = torch.randn(2, 64, 32, 32)  # raw bottom encoder output
t_q   = torch.randn(2, 64,  8,  8)  # quantized top codes
conditioned = enc(b_raw, t_q)       # (2, 64, 32, 32)
print(f'Bottom raw:       {b_raw.shape}')
print(f'Top upsampled to: {F.interpolate(t_q, size=(32,32)).shape}')
print(f'Conditioned feat: {conditioned.shape}')  # ready for VQ lookup
```

## Decoder Path

The VQ-VAE-2 decoder reconstructs images top-down. The 8x8 top quantized codes are first decoded by a small network that upsamples them to 32x32 feature maps. These decoded top features are then concatenated with the 32x32 bottom quantized codes, and a final decoder network upsamples the combined representation from 32x32 back to 256x256 RGB. The top-decoded features provide global structure guidance; the bottom codes inject local detail. This two-path merge allows the decoder to benefit from both levels of abstraction simultaneously.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class TopDownDecoder(nn.Module):
    """Decodes: top codes (8x8) -> upsample -> merge with bottom codes (32x32) -> image."""
    def __init__(self, embed_dim=64, hidden=128, out_ch=3):
        super().__init__()
        self.top_dec = nn.Sequential(
            nn.Conv2d(embed_dim, hidden, 3, 1, 1), nn.ReLU(),
            nn.Upsample(scale_factor=4, mode='nearest'),  # 8x8  -> 32x32
            nn.Conv2d(hidden, embed_dim, 3, 1, 1), nn.ReLU()
        )
        self.final_dec = nn.Sequential(
            nn.Conv2d(embed_dim * 2, hidden, 3, 1, 1), nn.ReLU(),
            nn.Upsample(scale_factor=4, mode='nearest'),  # 32x32 -> 128x128
            nn.Conv2d(hidden, hidden, 3, 1, 1), nn.ReLU(),
            nn.Upsample(scale_factor=2, mode='nearest'),  # 128x128 -> 256x256
            nn.Conv2d(hidden, out_ch, 3, 1, 1), nn.Tanh()
        )

    def forward(self, top_q, bottom_q):
        top_decoded = self.top_dec(top_q)                      # (B, C, 32, 32)
        combined    = torch.cat([top_decoded, bottom_q], dim=1) # (B, 2C, 32, 32)
        return self.final_dec(combined)                        # (B, 3, 256, 256)

torch.manual_seed(0)
decoder  = TopDownDecoder()
top_q    = torch.randn(2, 64,  8,  8)
bottom_q = torch.randn(2, 64, 32, 32)
recon    = decoder(top_q, bottom_q)
print(f'Top codes:   {top_q.shape}')     # (2, 64, 8, 8)
print(f'Bottom codes:{bottom_q.shape}')  # (2, 64, 32, 32)
print(f'Reconstruction: {recon.shape}')  # (2, 3, 256, 256)
```

## Two-Stage Prior Models

Generation with VQ-VAE-2 requires sampling discrete codes and decoding them — the VQ-VAE itself provides no generative prior. VQ-VAE-2 uses PixelSnail, a convolutional autoregressive model with attention, as a prior at each level. Stage 1: a PixelSnail top prior models p(z_top | class) autoregressively over the 8x8 = 64 top tokens. Stage 2: a conditioned PixelSnail bottom prior models p(z_bottom | z_top, class) autoregressively over the 1024 bottom tokens at 32x32, conditioned on the fully sampled top codes. Once both code maps are sampled, the VQ-VAE-2 decoder produces the final 256x256 image. The two-stage approach allows the top prior to establish global coherence before the bottom prior fills in local details.

- Top prior: PixelSnail over 8x8=64 discrete tokens; receptive field covers the full 8x8 grid via global self-attention.
- Bottom prior: conditioned PixelSnail over 32x32=1024 tokens; top codes are embedded and used as context via cross-attention.
- Sampling order: sample all 64 top tokens first (row-major autoregressive), then sample all 1024 bottom tokens conditioned on sampled top.
- Class conditioning: class label embedding is added to both top and bottom PixelSnail inputs, enabling class-conditional generation.
- FID ~2.5 on class-conditional ImageNet 256x256, competitive with BigGAN while using a fundamentally different (non-adversarial) training objective.

## VQGAN and Beyond

VQGAN (Esser et al. 2021) upgrades the VQ-VAE reconstruction quality by adding a PatchGAN adversarial discriminator and a VGG perceptual loss to the standard commitment + reconstruction objective. The discriminator pushes the decoder to produce perceptually sharp outputs rather than blurry MSE-optimal reconstructions. Critically, VQGAN also replaces PixelSnail with a GPT-style Transformer as the prior — the discrete tokens produced by the VQGAN encoder become a sequence modeled by a causal Transformer, enabling much longer-range dependencies. DALL-E v1 used exactly this architecture: a VQGAN tokenizer (256 image tokens at 32x32 from a 256x256 image) paired with a GPT-style Transformer conditioned on text tokens. Modern systems extend further: MAGVIT-v2 uses improved lookup-free quantization and an LLM-style masked prior, while LlamaGen applies LLaMA-style autoregressive Transformers to VQ image tokens with competitive FID.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F
from torchvision.models import vgg16

class PatchGANDiscriminator(nn.Module):
    """70x70 PatchGAN: classifies overlapping image patches as real/fake."""
    def __init__(self, in_ch=3, ndf=64):
        super().__init__()
        self.net = nn.Sequential(
            nn.Conv2d(in_ch,    ndf,   4, 2, 1), nn.LeakyReLU(0.2, True),
            nn.Conv2d(ndf,   ndf*2, 4, 2, 1, bias=False), nn.BatchNorm2d(ndf*2), nn.LeakyReLU(0.2, True),
            nn.Conv2d(ndf*2, ndf*4, 4, 2, 1, bias=False), nn.BatchNorm2d(ndf*4), nn.LeakyReLU(0.2, True),
            nn.Conv2d(ndf*4, ndf*8, 4, 1, 1, bias=False), nn.BatchNorm2d(ndf*8), nn.LeakyReLU(0.2, True),
            nn.Conv2d(ndf*8, 1, 4, 1, 1)  # patch-level logits
        )
    def forward(self, x):
        return self.net(x)

def perceptual_loss(vgg_feats, recon, target, layers=(3, 8, 15)):
    loss, x, y = 0.0, recon, target
    for i, layer in enumerate(vgg_feats):
        x, y = layer(x), layer(y)
        if i in layers:
            loss = loss + F.mse_loss(x, y)
    return loss

def vqgan_loss(recon, target, disc, vgg_feats, cb_loss, lam_d=0.8, lam_p=1.0):
    rec   = F.l1_loss(recon, target)
    perc  = perceptual_loss(vgg_feats, recon.detach(), target.detach())
    fake  = disc(recon)
    adv   = F.binary_cross_entropy_with_logits(fake, torch.ones_like(fake))
    return rec + lam_p * perc + lam_d * adv + cb_loss

disc = PatchGANDiscriminator()
vgg  = vgg16(weights=None)
recon, target = torch.randn(2, 3, 256, 256), torch.randn(2, 3, 256, 256)
loss = vqgan_loss(recon, target, disc, vgg.features, cb_loss=torch.tensor(0.05))
print(f'VQGAN total loss: {loss.item():.4f}')
print('L1 + VGG perceptual + PatchGAN adversarial + codebook commitment')
```

| Model | Levels | Prior | Resolution | FID (ImageNet 256) | Tokens / Image |
| --- | --- | --- | --- | --- | --- |
| VQ-VAE | 1 | PixelCNN | 32x32 native (upsampled) | ~67 (32x32) | 32x32 = 1024 |
| VQ-VAE-2 | 2 (8x8 + 32x32) | PixelSnail (two-stage) | 256x256 | ~2.5 (class-cond) | 64 top + 1024 bottom |
| VQGAN | 1 | GPT Transformer | 256x256 | ~7.9 (unconditional) | 16x16 = 256 |
| DALL-E v1 | 1 (VQGAN tokens) | GPT-3 style Transformer (text-cond) | 256x256 | ~17.9 (zero-shot) | 32x32 = 1024 |
| MAGVIT-v2 | 1 (lookup-free VQ) | MaskGIT / LLM masked prior | 256x256 | ~1.78 (class-cond) | 16x16 = 256 |

> **Training Order Matters**: Train the VQ-VAE reconstruction model completely before training the PixelSnail priors — the prior quality depends on stable, well-utilized codebooks. If you train the prior on a still-evolving codebook, the token distribution shifts under the prior and you must retrain from scratch. Monitor codebook utilization (fraction of active codes) during VQ-VAE training; utilization below 50% signals codebook collapse and requires a reset or EMA updates before proceeding to prior training.

## Practical Guidance

VQ-VAE-2 training has several failure modes to watch for. Codebook collapse — where most codes are never selected — is the most common issue. It occurs when the encoder variance is much smaller than the codebook spread, causing the same small subset of codes to win every nearest-neighbor lookup. Remedies include exponential moving average (EMA) codebook updates (instead of gradient-based), codebook reset (reinitialize dead codes to random encoder outputs), and reducing the commitment loss weight. The straight-through estimator gradient only approximates the true gradient; reparameterization-free quantization methods (MAGVIT-v2's lookup-free quantization) avoid this approximation entirely.

- Use EMA codebook updates: e_i <- decay * e_i + (1-decay) * mean(assigned z) gives smoother utilization than gradient-based commitment loss.
- Monitor codebook perplexity per level: healthy utilization targets ~70-80% of codes active; collapse shows perplexity < 10 out of 512.
- Bottom prior is the bottleneck: 1024 tokens autoregressively requires O(1024^2) attention; use local/dilated attention or Transformers with linear complexity.
- Separate learning rates: VQ-VAE encoder/decoder benefit from 1e-4; PixelSnail priors train stably at 3e-4 with gradient clipping at 1.0.
- For VQGAN: apply adaptive discriminator weighting — scale the adversarial loss by ||grad_last_dec(L_rec)|| / ||grad_last_dec(L_adv)||, preventing the GAN term from dominating early training.

## Key Takeaways

VQ-VAE-2 demonstrates that hierarchical discrete representations can match or exceed continuous latent models at high resolution without adversarial training in the reconstruction stage. The separation of global structure (top level, 8x8) from local detail (bottom level, 32x32) — with bottom encoding conditioned on top codes — is the architectural insight that makes 256x256 generation feasible. The two-stage prior training (top PixelSnail first, then conditioned bottom PixelSnail) is the generative mechanism. Subsequent work (VQGAN, DALL-E v1, MAGVIT-v2, LlamaGen) all follow the same paradigm of discrete image tokenization followed by a powerful sequence prior, with improvements in tokenizer quality (perceptual loss, adversarial training, lookup-free quantization) and prior expressiveness (Transformers over PixelCNNs).

- Two codebook levels with conditioning: bottom quantization conditioned on top codes means each level has a well-defined, non-overlapping role.
- Straight-through estimator makes discrete quantization end-to-end differentiable by passing gradients through the argmin as if it were identity.
- Two-stage autoregressive prior: sample top 8x8 tokens first (global), then bottom 32x32 tokens conditioned on top (local detail).
- VQGAN upgrade: replacing MSE/commitment loss with perceptual + adversarial loss dramatically sharpens reconstruction quality with no change to the discrete bottleneck.
- Modern trajectory: VQ-VAE-2 -> VQGAN -> DALL-E v1 -> MAGVIT-v2 / LlamaGen; all share discrete tokenization + sequence prior, differing in tokenizer quality and prior architecture.

---

