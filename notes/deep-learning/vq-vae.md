---
title: "VQ-VAE — Vector Quantization and Discrete Latent Spaces"
slug: "vq-vae"
description: "A deep dive into VQ-VAE: how vector quantization replaces continuous latents with discrete codebook lookups, enabling two-stage generation with autoregressive priors and powering VQGAN, DALL-E, and FSQ."
tags: ["deep-learning", "generative-models"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"heading","level":2,"content":"Introduction"},{"type":"text","content":"VQ-VAE (van den Oord et al., 2017) replaces the continuous Gaussian latent of a standard VAE with a **discrete codebook** of K learned embedding vectors E = {e₁, …, e_K} ∈ ℝ^D. Instead of sampling from a distribution, the encoder output z_e(x) is snapped to its nearest codebook entry, producing a structured symbolic representation. This sidesteps posterior collapse (the encoder ignoring the latent) and the blurring caused by averaging over continuous uncertainty."},{"type":"text","content":"The core design philosophy is to decouple representation from generation. VQ-VAE learns a compact discrete code per input; a separate autoregressive model (PixelCNN, Transformer) then learns a prior over those codes. This two-stage approach underpins DALL-E, VQGAN, AudioLM, and MusicLM. The discrete bottleneck forces the model to commit to meaningful, reusable symbolic units rather than smearing information across a continuous manifold."},{"type":"heading","level":2,"content":"Vector Quantization Mathematics"},{"type":"text","content":"The encoder maps input x to a continuous feature map z_e(x) ∈ ℝ^D. Quantization maps each spatial position to the nearest codebook vector: z_q = e_k where k = argmin‖z_e − e_i‖². The total VQ-VAE loss combines three terms: reconstruction (pixel-level MSE between input and decoder output), codebook loss (moves codebook entries toward encoder outputs using stop-gradient on z_e), and commitment loss (pushes the encoder toward the chosen code using stop-gradient on z_q). The stop-gradient sg() passes values forward but blocks all gradients backward."},{"type":"math","display":true,"content":"\\\\mathcal{L} = \\\\|x - \\\\hat{x}\\\\|^2 + \\\\|\\\\mathrm{sg}(z_e) - z_q\\\\|^2 + \\\\beta\\\\,\\\\|z_e - \\\\mathrm{sg}(z_q)\\\\|^2"},{"type":"text","content":"The commitment weight β ≈ 0.25 controls how strongly the encoder is pushed to stay near its chosen codebook entry. Without it, the encoder can drift between multiple entries during training, producing unstable code assignments and slow convergence. The codebook and commitment losses are complementary: codebook loss moves the dictionary; commitment loss anchors the encoder."},{"type":"heading","level":2,"content":"Straight-Through Gradient Estimator"},{"type":"text","content":"The argmin operation has zero derivative almost everywhere and is undefined at the boundaries between Voronoi cells. It cannot be differentiated through directly, so gradients from the decoder cannot reach the encoder. The straight-through estimator (Bengio et al., 2013) resolves this by simply copying gradients from the decoder input z_q back to the encoder output z_e, bypassing the non-differentiable quantization. In code this is one line: z_q_st = z_e + (z_q - z_e).detach(). The .detach() makes (z_q - z_e) a constant in the backward pass, so all gradient flows through z_e only, as if z_q and z_e were identical."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass VectorQuantizer(nn.Module):\n    def __init__(self, num_embeddings, embedding_dim, commitment_cost=0.25):\n        super().__init__()\n        self.embedding_dim = embedding_dim\n        self.num_embeddings = num_embeddings\n        self.commitment_cost = commitment_cost\n        self.embeddings = nn.Embedding(num_embeddings, embedding_dim)\n        nn.init.uniform_(self.embeddings.weight, -1/num_embeddings, 1/num_embeddings)\n\n    def forward(self, z_e):\n        # z_e: (B, D, H, W) -\u003e flatten spatial dims to (B*H*W, D)\n        z_e_flat = z_e.permute(0, 2, 3, 1).reshape(-1, self.embedding_dim)\n        # Squared L2 distances via expansion: ||a-b||^2 = ||a||^2 - 2a*b^T + ||b||^2\n        distances = (z_e_flat.pow(2).sum(1, keepdim=True)\n                     - 2 * z_e_flat @ self.embeddings.weight.T\n                     + self.embeddings.weight.pow(2).sum(1))\n        indices = distances.argmin(dim=1)           # nearest codebook entry\n        z_q_flat = self.embeddings(indices)\n        z_q = z_q_flat.reshape(z_e.shape[0], z_e.shape[2], z_e.shape[3], -1).permute(0, 3, 1, 2)\n        codebook_loss = F.mse_loss(z_q, z_e.detach())     # move codes toward encoder\n        commitment_loss = F.mse_loss(z_e, z_q.detach())   # move encoder toward codes\n        loss = codebook_loss + self.commitment_cost * commitment_loss\n        z_q_st = z_e + (z_q - z_e).detach()       # straight-through estimator\n        return z_q_st, loss, indices"},{"type":"heading","level":2,"content":"Codebook Learning with EMA"},{"type":"text","content":"Instead of gradient descent on the codebook loss, the VQ-VAE paper recommends exponential moving average (EMA) updates as a more stable alternative. For each codebook entry e_i, maintain a running count n_i of assignments and a running embedding sum m_i. After each batch, update with decay γ ≈ 0.99: n_i ← γn_i + (1−γ)·count(i), and m_i ← γm_i + (1−γ)·sum(z_e assigned to i), then set e_i = m_i / n_i. This is online k-means. It avoids the interaction between codebook gradient updates and the encoder gradient, leading to faster convergence and fewer dead codes in practice."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass VectorQuantizerEMA(nn.Module):\n    def __init__(self, num_embeddings, embedding_dim, decay=0.99, commitment_cost=0.25, eps=1e-5):\n        super().__init__()\n        self.embedding_dim = embedding_dim\n        self.num_embeddings = num_embeddings\n        self.commitment_cost = commitment_cost\n        self.decay = decay\n        self.eps = eps\n        embedding = torch.randn(num_embeddings, embedding_dim)\n        self.register_buffer(\u0027embeddings\u0027, embedding)\n        self.register_buffer(\u0027cluster_size\u0027, torch.zeros(num_embeddings))\n        self.register_buffer(\u0027embed_avg\u0027, embedding.clone())\n\n    def update_ema(self, z_e_flat, indices):\n        # One-hot encode code assignments: shape (N, K)\n        one_hot = torch.zeros(indices.shape[0], self.num_embeddings, device=z_e_flat.device)\n        one_hot.scatter_(1, indices.unsqueeze(1), 1)\n        # EMA update for cluster sizes and embedding running sums\n        self.cluster_size.mul_(self.decay).add_((1 - self.decay) * one_hot.sum(0))\n        embed_sum = one_hot.T @ z_e_flat\n        self.embed_avg.mul_(self.decay).add_((1 - self.decay) * embed_sum)\n        # Laplace smoothing avoids division by zero for empty clusters\n        n = self.cluster_size.sum()\n        smoothed = (self.cluster_size + self.eps) / (n + self.num_embeddings * self.eps) * n\n        self.embeddings = self.embed_avg / smoothed.unsqueeze(1)"},{"type":"heading","level":2,"content":"Dead Code Problem"},{"type":"text","content":"In practice, many codebook entries receive zero assignments throughout training — they are never the nearest neighbour for any encoder output. These **dead codes** waste codebook capacity and reduce the effective number of distinct representations. Common symptoms: codebook utilisation below 50% and reconstruction quality plateauing early. Dead codes arise because once a code falls behind its neighbours due to random initialisation, it gets no gradient signal or EMA update and can never recover on its own."},{"type":"callout","variant":"warning","title":"Batch Size Warning","content":"EMA codebook updates require large batch size (≥256) to get enough code assignments per step — small batches lead to dead code collapse. With batch size 32, most codes receive zero assignments in any single step, causing the EMA cluster sizes to decay toward zero without recovery. Use gradient accumulation or increase batch size before relying on EMA codebook updates."},{"type":"code","language":"python","content":"import torch\n\nclass DeadCodeMonitor:\n    def __init__(self, num_embeddings, threshold=1.0, restart_every=50):\n        self.num_embeddings = num_embeddings\n        self.threshold = threshold      # codes used fewer times than this are dead\n        self.restart_every = restart_every  # check interval in training steps\n        self.usage_count = torch.zeros(num_embeddings)\n        self.step = 0\n\n    def update(self, indices):\n        # Accumulate per-code usage counts from this batch\n        counts = torch.zeros(self.num_embeddings)\n        counts.scatter_add_(0, indices.flatten().cpu(), torch.ones(indices.numel()))\n        self.usage_count += counts\n        self.step += 1\n\n    def restart_dead_codes(self, embeddings, z_e_flat):\n        # Only check at restart_every intervals to reduce overhead\n        if self.step % self.restart_every != 0:\n            return 0\n        dead_mask = self.usage_count \u003c self.threshold\n        num_dead = int(dead_mask.sum().item())\n        if num_dead == 0:\n            self.usage_count.zero_()\n            return 0\n        # Reinitialize dead codes with random encoder outputs from current batch\n        perm = torch.randperm(z_e_flat.shape[0])[:num_dead]\n        with torch.no_grad():\n            embeddings.data[dead_mask] = z_e_flat[perm].detach()\n        self.usage_count.zero_()\n        print(f\u0027Restarted {num_dead} dead codes at step {self.step}\u0027)\n        return num_dead"},{"type":"heading","level":2,"content":"Two-Stage Generation"},{"type":"text","content":"VQ-VAE is only an autoencoder — it cannot generate novel samples on its own. Stage 2 trains an autoregressive model to model the distribution of discrete code sequences produced by the encoder on the training set. At inference, sample a complete code sequence from the prior, then pass it through the VQ-VAE decoder to produce an image. The separation is architecturally powerful: the VQ-VAE solves the hard perceptual reconstruction problem at the pixel level; the prior only needs to model a short sequence of discrete tokens representing high-level structure."},{"type":"code","language":"python","content":"import torch\nfrom torch.distributions import Categorical\n\nclass VQVAEGenerator:\n    # Two-stage: (1) train VQ-VAE, (2) train autoregressive prior on discrete codes\n    def __init__(self, encoder, quantizer, decoder, prior):\n        self.encoder = encoder\n        self.quantizer = quantizer\n        self.decoder = decoder\n        self.prior = prior  # PixelCNN or Transformer trained on code sequences\n\n    @torch.no_grad()\n    def encode_to_codes(self, x):\n        # Stage 1 output: discrete index for each spatial position\n        z_e = self.encoder(x)\n        _, _, indices = self.quantizer(z_e)\n        return indices  # shape: (B, H*W)\n\n    @torch.no_grad()\n    def generate(self, batch_size, code_shape=(16, 16), device=\u0027cuda\u0027, temperature=1.0):\n        # Stage 2: autoregressively sample code indices then decode to image\n        H, W = code_shape\n        codes = torch.zeros(batch_size, H * W, dtype=torch.long, device=device)\n        for pos in range(H * W):\n            logits = self.prior(codes)[:, pos, :]  # (B, num_embeddings)\n            probs = torch.softmax(logits / temperature, dim=-1)\n            codes[:, pos] = Categorical(probs).sample()\n        # Look up quantized vectors and decode to image space\n        z_q = self.quantizer.embeddings[codes]  # (B, H*W, D)\n        z_q = z_q.reshape(batch_size, H, W, -1).permute(0, 3, 1, 2)  # (B, D, H, W)\n        return self.decoder(z_q)"},{"type":"heading","level":2,"content":"VQGAN and Extensions"},{"type":"text","content":"VQGAN (Esser et al., 2021) augments VQ-VAE with two additional losses: a **perceptual loss** (VGG feature-space L2 matching that penalises high-level discrepancies) and a **patch adversarial loss** from a PatchGAN discriminator that penalises locally unrealistic textures. Together these produce far sharper reconstructions than pixel-level MSE alone. VQGAN codes fed to a GPT-style Transformer prior formed the backbone of DALL-E. The same encoder-decoder design underpins Stable Diffusion’s latent space (with a KL-regularised continuous variant for the final model)."},{"type":"text","content":"**FSQ (Finite Scalar Quantization, Mentzer et al., 2023)** offers a simpler, collapse-free alternative: independently quantize each latent dimension to a small set of integers (e.g., {-2, -1, 0, 1, 2}) via bounded rounding. With D dimensions at L levels each, the effective codebook size is L^D. FSQ eliminates dead code collapse entirely (every lattice point is reachable), requires no codebook loss, EMA updates, or commitment loss, and matches VQ-VAE and VQGAN quality on standard benchmarks with dramatically simpler implementation."},{"type":"table","headers":["Model","Latent Type","Collapse Risk","Prior Model","Generation Quality","Key Application"],"rows":[["VAE","Continuous Gaussian","Posterior collapse","Flow / Diffusion","Blurry (MSE)","Representation learning"],["VQ-VAE","Discrete codebook","Dead codes","PixelCNN / Transformer","Sharp, compressed","Audio and image compression"],["VQGAN","Discrete codebook + perceptual","Dead codes (managed)","GPT-style Transformer","High fidelity","High-res image generation"],["FSQ","Discrete scalar grid","None (deterministic)","Transformer","Comparable to VQ-VAE","Simpler drop-in replacement"]]},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"list","ordered":false,"items":["VQ-VAE replaces continuous latents with discrete codebook lookups, enabling clean symbolic representations without posterior collapse or blurring.","The straight-through estimator (z_q_st = z_e + (z_q - z_e).detach()) is the single line that enables end-to-end backpropagation through the non-differentiable argmin.","EMA codebook updates (equivalent to online k-means) are more stable than gradient descent on the codebook loss and are the recommended approach in practice.","Dead code collapse is the main failure mode: monitor per-code utilisation and use random restart to reinitialise unused entries from current encoder outputs.","Two-stage generation cleanly separates compression from synthesis: VQ-VAE handles pixel-level fidelity; the autoregressive prior handles high-level compositional structure.","VQGAN adds perceptual and adversarial losses for significantly sharper reconstructions and powers DALL-E and latent diffusion models.","FSQ offers a collapse-free drop-in alternative by quantizing each latent dimension independently to scalar integer levels, eliminating all codebook complexity."]}]"
---
# VQ-VAE — Vector Quantization and Discrete Latent Spaces

## Introduction

VQ-VAE (van den Oord et al., 2017) replaces the continuous Gaussian latent of a standard VAE with a **discrete codebook** of K learned embedding vectors E = {e₁, …, e_K} ∈ ℝ^D. Instead of sampling from a distribution, the encoder output z_e(x) is snapped to its nearest codebook entry, producing a structured symbolic representation. This sidesteps posterior collapse (the encoder ignoring the latent) and the blurring caused by averaging over continuous uncertainty.

The core design philosophy is to decouple representation from generation. VQ-VAE learns a compact discrete code per input; a separate autoregressive model (PixelCNN, Transformer) then learns a prior over those codes. This two-stage approach underpins DALL-E, VQGAN, AudioLM, and MusicLM. The discrete bottleneck forces the model to commit to meaningful, reusable symbolic units rather than smearing information across a continuous manifold.

## Vector Quantization Mathematics

The encoder maps input x to a continuous feature map z_e(x) ∈ ℝ^D. Quantization maps each spatial position to the nearest codebook vector: z_q = e_k where k = argmin‖z_e − e_i‖². The total VQ-VAE loss combines three terms: reconstruction (pixel-level MSE between input and decoder output), codebook loss (moves codebook entries toward encoder outputs using stop-gradient on z_e), and commitment loss (pushes the encoder toward the chosen code using stop-gradient on z_q). The stop-gradient sg() passes values forward but blocks all gradients backward.

$$\\mathcal{L} = \\|x - \\hat{x}\\|^2 + \\|\\mathrm{sg}(z_e) - z_q\\|^2 + \\beta\\,\\|z_e - \\mathrm{sg}(z_q)\\|^2$$

The commitment weight β ≈ 0.25 controls how strongly the encoder is pushed to stay near its chosen codebook entry. Without it, the encoder can drift between multiple entries during training, producing unstable code assignments and slow convergence. The codebook and commitment losses are complementary: codebook loss moves the dictionary; commitment loss anchors the encoder.

## Straight-Through Gradient Estimator

The argmin operation has zero derivative almost everywhere and is undefined at the boundaries between Voronoi cells. It cannot be differentiated through directly, so gradients from the decoder cannot reach the encoder. The straight-through estimator (Bengio et al., 2013) resolves this by simply copying gradients from the decoder input z_q back to the encoder output z_e, bypassing the non-differentiable quantization. In code this is one line: z_q_st = z_e + (z_q - z_e).detach(). The .detach() makes (z_q - z_e) a constant in the backward pass, so all gradient flows through z_e only, as if z_q and z_e were identical.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class VectorQuantizer(nn.Module):
    def __init__(self, num_embeddings, embedding_dim, commitment_cost=0.25):
        super().__init__()
        self.embedding_dim = embedding_dim
        self.num_embeddings = num_embeddings
        self.commitment_cost = commitment_cost
        self.embeddings = nn.Embedding(num_embeddings, embedding_dim)
        nn.init.uniform_(self.embeddings.weight, -1/num_embeddings, 1/num_embeddings)

    def forward(self, z_e):
        # z_e: (B, D, H, W) -> flatten spatial dims to (B*H*W, D)
        z_e_flat = z_e.permute(0, 2, 3, 1).reshape(-1, self.embedding_dim)
        # Squared L2 distances via expansion: ||a-b||^2 = ||a||^2 - 2a*b^T + ||b||^2
        distances = (z_e_flat.pow(2).sum(1, keepdim=True)
                     - 2 * z_e_flat @ self.embeddings.weight.T
                     + self.embeddings.weight.pow(2).sum(1))
        indices = distances.argmin(dim=1)           # nearest codebook entry
        z_q_flat = self.embeddings(indices)
        z_q = z_q_flat.reshape(z_e.shape[0], z_e.shape[2], z_e.shape[3], -1).permute(0, 3, 1, 2)
        codebook_loss = F.mse_loss(z_q, z_e.detach())     # move codes toward encoder
        commitment_loss = F.mse_loss(z_e, z_q.detach())   # move encoder toward codes
        loss = codebook_loss + self.commitment_cost * commitment_loss
        z_q_st = z_e + (z_q - z_e).detach()       # straight-through estimator
        return z_q_st, loss, indices
```

## Codebook Learning with EMA

Instead of gradient descent on the codebook loss, the VQ-VAE paper recommends exponential moving average (EMA) updates as a more stable alternative. For each codebook entry e_i, maintain a running count n_i of assignments and a running embedding sum m_i. After each batch, update with decay γ ≈ 0.99: n_i ← γn_i + (1−γ)·count(i), and m_i ← γm_i + (1−γ)·sum(z_e assigned to i), then set e_i = m_i / n_i. This is online k-means. It avoids the interaction between codebook gradient updates and the encoder gradient, leading to faster convergence and fewer dead codes in practice.

```python
import torch
import torch.nn as nn

class VectorQuantizerEMA(nn.Module):
    def __init__(self, num_embeddings, embedding_dim, decay=0.99, commitment_cost=0.25, eps=1e-5):
        super().__init__()
        self.embedding_dim = embedding_dim
        self.num_embeddings = num_embeddings
        self.commitment_cost = commitment_cost
        self.decay = decay
        self.eps = eps
        embedding = torch.randn(num_embeddings, embedding_dim)
        self.register_buffer('embeddings', embedding)
        self.register_buffer('cluster_size', torch.zeros(num_embeddings))
        self.register_buffer('embed_avg', embedding.clone())

    def update_ema(self, z_e_flat, indices):
        # One-hot encode code assignments: shape (N, K)
        one_hot = torch.zeros(indices.shape[0], self.num_embeddings, device=z_e_flat.device)
        one_hot.scatter_(1, indices.unsqueeze(1), 1)
        # EMA update for cluster sizes and embedding running sums
        self.cluster_size.mul_(self.decay).add_((1 - self.decay) * one_hot.sum(0))
        embed_sum = one_hot.T @ z_e_flat
        self.embed_avg.mul_(self.decay).add_((1 - self.decay) * embed_sum)
        # Laplace smoothing avoids division by zero for empty clusters
        n = self.cluster_size.sum()
        smoothed = (self.cluster_size + self.eps) / (n + self.num_embeddings * self.eps) * n
        self.embeddings = self.embed_avg / smoothed.unsqueeze(1)
```

## Dead Code Problem

In practice, many codebook entries receive zero assignments throughout training — they are never the nearest neighbour for any encoder output. These **dead codes** waste codebook capacity and reduce the effective number of distinct representations. Common symptoms: codebook utilisation below 50% and reconstruction quality plateauing early. Dead codes arise because once a code falls behind its neighbours due to random initialisation, it gets no gradient signal or EMA update and can never recover on its own.

> **Batch Size Warning**: EMA codebook updates require large batch size (≥256) to get enough code assignments per step — small batches lead to dead code collapse. With batch size 32, most codes receive zero assignments in any single step, causing the EMA cluster sizes to decay toward zero without recovery. Use gradient accumulation or increase batch size before relying on EMA codebook updates.

```python
import torch

class DeadCodeMonitor:
    def __init__(self, num_embeddings, threshold=1.0, restart_every=50):
        self.num_embeddings = num_embeddings
        self.threshold = threshold      # codes used fewer times than this are dead
        self.restart_every = restart_every  # check interval in training steps
        self.usage_count = torch.zeros(num_embeddings)
        self.step = 0

    def update(self, indices):
        # Accumulate per-code usage counts from this batch
        counts = torch.zeros(self.num_embeddings)
        counts.scatter_add_(0, indices.flatten().cpu(), torch.ones(indices.numel()))
        self.usage_count += counts
        self.step += 1

    def restart_dead_codes(self, embeddings, z_e_flat):
        # Only check at restart_every intervals to reduce overhead
        if self.step % self.restart_every != 0:
            return 0
        dead_mask = self.usage_count < self.threshold
        num_dead = int(dead_mask.sum().item())
        if num_dead == 0:
            self.usage_count.zero_()
            return 0
        # Reinitialize dead codes with random encoder outputs from current batch
        perm = torch.randperm(z_e_flat.shape[0])[:num_dead]
        with torch.no_grad():
            embeddings.data[dead_mask] = z_e_flat[perm].detach()
        self.usage_count.zero_()
        print(f'Restarted {num_dead} dead codes at step {self.step}')
        return num_dead
```

## Two-Stage Generation

VQ-VAE is only an autoencoder — it cannot generate novel samples on its own. Stage 2 trains an autoregressive model to model the distribution of discrete code sequences produced by the encoder on the training set. At inference, sample a complete code sequence from the prior, then pass it through the VQ-VAE decoder to produce an image. The separation is architecturally powerful: the VQ-VAE solves the hard perceptual reconstruction problem at the pixel level; the prior only needs to model a short sequence of discrete tokens representing high-level structure.

```python
import torch
from torch.distributions import Categorical

class VQVAEGenerator:
    # Two-stage: (1) train VQ-VAE, (2) train autoregressive prior on discrete codes
    def __init__(self, encoder, quantizer, decoder, prior):
        self.encoder = encoder
        self.quantizer = quantizer
        self.decoder = decoder
        self.prior = prior  # PixelCNN or Transformer trained on code sequences

    @torch.no_grad()
    def encode_to_codes(self, x):
        # Stage 1 output: discrete index for each spatial position
        z_e = self.encoder(x)
        _, _, indices = self.quantizer(z_e)
        return indices  # shape: (B, H*W)

    @torch.no_grad()
    def generate(self, batch_size, code_shape=(16, 16), device='cuda', temperature=1.0):
        # Stage 2: autoregressively sample code indices then decode to image
        H, W = code_shape
        codes = torch.zeros(batch_size, H * W, dtype=torch.long, device=device)
        for pos in range(H * W):
            logits = self.prior(codes)[:, pos, :]  # (B, num_embeddings)
            probs = torch.softmax(logits / temperature, dim=-1)
            codes[:, pos] = Categorical(probs).sample()
        # Look up quantized vectors and decode to image space
        z_q = self.quantizer.embeddings[codes]  # (B, H*W, D)
        z_q = z_q.reshape(batch_size, H, W, -1).permute(0, 3, 1, 2)  # (B, D, H, W)
        return self.decoder(z_q)
```

## VQGAN and Extensions

VQGAN (Esser et al., 2021) augments VQ-VAE with two additional losses: a **perceptual loss** (VGG feature-space L2 matching that penalises high-level discrepancies) and a **patch adversarial loss** from a PatchGAN discriminator that penalises locally unrealistic textures. Together these produce far sharper reconstructions than pixel-level MSE alone. VQGAN codes fed to a GPT-style Transformer prior formed the backbone of DALL-E. The same encoder-decoder design underpins Stable Diffusion’s latent space (with a KL-regularised continuous variant for the final model).

**FSQ (Finite Scalar Quantization, Mentzer et al., 2023)** offers a simpler, collapse-free alternative: independently quantize each latent dimension to a small set of integers (e.g., {-2, -1, 0, 1, 2}) via bounded rounding. With D dimensions at L levels each, the effective codebook size is L^D. FSQ eliminates dead code collapse entirely (every lattice point is reachable), requires no codebook loss, EMA updates, or commitment loss, and matches VQ-VAE and VQGAN quality on standard benchmarks with dramatically simpler implementation.

| Model | Latent Type | Collapse Risk | Prior Model | Generation Quality | Key Application |
| --- | --- | --- | --- | --- | --- |
| VAE | Continuous Gaussian | Posterior collapse | Flow / Diffusion | Blurry (MSE) | Representation learning |
| VQ-VAE | Discrete codebook | Dead codes | PixelCNN / Transformer | Sharp, compressed | Audio and image compression |
| VQGAN | Discrete codebook + perceptual | Dead codes (managed) | GPT-style Transformer | High fidelity | High-res image generation |
| FSQ | Discrete scalar grid | None (deterministic) | Transformer | Comparable to VQ-VAE | Simpler drop-in replacement |

## Key Takeaways

- VQ-VAE replaces continuous latents with discrete codebook lookups, enabling clean symbolic representations without posterior collapse or blurring.
- The straight-through estimator (z_q_st = z_e + (z_q - z_e).detach()) is the single line that enables end-to-end backpropagation through the non-differentiable argmin.
- EMA codebook updates (equivalent to online k-means) are more stable than gradient descent on the codebook loss and are the recommended approach in practice.
- Dead code collapse is the main failure mode: monitor per-code utilisation and use random restart to reinitialise unused entries from current encoder outputs.
- Two-stage generation cleanly separates compression from synthesis: VQ-VAE handles pixel-level fidelity; the autoregressive prior handles high-level compositional structure.
- VQGAN adds perceptual and adversarial losses for significantly sharper reconstructions and powers DALL-E and latent diffusion models.
- FSQ offers a collapse-free drop-in alternative by quantizing each latent dimension independently to scalar integer levels, eliminating all codebook complexity.

