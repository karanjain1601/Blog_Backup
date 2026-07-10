---
title: "Latent Diffusion Models — Compress Then Diffuse"
slug: "latent-diffusion-models"
description: "Understand why pixel-space diffusion is computationally expensive, implement a KL-regularized VAE for image compression, run the diffusion process in 64x64 latent space instead of 512x512 pixel space, build cross-attention conditioning for text, and compare compute costs across diffusion architectures."
tags: ["deep-learning", "generative-models", "diffusion-models"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Latent diffusion models (LDM, Rombach et al. 2022) solve the fundamental compute problem of pixel-space diffusion: at 512×512 resolution, each U-Net forward pass processes 786,432 values. By first compressing to a 64×64 latent (4× spatial downsampling), the diffusion process operates on 16,384 values — a 48× reduction in spatial elements. The self-attention cost drops by 48² = 2304×. The autoencoder compression is learned to be perceptual — preserving visual information, not just pixel values — so the latent space faithfully captures image content at a fraction of the compute cost."},{"type":"heading","level":2,"content":"Why Pixel-Space Diffusion is Expensive"},{"type":"text","content":"U-Net self-attention has O(n²) cost in the number of spatial positions n. At 64×64 resolution, n=4096; at 512×512, n=262144. The attention cost ratio is (262144/4096)² = 4096× — four thousand times more expensive at full resolution. For a T=1000 step DDPM on 512×512 images, each training step requires a full U-Net forward and backward pass at this cost. Pixel-space models like DALL-E 1 and early DDPM worked at 256×256 or lower; generating at 512×512 or higher required architectural innovations — specifically, moving to latent space."},{"type":"heading","level":2,"content":"LDM Architecture — Encode, Diffuse, Decode"},{"type":"text","content":"The LDM pipeline has three stages: (1) Encode: E(x) → z, mapping a 512×512 image to a 64×64×4 latent (4× spatial downsampling, 3→4 channels). (2) Diffuse: train a U-Net ε_θ(z_t, t, c) in the latent space z ∈ ℝ^{64×64×4}. (3) Decode: D(z_0) → x, mapping the denoised latent back to pixel space. The autoencoder (E, D) is trained once with perceptual loss + GAN discriminator; the diffusion U-Net is trained separately on encoded latents. At inference, only the diffusion U-Net and decoder are needed — the encoder is used only for editing or inversion workflows."},{"type":"heading","level":2,"content":"Autoencoder — VQ and KL Regularization"},{"type":"text","content":"LDM uses two autoencoder variants. VQ-regularized (LDM-VQ): the latent is quantized to a discrete codebook (VQ-VAE style), producing a sequence of integers. This enables autoregressive modeling of the latent. KL-regularized (LDM-KL): the encoder outputs a Gaussian distribution q(z|x) = N(μ, σ²) with a KL penalty KL(q(z|x) || N(0,I)) — a standard VAE. The KL weight is kept very small (e.g. 1×10⁻⁶) to prioritize reconstruction quality over regularization. Stable Diffusion uses KL-regularization with f=8 downsampling (512→64) and 4 latent channels."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass LDMAutoencoder(nn.Module):\n    \"\"\"Simplified KL-regularized autoencoder for LDM.\"\"\"\n    def __init__(self, img_ch=3, latent_ch=4, base_ch=32):\n        super().__init__()\n        self.encoder = nn.Sequential(\n            nn.Conv2d(img_ch, base_ch, 4, 2, 1), nn.SiLU(),  # 2x downsample\n            nn.Conv2d(base_ch, base_ch*2, 4, 2, 1), nn.SiLU(),  # 4x down\n            nn.Conv2d(base_ch*2, latent_ch*2, 3, 1, 1)  # mu and logvar\n        )\n        self.decoder = nn.Sequential(\n            nn.Conv2d(latent_ch, base_ch*2, 3, 1, 1), nn.SiLU(),\n            nn.ConvTranspose2d(base_ch*2, base_ch, 4, 2, 1), nn.SiLU(),  # 2x up\n            nn.ConvTranspose2d(base_ch, img_ch, 4, 2, 1), nn.Tanh()  # 4x up\n        )\n\n    def encode(self, x):\n        h = self.encoder(x)\n        mu, logvar = h.chunk(2, dim=1)\n        return mu, logvar\n\n    def reparameterize(self, mu, logvar):\n        std = torch.exp(0.5 * logvar)\n        return mu + std * torch.randn_like(std)\n\n    def forward(self, x, kl_weight=1e-4):\n        mu, logvar = self.encode(x)\n        z = self.reparameterize(mu, logvar)\n        recon = self.decoder(z)\n        recon_loss = F.mse_loss(recon, x)\n        kl_loss = -0.5 * (1 + logvar - mu.pow(2) - logvar.exp()).mean()\n        return recon, recon_loss + kl_weight * kl_loss\n\ntorch.manual_seed(0)\nautoenc = LDMAutoencoder()\nx = torch.randn(2, 3, 32, 32)  # batch of 32x32 images\nrecon, loss = autoenc(x)\nprint(f\u0027Input: {x.shape}, Latent: {autoenc.encode(x)[0].shape}, Recon: {recon.shape}\u0027)\nprint(f\u0027AE loss: {loss.item():.4f}\u0027)"},{"type":"heading","level":2,"content":"Diffusion in Latent Space"},{"type":"text","content":"Once the autoencoder is trained, the latent space z = E(x) replaces the pixel space for the diffusion process. The latents are scaled to unit variance before diffusion training (z_scaled = z / std(z_train)), which ensures the noise schedule is meaningful. The U-Net ε_θ(z_t, t, c) processes 64×64×4 tensors instead of 512×512×3 — a 16× reduction in spatial area. The resulting model trains 4–16× faster per step and can run inference in seconds rather than minutes. Crucially, the perceptual compression by the autoencoder means 64×64 latents capture the same visual content as 512×512 pixels."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass LatentUNet(nn.Module):\n    \"\"\"Simplified U-Net for diffusion in latent space (no spatial attention shown).\"\"\"\n    def __init__(self, latent_ch=4, hidden=64, T=1000):\n        super().__init__()\n        self.time_embed = nn.Embedding(T, 32)\n        self.down1 = nn.Conv2d(latent_ch, hidden, 3, 1, 1)\n        self.down2 = nn.Conv2d(hidden, hidden*2, 4, 2, 1)  # 32x32\n        self.mid   = nn.Conv2d(hidden*2 + 32, hidden*2, 3, 1, 1)\n        self.up1   = nn.ConvTranspose2d(hidden*2, hidden, 4, 2, 1)\n        self.out   = nn.Conv2d(hidden + hidden, latent_ch, 3, 1, 1)\n        self.act   = nn.SiLU()\n\n    def forward(self, z_t, t):\n        B, C, H, W = z_t.shape\n        t_emb = self.time_embed(t)[:, :, None, None].expand(B, 32, H//2, W//2)\n        h1 = self.act(self.down1(z_t))             # (B, 64, H, W)\n        h2 = self.act(self.down2(h1))              # (B, 128, H/2, W/2)\n        h_mid = self.act(self.mid(torch.cat([h2, t_emb], dim=1)))\n        h_up = self.act(self.up1(h_mid))           # (B, 64, H, W)\n        return self.out(torch.cat([h_up, h1], dim=1))\n\ntorch.manual_seed(0)\nalpha_bar = torch.cumprod(1 - torch.linspace(1e-4, 0.02, 1000), dim=0)\nunet = LatentUNet()\nz = torch.randn(2, 4, 16, 16)  # latent at 16x16 (toy scale)\nt = torch.randint(0, 1000, (2,))\nab = alpha_bar[t][:, None, None, None]\neps = torch.randn_like(z)\nz_t = torch.sqrt(ab) * z + torch.sqrt(1 - ab) * eps\neps_pred = unet(z_t, t)\nloss = F.mse_loss(eps_pred, eps)\nprint(f\u0027Latent z: {z.shape}, Noisy z_t: {z_t.shape}\u0027)\nprint(f\u0027Diffusion loss in latent space: {loss.item():.4f}\u0027)"},{"type":"heading","level":2,"content":"Cross-Attention Conditioning"},{"type":"text","content":"LDM conditions the U-Net on text, class labels, or other signals via cross-attention. At each U-Net resolution, image feature maps are flattened to queries Q = W_Q·φ(z_t), and the condition (e.g. CLIP text embedding) is projected to keys K = W_K·τ_θ(c) and values V = W_V·τ_θ(c). The attention output Attention(Q,K,V) = softmax(QK^T/√d)·V is added back to the image features. This cross-attention mechanism is spatial: each image patch attends to the full text sequence, producing spatially variable conditioning. The attention maps are interpretable — they show which image regions each text token influences."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass SpatialCrossAttention(nn.Module):\n    \"\"\"Cross-attention: image latents (Q) attend to text features (K, V).\"\"\"\n    def __init__(self, latent_dim=64, context_dim=32, n_heads=4):\n        super().__init__()\n        self.n_heads = n_heads\n        self.head_dim = latent_dim // n_heads\n        self.to_q = nn.Linear(latent_dim, latent_dim)\n        self.to_k = nn.Linear(context_dim, latent_dim)\n        self.to_v = nn.Linear(context_dim, latent_dim)\n        self.to_out = nn.Linear(latent_dim, latent_dim)\n\n    def forward(self, x, context):\n        B, S, D = x.shape\n        T_ctx = context.shape[1]\n        H = self.n_heads\n        def reshape(t): return t.view(B, -1, H, self.head_dim).transpose(1, 2)\n        Q = reshape(self.to_q(x))\n        K = reshape(self.to_k(context))\n        V = reshape(self.to_v(context))\n        attn = F.softmax(Q @ K.transpose(-2,-1) / self.head_dim**0.5, dim=-1)\n        out = (attn @ V).transpose(1,2).reshape(B, S, D)\n        return self.to_out(out), attn\n\ntorch.manual_seed(0)\nB, S, T_ctx = 2, 64, 12  # 2 samples, 64 spatial tokens, 12 text tokens\nlatent_tokens = torch.randn(B, S, 64)\ntext_feats = torch.randn(B, T_ctx, 32)\nxattn = SpatialCrossAttention()\nout, attn_maps = xattn(latent_tokens, text_feats)\nprint(f\u0027Latent tokens: {latent_tokens.shape} -\u003e output: {out.shape}\u0027)\nprint(f\u0027Attention maps: {attn_maps.shape}  (B, heads, spatial, text_tokens)\u0027)\nprint(f\u0027Attention sum over text: {attn_maps[0, 0, :3, :].sum(dim=-1).tolist()}\u0027)"},{"type":"heading","level":2,"content":"Stable Diffusion as LDM Instance"},{"type":"text","content":"Stable Diffusion (Rombach et al. 2022) is an LDM with: (1) CLIP ViT-L/14 text encoder (768-dim embeddings, up to 77 tokens); (2) KL-regularized autoencoder with f=8 downsampling (512×512 → 64×64×4 latents); (3) U-Net with cross-attention conditioning at 32×32, 16×16, and 8×8 resolutions; (4) CFG at inference (w≈7.5). Training used LAION-5B (5B image-text pairs). The latent space dimensionality reduction (64×64×4 vs 512×512×3) enables training on consumer GPUs (24GB VRAM for batch size 4) at a cost ~50× lower than pixel-space equivalents. SD v1.5 has 860M parameters in the U-Net; SDXL has 2.6B."},{"type":"heading","level":2,"content":"Pixel-Space vs Latent Diffusion"},{"type":"code","language":"python","content":"import torch\nimport time\nimport numpy as np\n\ndef estimate_flops_and_time(resolution, latent_factor=1, batch=1, n_steps=50):\n    \"\"\"Rough estimate of diffusion inference cost at different resolutions.\"\"\"\n    spatial = (resolution // latent_factor) ** 2\n    # Self-attention cost O(spatial^2 * channels)\n    attn_cost = spatial ** 2 * 64  # proportional\n    # Conv cost O(spatial * channels^2 * kernel^2)\n    conv_cost = spatial * 64**2 * 9\n    step_cost = (attn_cost + conv_cost) / 1e9  # in GFLOPs (approx)\n    total_gflops = step_cost * n_steps * batch\n\n    mode = \u0027pixel-space\u0027 if latent_factor == 1 else f\u0027latent (f={latent_factor})\u0027\n    print(f\u0027{mode:20s} | res={resolution//latent_factor:3d}x{resolution//latent_factor:3d} \u0027\n          f\u0027| attn cost: {attn_cost/1e6:7.1f}M | total GFLOPs: {total_gflops:.1f}\u0027)\n    return total_gflops\n\nprint(f\u0027{\"Mode\":20s} | {\"Latent res\":12s} | {\"Attn cost\":13s} | {\"GFLOPs (50 steps)\"}\u0027 )\nprint(\u0027-\u0027 * 72)\nfor res, f in [(512, 1), (512, 4), (512, 8), (1024, 8)]:\n    estimate_flops_and_time(res, latent_factor=f)\nprint()\nprint(\u0027Latent f=8 reduces attention cost by 64^2 = 4096x vs pixel-space at 512x512\u0027)"},{"type":"table","headers":["Model","Latent type","Resolution","Latent size","Condition type","Training compute"],"rows":[["DDPM (Ho et al. 2020)","None — pixel space","256×256","256×256×3 pixels","Class label (embed)","High — pixel U-Net"],["LDM (Rombach et al. 2022)","KL-VAE or VQ-VAE","256–512×256–512","32–64×32–64×4","Text/class via cross-attn","~4–16× cheaper than pixel"],["Stable Diffusion 1.5","KL-VAE f=8","512×512","64×64×4","CLIP ViT-L/14 text","~50× cheaper than pixel SD"],["DALL-E 3 / SDXL","KL-VAE f=8","1024×1024","128×128×4","T5 / CLIP dual text encoder","~200× cheaper than naive pixel"]]},{"type":"callout","variant":"info","title":"Why Latent Space Works for Diffusion","content":"A perceptually-trained autoencoder (using LPIPS loss + GAN discriminator) compresses images into latents that preserve semantic and structural information while discarding high-frequency pixel noise. Diffusion in this perceptual latent space is efficient because the latent space is semantically smooth — small latent changes correspond to semantically meaningful image changes, making the score field easier to learn."},{"type":"list","ordered":false,"items":["Pixel-space self-attention at 512×512 costs 4096× more than at 64×64 — the primary motivation for latent diffusion.","KL-regularized autoencoder: small KL weight (1e-6) prioritizes reconstruction fidelity over posterior regularization.","Latent scaling: divide latents by std of the training set before diffusion training to match the noise schedule assumptions.","Cross-attention at multiple U-Net resolutions (32×32, 16×16, 8×8) enables spatially-grounded text conditioning.","Stable Diffusion = LDM + CLIP text encoder + CFG — each component is independently replaceable.","SDXL improves by using two CLIP encoders (ViT-L and ViT-G), increasing text capacity from 768 to 2048 dims."]},{"type":"divider"}]"
---
# Latent Diffusion Models — Compress Then Diffuse

Latent diffusion models (LDM, Rombach et al. 2022) solve the fundamental compute problem of pixel-space diffusion: at 512×512 resolution, each U-Net forward pass processes 786,432 values. By first compressing to a 64×64 latent (4× spatial downsampling), the diffusion process operates on 16,384 values — a 48× reduction in spatial elements. The self-attention cost drops by 48² = 2304×. The autoencoder compression is learned to be perceptual — preserving visual information, not just pixel values — so the latent space faithfully captures image content at a fraction of the compute cost.

## Why Pixel-Space Diffusion is Expensive

U-Net self-attention has O(n²) cost in the number of spatial positions n. At 64×64 resolution, n=4096; at 512×512, n=262144. The attention cost ratio is (262144/4096)² = 4096× — four thousand times more expensive at full resolution. For a T=1000 step DDPM on 512×512 images, each training step requires a full U-Net forward and backward pass at this cost. Pixel-space models like DALL-E 1 and early DDPM worked at 256×256 or lower; generating at 512×512 or higher required architectural innovations — specifically, moving to latent space.

## LDM Architecture — Encode, Diffuse, Decode

The LDM pipeline has three stages: (1) Encode: E(x) → z, mapping a 512×512 image to a 64×64×4 latent (4× spatial downsampling, 3→4 channels). (2) Diffuse: train a U-Net ε_θ(z_t, t, c) in the latent space z ∈ ℝ^{64×64×4}. (3) Decode: D(z_0) → x, mapping the denoised latent back to pixel space. The autoencoder (E, D) is trained once with perceptual loss + GAN discriminator; the diffusion U-Net is trained separately on encoded latents. At inference, only the diffusion U-Net and decoder are needed — the encoder is used only for editing or inversion workflows.

## Autoencoder — VQ and KL Regularization

LDM uses two autoencoder variants. VQ-regularized (LDM-VQ): the latent is quantized to a discrete codebook (VQ-VAE style), producing a sequence of integers. This enables autoregressive modeling of the latent. KL-regularized (LDM-KL): the encoder outputs a Gaussian distribution q(z|x) = N(μ, σ²) with a KL penalty KL(q(z|x) || N(0,I)) — a standard VAE. The KL weight is kept very small (e.g. 1×10⁻⁶) to prioritize reconstruction quality over regularization. Stable Diffusion uses KL-regularization with f=8 downsampling (512→64) and 4 latent channels.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class LDMAutoencoder(nn.Module):
    """Simplified KL-regularized autoencoder for LDM."""
    def __init__(self, img_ch=3, latent_ch=4, base_ch=32):
        super().__init__()
        self.encoder = nn.Sequential(
            nn.Conv2d(img_ch, base_ch, 4, 2, 1), nn.SiLU(),  # 2x downsample
            nn.Conv2d(base_ch, base_ch*2, 4, 2, 1), nn.SiLU(),  # 4x down
            nn.Conv2d(base_ch*2, latent_ch*2, 3, 1, 1)  # mu and logvar
        )
        self.decoder = nn.Sequential(
            nn.Conv2d(latent_ch, base_ch*2, 3, 1, 1), nn.SiLU(),
            nn.ConvTranspose2d(base_ch*2, base_ch, 4, 2, 1), nn.SiLU(),  # 2x up
            nn.ConvTranspose2d(base_ch, img_ch, 4, 2, 1), nn.Tanh()  # 4x up
        )

    def encode(self, x):
        h = self.encoder(x)
        mu, logvar = h.chunk(2, dim=1)
        return mu, logvar

    def reparameterize(self, mu, logvar):
        std = torch.exp(0.5 * logvar)
        return mu + std * torch.randn_like(std)

    def forward(self, x, kl_weight=1e-4):
        mu, logvar = self.encode(x)
        z = self.reparameterize(mu, logvar)
        recon = self.decoder(z)
        recon_loss = F.mse_loss(recon, x)
        kl_loss = -0.5 * (1 + logvar - mu.pow(2) - logvar.exp()).mean()
        return recon, recon_loss + kl_weight * kl_loss

torch.manual_seed(0)
autoenc = LDMAutoencoder()
x = torch.randn(2, 3, 32, 32)  # batch of 32x32 images
recon, loss = autoenc(x)
print(f'Input: {x.shape}, Latent: {autoenc.encode(x)[0].shape}, Recon: {recon.shape}')
print(f'AE loss: {loss.item():.4f}')
```

## Diffusion in Latent Space

Once the autoencoder is trained, the latent space z = E(x) replaces the pixel space for the diffusion process. The latents are scaled to unit variance before diffusion training (z_scaled = z / std(z_train)), which ensures the noise schedule is meaningful. The U-Net ε_θ(z_t, t, c) processes 64×64×4 tensors instead of 512×512×3 — a 16× reduction in spatial area. The resulting model trains 4–16× faster per step and can run inference in seconds rather than minutes. Crucially, the perceptual compression by the autoencoder means 64×64 latents capture the same visual content as 512×512 pixels.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class LatentUNet(nn.Module):
    """Simplified U-Net for diffusion in latent space (no spatial attention shown)."""
    def __init__(self, latent_ch=4, hidden=64, T=1000):
        super().__init__()
        self.time_embed = nn.Embedding(T, 32)
        self.down1 = nn.Conv2d(latent_ch, hidden, 3, 1, 1)
        self.down2 = nn.Conv2d(hidden, hidden*2, 4, 2, 1)  # 32x32
        self.mid   = nn.Conv2d(hidden*2 + 32, hidden*2, 3, 1, 1)
        self.up1   = nn.ConvTranspose2d(hidden*2, hidden, 4, 2, 1)
        self.out   = nn.Conv2d(hidden + hidden, latent_ch, 3, 1, 1)
        self.act   = nn.SiLU()

    def forward(self, z_t, t):
        B, C, H, W = z_t.shape
        t_emb = self.time_embed(t)[:, :, None, None].expand(B, 32, H//2, W//2)
        h1 = self.act(self.down1(z_t))             # (B, 64, H, W)
        h2 = self.act(self.down2(h1))              # (B, 128, H/2, W/2)
        h_mid = self.act(self.mid(torch.cat([h2, t_emb], dim=1)))
        h_up = self.act(self.up1(h_mid))           # (B, 64, H, W)
        return self.out(torch.cat([h_up, h1], dim=1))

torch.manual_seed(0)
alpha_bar = torch.cumprod(1 - torch.linspace(1e-4, 0.02, 1000), dim=0)
unet = LatentUNet()
z = torch.randn(2, 4, 16, 16)  # latent at 16x16 (toy scale)
t = torch.randint(0, 1000, (2,))
ab = alpha_bar[t][:, None, None, None]
eps = torch.randn_like(z)
z_t = torch.sqrt(ab) * z + torch.sqrt(1 - ab) * eps
eps_pred = unet(z_t, t)
loss = F.mse_loss(eps_pred, eps)
print(f'Latent z: {z.shape}, Noisy z_t: {z_t.shape}')
print(f'Diffusion loss in latent space: {loss.item():.4f}')
```

## Cross-Attention Conditioning

LDM conditions the U-Net on text, class labels, or other signals via cross-attention. At each U-Net resolution, image feature maps are flattened to queries Q = W_Q·φ(z_t), and the condition (e.g. CLIP text embedding) is projected to keys K = W_K·τ_θ(c) and values V = W_V·τ_θ(c). The attention output Attention(Q,K,V) = softmax(QK^T/√d)·V is added back to the image features. This cross-attention mechanism is spatial: each image patch attends to the full text sequence, producing spatially variable conditioning. The attention maps are interpretable — they show which image regions each text token influences.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class SpatialCrossAttention(nn.Module):
    """Cross-attention: image latents (Q) attend to text features (K, V)."""
    def __init__(self, latent_dim=64, context_dim=32, n_heads=4):
        super().__init__()
        self.n_heads = n_heads
        self.head_dim = latent_dim // n_heads
        self.to_q = nn.Linear(latent_dim, latent_dim)
        self.to_k = nn.Linear(context_dim, latent_dim)
        self.to_v = nn.Linear(context_dim, latent_dim)
        self.to_out = nn.Linear(latent_dim, latent_dim)

    def forward(self, x, context):
        B, S, D = x.shape
        T_ctx = context.shape[1]
        H = self.n_heads
        def reshape(t): return t.view(B, -1, H, self.head_dim).transpose(1, 2)
        Q = reshape(self.to_q(x))
        K = reshape(self.to_k(context))
        V = reshape(self.to_v(context))
        attn = F.softmax(Q @ K.transpose(-2,-1) / self.head_dim**0.5, dim=-1)
        out = (attn @ V).transpose(1,2).reshape(B, S, D)
        return self.to_out(out), attn

torch.manual_seed(0)
B, S, T_ctx = 2, 64, 12  # 2 samples, 64 spatial tokens, 12 text tokens
latent_tokens = torch.randn(B, S, 64)
text_feats = torch.randn(B, T_ctx, 32)
xattn = SpatialCrossAttention()
out, attn_maps = xattn(latent_tokens, text_feats)
print(f'Latent tokens: {latent_tokens.shape} -> output: {out.shape}')
print(f'Attention maps: {attn_maps.shape}  (B, heads, spatial, text_tokens)')
print(f'Attention sum over text: {attn_maps[0, 0, :3, :].sum(dim=-1).tolist()}')
```

## Stable Diffusion as LDM Instance

Stable Diffusion (Rombach et al. 2022) is an LDM with: (1) CLIP ViT-L/14 text encoder (768-dim embeddings, up to 77 tokens); (2) KL-regularized autoencoder with f=8 downsampling (512×512 → 64×64×4 latents); (3) U-Net with cross-attention conditioning at 32×32, 16×16, and 8×8 resolutions; (4) CFG at inference (w≈7.5). Training used LAION-5B (5B image-text pairs). The latent space dimensionality reduction (64×64×4 vs 512×512×3) enables training on consumer GPUs (24GB VRAM for batch size 4) at a cost ~50× lower than pixel-space equivalents. SD v1.5 has 860M parameters in the U-Net; SDXL has 2.6B.

## Pixel-Space vs Latent Diffusion

```python
import torch
import time
import numpy as np

def estimate_flops_and_time(resolution, latent_factor=1, batch=1, n_steps=50):
    """Rough estimate of diffusion inference cost at different resolutions."""
    spatial = (resolution // latent_factor) ** 2
    # Self-attention cost O(spatial^2 * channels)
    attn_cost = spatial ** 2 * 64  # proportional
    # Conv cost O(spatial * channels^2 * kernel^2)
    conv_cost = spatial * 64**2 * 9
    step_cost = (attn_cost + conv_cost) / 1e9  # in GFLOPs (approx)
    total_gflops = step_cost * n_steps * batch

    mode = 'pixel-space' if latent_factor == 1 else f'latent (f={latent_factor})'
    print(f'{mode:20s} | res={resolution//latent_factor:3d}x{resolution//latent_factor:3d} '
          f'| attn cost: {attn_cost/1e6:7.1f}M | total GFLOPs: {total_gflops:.1f}')
    return total_gflops

print(f'{"Mode":20s} | {"Latent res":12s} | {"Attn cost":13s} | {"GFLOPs (50 steps)"}' )
print('-' * 72)
for res, f in [(512, 1), (512, 4), (512, 8), (1024, 8)]:
    estimate_flops_and_time(res, latent_factor=f)
print()
print('Latent f=8 reduces attention cost by 64^2 = 4096x vs pixel-space at 512x512')
```

| Model | Latent type | Resolution | Latent size | Condition type | Training compute |
| --- | --- | --- | --- | --- | --- |
| DDPM (Ho et al. 2020) | None — pixel space | 256×256 | 256×256×3 pixels | Class label (embed) | High — pixel U-Net |
| LDM (Rombach et al. 2022) | KL-VAE or VQ-VAE | 256–512×256–512 | 32–64×32–64×4 | Text/class via cross-attn | ~4–16× cheaper than pixel |
| Stable Diffusion 1.5 | KL-VAE f=8 | 512×512 | 64×64×4 | CLIP ViT-L/14 text | ~50× cheaper than pixel SD |
| DALL-E 3 / SDXL | KL-VAE f=8 | 1024×1024 | 128×128×4 | T5 / CLIP dual text encoder | ~200× cheaper than naive pixel |

> **Why Latent Space Works for Diffusion**: A perceptually-trained autoencoder (using LPIPS loss + GAN discriminator) compresses images into latents that preserve semantic and structural information while discarding high-frequency pixel noise. Diffusion in this perceptual latent space is efficient because the latent space is semantically smooth — small latent changes correspond to semantically meaningful image changes, making the score field easier to learn.

- Pixel-space self-attention at 512×512 costs 4096× more than at 64×64 — the primary motivation for latent diffusion.
- KL-regularized autoencoder: small KL weight (1e-6) prioritizes reconstruction fidelity over posterior regularization.
- Latent scaling: divide latents by std of the training set before diffusion training to match the noise schedule assumptions.
- Cross-attention at multiple U-Net resolutions (32×32, 16×16, 8×8) enables spatially-grounded text conditioning.
- Stable Diffusion = LDM + CLIP text encoder + CFG — each component is independently replaceable.
- SDXL improves by using two CLIP encoders (ViT-L and ViT-G), increasing text capacity from 768 to 2048 dims.

---

