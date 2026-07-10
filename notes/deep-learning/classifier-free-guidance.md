---
title: "Classifier-Free Guidance — CFG and the Quality-Diversity Trade-off"
slug: "classifier-free-guidance"
description: "Implement classifier-free guidance training with conditioning dropout, build the CFG inference formula, sweep the guidance scale w from 1 to 15, apply CFG to text-to-image with CLIP embeddings, and compare CFG against classifier guidance and PAG."
tags: ["deep-learning", "generative-models", "diffusion-models"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Classifier-free guidance (Ho \u0026 Salimans 2022) achieves class-conditional quality equivalent to classifier guidance — without a separately trained classifier. The key insight: train a single diffusion model to be both unconditional (condition c replaced by null token ∅) and conditional (condition c provided), by randomly dropping the conditioning during training. At inference, combine both predictions to extrapolate in the direction of the condition, amplifying the class signal without any classifier gradient computation."},{"type":"heading","level":2,"content":"Motivation — Avoiding the Separate Classifier"},{"type":"text","content":"Classifier guidance requires (1) a separately trained noisy classifier p_φ(y|x_t) trained at all noise levels, (2) gradient computation through this classifier at every denoising step, and (3) careful tuning to avoid classifier gradient instability at high noise levels. These costs add ~50% inference compute and significant training complexity. Classifier-free guidance eliminates the classifier entirely: the guidance signal is derived from the difference between conditional and unconditional predictions of the same network, which is a cheap extra forward pass rather than an expensive gradient computation."},{"type":"heading","level":2,"content":"CFG Training — Conditional and Unconditional Together"},{"type":"text","content":"CFG training modifies the standard diffusion training loop by randomly replacing the condition c with a null token ∅ with probability p_uncond (typically 0.1–0.2). The network learns both p(x_t|c) (conditional denoising) and p(x_t|∅) (unconditional denoising) from the same weights. At inference time, both the conditional prediction ε_θ(x_t,t,c) and unconditional prediction ε_θ(x_t,t,∅) are computed in a single forward pass (or two forward passes if batched separately), and combined with the guidance formula."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass CFGDiffusionModel(nn.Module):\n    def __init__(self, data_dim=32, cond_dim=16, hidden=128, T=1000):\n        super().__init__()\n        self.null_cond = nn.Parameter(torch.zeros(cond_dim))  # learned null token\n        self.time_embed = nn.Embedding(T, 16)\n        self.net = nn.Sequential(\n            nn.Linear(data_dim + cond_dim + 16, hidden), nn.SiLU(),\n            nn.Linear(hidden, hidden), nn.SiLU(),\n            nn.Linear(hidden, data_dim)\n        )\n    def forward(self, x_t, t, cond):\n        t_emb = self.time_embed(t)\n        h = torch.cat([x_t, cond, t_emb], dim=-1)\n        return self.net(h)\n\ndef cfg_train_step(model, x0, cond, alpha_bar, p_uncond=0.15):\n    \"\"\"CFG training: randomly drop conditioning with probability p_uncond.\"\"\"\n    B = x0.size(0)\n    T = len(alpha_bar)\n    t = torch.randint(0, T, (B,))\n    eps = torch.randn_like(x0)\n    ab = alpha_bar[t].unsqueeze(1)\n    x_t = torch.sqrt(ab) * x0 + torch.sqrt(1 - ab) * eps\n    # Drop condition with probability p_uncond\n    drop_mask = torch.rand(B) \u003c p_uncond\n    cond_used = cond.clone()\n    cond_used[drop_mask] = model.null_cond.unsqueeze(0).expand(drop_mask.sum(), -1)\n    eps_pred = model(x_t, t, cond_used)\n    return F.mse_loss(eps_pred, eps)\n\ntorch.manual_seed(0)\nalpha_bar = torch.cumprod(1 - torch.linspace(1e-4, 0.02, 1000), dim=0)\nmodel = CFGDiffusionModel()\nopt = torch.optim.Adam(model.parameters(), lr=1e-3)\ndata = torch.randn(400, 32)\nconds = torch.randn(400, 16)\nfor step in range(200):\n    idx = torch.randint(0, 400, (32,))\n    loss = cfg_train_step(model, data[idx], conds[idx], alpha_bar)\n    opt.zero_grad(); loss.backward(); opt.step()\n    if step % 100 == 0:\n        print(f\u0027Step {step}: CFG training loss = {loss.item():.4f}\u0027)"},{"type":"heading","level":2,"content":"CFG Inference Formula"},{"type":"text","content":"At inference, the CFG epsilon is: ε̃ = ε_θ(x_t,t,∅) + w·(ε_θ(x_t,t,c) − ε_θ(x_t,t,∅)), where w is the guidance scale. At w=0 this is unconditional; at w=1 it is purely conditional; at w \u003e 1 the guidance extrapolates beyond the conditional distribution toward high-probability modes for class c. Mechanically, CFG steers the score in the direction that increases p(c|x_t) — it performs approximate classifier guidance implicitly, without a real classifier. The effective implicit classifier gradient is: s·∇ log p(c|x_t) ≈ (w−1)·[ε_cond − ε_uncond]/√(1−ᾱ_t)."},{"type":"code","language":"python","content":"import torch\n\n@torch.no_grad()\ndef cfg_sampling(model, cond, alpha_bar, timesteps, w=7.0, data_dim=32, B=4):\n    \"\"\"CFG inference: combine conditional and unconditional predictions.\"\"\"\n    null_cond = model.null_cond.unsqueeze(0).expand(B, -1)\n    x = torch.randn(B, data_dim)\n    for i in range(len(timesteps) - 1):\n        t = timesteps[i]\n        t_prev = timesteps[i + 1]\n        ab_t = alpha_bar[t]\n        ab_p = alpha_bar[t_prev]\n        t_batch = torch.full((B,), t, dtype=torch.long)\n        # Two forward passes (or one with doubled batch)\n        eps_cond   = model(x, t_batch, cond.expand(B, -1))\n        eps_uncond = model(x, t_batch, null_cond)\n        # CFG combination\n        eps_cfg = eps_uncond + w * (eps_cond - eps_uncond)\n        # DDIM-style update\n        x0 = (x - torch.sqrt(1 - ab_t) * eps_cfg) / torch.sqrt(ab_t)\n        x0 = x0.clamp(-1, 1)\n        x = torch.sqrt(ab_p) * x0 + torch.sqrt(1 - ab_p) * eps_cfg\n    return x\n\nalpha_bar = torch.cumprod(1 - torch.linspace(1e-4, 0.02, 1000), dim=0)\ntimesteps = list(range(0, 1000, 20))[::-1]\ncond = torch.randn(1, 16)\nfor w in [1.0, 3.0, 7.5]:\n    out = cfg_sampling(model, cond, alpha_bar, timesteps, w=w)\n    print(f\u0027w={w:4.1f}: output norm={out.norm():.3f}, std={out.std():.4f}\u0027)"},{"type":"heading","level":2,"content":"Guidance Scale and the Quality-Diversity Trade-off"},{"type":"text","content":"The guidance scale w drives a precision-recall trade-off. Low w (0–2): high diversity, lower class fidelity. Optimal w (7–10 for text-to-image, ~3–5 for class-conditional ImageNet): best FID. High w (\u003e12): mode collapse, over-saturated colors, unnatural sharpness. The mechanism is mode-seeking: CFG extrapolates in the direction that maximizes p(c|x), pushing samples toward high-density class modes at the cost of marginal diversity. SDXL models use a default w=7.5; Stable Diffusion XL uses w=5.0 with rescaling."},{"type":"code","language":"python","content":"import torch\nimport numpy as np\n\ndef guidance_scale_sweep(model, cond, alpha_bar, timesteps, data_dim=32, B=16):\n    \"\"\"Sweep guidance scale and measure proxy diversity (std) and sharpness.\"\"\"\n    null_cond = model.null_cond.unsqueeze(0).expand(B, -1)\n    results = []\n    for w in [0.0, 1.0, 3.0, 5.0, 7.5, 10.0, 15.0]:\n        torch.manual_seed(42)\n        x = torch.randn(B, data_dim)\n        with torch.no_grad():\n            for i in range(len(timesteps) - 1):\n                t, t_p = timesteps[i], timesteps[i+1]\n                ab_t, ab_p = alpha_bar[t], alpha_bar[t_p]\n                t_b = torch.full((B,), t, dtype=torch.long)\n                eps_c = model(x, t_b, cond.expand(B, -1))\n                eps_u = model(x, t_b, null_cond)\n                eps = eps_u + w * (eps_c - eps_u)\n                x0 = (x - torch.sqrt(1 - ab_t)*eps) / torch.sqrt(ab_t)\n                x = torch.sqrt(ab_p)*x0.clamp(-1,1) + torch.sqrt(1-ab_p)*eps\n        diversity = x.std(dim=0).mean().item()   # across samples\n        sharpness = x.abs().mean().item()         # proxy for signal strength\n        results.append((w, diversity, sharpness))\n        print(f\u0027w={w:5.1f}: diversity(std)={diversity:.4f}  sharpness={sharpness:.4f}\u0027)\n    return results\n\ncond = torch.randn(1, 16)\ntimesteps = list(range(0, 1000, 50))[::-1]\nguidance_scale_sweep(model, cond, alpha_bar, timesteps)"},{"type":"heading","level":2,"content":"Text-to-Image with CLIP Embeddings"},{"type":"text","content":"In text-to-image models, the condition c is a CLIP text embedding (e.g. 768-dim for CLIP ViT-L/14). The diffusion model receives the text embedding via cross-attention in the U-Net, not concatenation. CFG is applied identically: ε̃ = ε_θ(x_t,t,∅) + w·(ε_θ(x_t,t,CLIP(text)) − ε_θ(x_t,t,∅)), where ∅ is the CLIP embedding of the empty string. Guidance scale w=7–9 is typical for Stable Diffusion. CLIP embeddings are normalized to unit norm before injection, and the cross-attention keys/values are derived from the CLIP features via learned linear projections."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass CrossAttentionBlock(nn.Module):\n    \"\"\"Single cross-attention layer: queries from image, keys/values from text.\"\"\"\n    def __init__(self, img_dim=64, text_dim=32, n_heads=4):\n        super().__init__()\n        self.n_heads = n_heads\n        self.head_dim = img_dim // n_heads\n        self.to_q = nn.Linear(img_dim, img_dim, bias=False)\n        self.to_k = nn.Linear(text_dim, img_dim, bias=False)\n        self.to_v = nn.Linear(text_dim, img_dim, bias=False)\n        self.to_out = nn.Linear(img_dim, img_dim)\n\n    def forward(self, x, text_emb):\n        B, S, D = x.shape\n        T = text_emb.shape[1]\n        Q = self.to_q(x).view(B, S, self.n_heads, self.head_dim).transpose(1, 2)\n        K = self.to_k(text_emb).view(B, T, self.n_heads, self.head_dim).transpose(1, 2)\n        V = self.to_v(text_emb).view(B, T, self.n_heads, self.head_dim).transpose(1, 2)\n        scale = self.head_dim ** -0.5\n        attn = (Q @ K.transpose(-2, -1)) * scale\n        attn = F.softmax(attn, dim=-1)  # (B, n_heads, S, T)\n        out = (attn @ V).transpose(1, 2).reshape(B, S, D)\n        return self.to_out(out)\n\ntorch.manual_seed(0)\nB, S = 2, 16  # batch, spatial tokens\nimg_feat = torch.randn(B, S, 64)  # image latent tokens\nnull_text = torch.zeros(B, 8, 32)  # null text (empty prompt)\ntext_emb = torch.randn(B, 8, 32)  # CLIP text embedding\nattn = CrossAttentionBlock(img_dim=64, text_dim=32)\nout_cond = attn(img_feat, text_emb)\nout_uncond = attn(img_feat, null_text)\neps_cfg = out_uncond + 7.5 * (out_cond - out_uncond)\nprint(f\u0027Conditional output norm:   {out_cond.norm():.4f}\u0027)\nprint(f\u0027Unconditional output norm: {out_uncond.norm():.4f}\u0027)\nprint(f\u0027CFG output norm (w=7.5):   {eps_cfg.norm():.4f}\u0027)"},{"type":"heading","level":2,"content":"PAG and Guidance Variants"},{"type":"text","content":"Perturbed Attention Guidance (PAG, 2024) replaces the null condition ∅ with identity self-attention maps — instead of dropping the condition, it degrades attention processing. This produces a different kind of structural guidance that improves fine-grained detail without over-saturating colors. SDXL guidance rescaling (Basile et al. 2023) addresses the color artifact problem at w \u003e 7: the CFG output has a larger standard deviation than the conditional output, so rescaling ε_cfg by std(ε_cond)/std(ε_cfg) before the denoising step prevents over-saturation. Negative prompts are another practical CFG extension: replace ∅ with CLIP(negative_prompt) to actively steer away from undesirable attributes."},{"type":"heading","level":2,"content":"Comparison of Guidance Methods"},{"type":"table","headers":["Method","Classifier needed","Guidance formula","Optimal w","Artifacts at high w","Inversion support"],"rows":[["No guidance (w=1)","No","ε_θ(x_t, t, c)","N/A","None","Yes (DDIM)"],["Classifier guidance","Yes — noisy p_φ(y|x_t)","ε_θ − s·√(1−ᾱ)·∇ log p_φ(y|x_t)","s=3–5 (ImageNet)","Noisy at high s","No — stochastic"],["CFG (Ho \u0026 Salimans 2022)","No — joint training","ε_uncond + w·(ε_cond−ε_uncond)","w=7–10 (text-to-image)","Color saturation, sharpness","Yes — with null cond"],["PAG (2024)","No","ε_identity_attn + w·(ε_cond−ε_identity_attn)","w=3–5","Fewer artifacts than CFG","Yes"]]},{"type":"callout","variant":"tip","title":"Guidance Scale Tuning Rule of Thumb","content":"Start with w=7.5 for text-to-image tasks. If samples are over-saturated or have unnatural edges, reduce to w=5.0 and try guidance rescaling. If semantic alignment to the prompt is poor, increase to w=10–12. For class-conditional ImageNet models, optimal FID is usually at w=3–5. Always validate on a held-out prompt set — the optimal w varies across model families."},{"type":"list","ordered":false,"items":["CFG trains one network for both conditional and unconditional generation via condition dropout (p=0.1–0.2).","Inference formula: ε_cfg = ε_uncond + w·(ε_cond − ε_uncond) — just two forward passes.","w=0: unconditional; w=1: conditional; w\u003e1: extrapolated toward high-class-probability modes.","Optimal w for text-to-image is 7–10; for class-conditional ImageNet, 3–5.","Negative prompts replace ∅ with CLIP(negative text), actively steering away from undesired attributes.","Guidance rescaling (std normalization) fixes the color saturation artifacts seen at high guidance scales."]},{"type":"divider"}]"
---
# Classifier-Free Guidance — CFG and the Quality-Diversity Trade-off

Classifier-free guidance (Ho & Salimans 2022) achieves class-conditional quality equivalent to classifier guidance — without a separately trained classifier. The key insight: train a single diffusion model to be both unconditional (condition c replaced by null token ∅) and conditional (condition c provided), by randomly dropping the conditioning during training. At inference, combine both predictions to extrapolate in the direction of the condition, amplifying the class signal without any classifier gradient computation.

## Motivation — Avoiding the Separate Classifier

Classifier guidance requires (1) a separately trained noisy classifier p_φ(y|x_t) trained at all noise levels, (2) gradient computation through this classifier at every denoising step, and (3) careful tuning to avoid classifier gradient instability at high noise levels. These costs add ~50% inference compute and significant training complexity. Classifier-free guidance eliminates the classifier entirely: the guidance signal is derived from the difference between conditional and unconditional predictions of the same network, which is a cheap extra forward pass rather than an expensive gradient computation.

## CFG Training — Conditional and Unconditional Together

CFG training modifies the standard diffusion training loop by randomly replacing the condition c with a null token ∅ with probability p_uncond (typically 0.1–0.2). The network learns both p(x_t|c) (conditional denoising) and p(x_t|∅) (unconditional denoising) from the same weights. At inference time, both the conditional prediction ε_θ(x_t,t,c) and unconditional prediction ε_θ(x_t,t,∅) are computed in a single forward pass (or two forward passes if batched separately), and combined with the guidance formula.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class CFGDiffusionModel(nn.Module):
    def __init__(self, data_dim=32, cond_dim=16, hidden=128, T=1000):
        super().__init__()
        self.null_cond = nn.Parameter(torch.zeros(cond_dim))  # learned null token
        self.time_embed = nn.Embedding(T, 16)
        self.net = nn.Sequential(
            nn.Linear(data_dim + cond_dim + 16, hidden), nn.SiLU(),
            nn.Linear(hidden, hidden), nn.SiLU(),
            nn.Linear(hidden, data_dim)
        )
    def forward(self, x_t, t, cond):
        t_emb = self.time_embed(t)
        h = torch.cat([x_t, cond, t_emb], dim=-1)
        return self.net(h)

def cfg_train_step(model, x0, cond, alpha_bar, p_uncond=0.15):
    """CFG training: randomly drop conditioning with probability p_uncond."""
    B = x0.size(0)
    T = len(alpha_bar)
    t = torch.randint(0, T, (B,))
    eps = torch.randn_like(x0)
    ab = alpha_bar[t].unsqueeze(1)
    x_t = torch.sqrt(ab) * x0 + torch.sqrt(1 - ab) * eps
    # Drop condition with probability p_uncond
    drop_mask = torch.rand(B) < p_uncond
    cond_used = cond.clone()
    cond_used[drop_mask] = model.null_cond.unsqueeze(0).expand(drop_mask.sum(), -1)
    eps_pred = model(x_t, t, cond_used)
    return F.mse_loss(eps_pred, eps)

torch.manual_seed(0)
alpha_bar = torch.cumprod(1 - torch.linspace(1e-4, 0.02, 1000), dim=0)
model = CFGDiffusionModel()
opt = torch.optim.Adam(model.parameters(), lr=1e-3)
data = torch.randn(400, 32)
conds = torch.randn(400, 16)
for step in range(200):
    idx = torch.randint(0, 400, (32,))
    loss = cfg_train_step(model, data[idx], conds[idx], alpha_bar)
    opt.zero_grad(); loss.backward(); opt.step()
    if step % 100 == 0:
        print(f'Step {step}: CFG training loss = {loss.item():.4f}')
```

## CFG Inference Formula

At inference, the CFG epsilon is: ε̃ = ε_θ(x_t,t,∅) + w·(ε_θ(x_t,t,c) − ε_θ(x_t,t,∅)), where w is the guidance scale. At w=0 this is unconditional; at w=1 it is purely conditional; at w > 1 the guidance extrapolates beyond the conditional distribution toward high-probability modes for class c. Mechanically, CFG steers the score in the direction that increases p(c|x_t) — it performs approximate classifier guidance implicitly, without a real classifier. The effective implicit classifier gradient is: s·∇ log p(c|x_t) ≈ (w−1)·[ε_cond − ε_uncond]/√(1−ᾱ_t).

```python
import torch

@torch.no_grad()
def cfg_sampling(model, cond, alpha_bar, timesteps, w=7.0, data_dim=32, B=4):
    """CFG inference: combine conditional and unconditional predictions."""
    null_cond = model.null_cond.unsqueeze(0).expand(B, -1)
    x = torch.randn(B, data_dim)
    for i in range(len(timesteps) - 1):
        t = timesteps[i]
        t_prev = timesteps[i + 1]
        ab_t = alpha_bar[t]
        ab_p = alpha_bar[t_prev]
        t_batch = torch.full((B,), t, dtype=torch.long)
        # Two forward passes (or one with doubled batch)
        eps_cond   = model(x, t_batch, cond.expand(B, -1))
        eps_uncond = model(x, t_batch, null_cond)
        # CFG combination
        eps_cfg = eps_uncond + w * (eps_cond - eps_uncond)
        # DDIM-style update
        x0 = (x - torch.sqrt(1 - ab_t) * eps_cfg) / torch.sqrt(ab_t)
        x0 = x0.clamp(-1, 1)
        x = torch.sqrt(ab_p) * x0 + torch.sqrt(1 - ab_p) * eps_cfg
    return x

alpha_bar = torch.cumprod(1 - torch.linspace(1e-4, 0.02, 1000), dim=0)
timesteps = list(range(0, 1000, 20))[::-1]
cond = torch.randn(1, 16)
for w in [1.0, 3.0, 7.5]:
    out = cfg_sampling(model, cond, alpha_bar, timesteps, w=w)
    print(f'w={w:4.1f}: output norm={out.norm():.3f}, std={out.std():.4f}')
```

## Guidance Scale and the Quality-Diversity Trade-off

The guidance scale w drives a precision-recall trade-off. Low w (0–2): high diversity, lower class fidelity. Optimal w (7–10 for text-to-image, ~3–5 for class-conditional ImageNet): best FID. High w (>12): mode collapse, over-saturated colors, unnatural sharpness. The mechanism is mode-seeking: CFG extrapolates in the direction that maximizes p(c|x), pushing samples toward high-density class modes at the cost of marginal diversity. SDXL models use a default w=7.5; Stable Diffusion XL uses w=5.0 with rescaling.

```python
import torch
import numpy as np

def guidance_scale_sweep(model, cond, alpha_bar, timesteps, data_dim=32, B=16):
    """Sweep guidance scale and measure proxy diversity (std) and sharpness."""
    null_cond = model.null_cond.unsqueeze(0).expand(B, -1)
    results = []
    for w in [0.0, 1.0, 3.0, 5.0, 7.5, 10.0, 15.0]:
        torch.manual_seed(42)
        x = torch.randn(B, data_dim)
        with torch.no_grad():
            for i in range(len(timesteps) - 1):
                t, t_p = timesteps[i], timesteps[i+1]
                ab_t, ab_p = alpha_bar[t], alpha_bar[t_p]
                t_b = torch.full((B,), t, dtype=torch.long)
                eps_c = model(x, t_b, cond.expand(B, -1))
                eps_u = model(x, t_b, null_cond)
                eps = eps_u + w * (eps_c - eps_u)
                x0 = (x - torch.sqrt(1 - ab_t)*eps) / torch.sqrt(ab_t)
                x = torch.sqrt(ab_p)*x0.clamp(-1,1) + torch.sqrt(1-ab_p)*eps
        diversity = x.std(dim=0).mean().item()   # across samples
        sharpness = x.abs().mean().item()         # proxy for signal strength
        results.append((w, diversity, sharpness))
        print(f'w={w:5.1f}: diversity(std)={diversity:.4f}  sharpness={sharpness:.4f}')
    return results

cond = torch.randn(1, 16)
timesteps = list(range(0, 1000, 50))[::-1]
guidance_scale_sweep(model, cond, alpha_bar, timesteps)
```

## Text-to-Image with CLIP Embeddings

In text-to-image models, the condition c is a CLIP text embedding (e.g. 768-dim for CLIP ViT-L/14). The diffusion model receives the text embedding via cross-attention in the U-Net, not concatenation. CFG is applied identically: ε̃ = ε_θ(x_t,t,∅) + w·(ε_θ(x_t,t,CLIP(text)) − ε_θ(x_t,t,∅)), where ∅ is the CLIP embedding of the empty string. Guidance scale w=7–9 is typical for Stable Diffusion. CLIP embeddings are normalized to unit norm before injection, and the cross-attention keys/values are derived from the CLIP features via learned linear projections.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class CrossAttentionBlock(nn.Module):
    """Single cross-attention layer: queries from image, keys/values from text."""
    def __init__(self, img_dim=64, text_dim=32, n_heads=4):
        super().__init__()
        self.n_heads = n_heads
        self.head_dim = img_dim // n_heads
        self.to_q = nn.Linear(img_dim, img_dim, bias=False)
        self.to_k = nn.Linear(text_dim, img_dim, bias=False)
        self.to_v = nn.Linear(text_dim, img_dim, bias=False)
        self.to_out = nn.Linear(img_dim, img_dim)

    def forward(self, x, text_emb):
        B, S, D = x.shape
        T = text_emb.shape[1]
        Q = self.to_q(x).view(B, S, self.n_heads, self.head_dim).transpose(1, 2)
        K = self.to_k(text_emb).view(B, T, self.n_heads, self.head_dim).transpose(1, 2)
        V = self.to_v(text_emb).view(B, T, self.n_heads, self.head_dim).transpose(1, 2)
        scale = self.head_dim ** -0.5
        attn = (Q @ K.transpose(-2, -1)) * scale
        attn = F.softmax(attn, dim=-1)  # (B, n_heads, S, T)
        out = (attn @ V).transpose(1, 2).reshape(B, S, D)
        return self.to_out(out)

torch.manual_seed(0)
B, S = 2, 16  # batch, spatial tokens
img_feat = torch.randn(B, S, 64)  # image latent tokens
null_text = torch.zeros(B, 8, 32)  # null text (empty prompt)
text_emb = torch.randn(B, 8, 32)  # CLIP text embedding
attn = CrossAttentionBlock(img_dim=64, text_dim=32)
out_cond = attn(img_feat, text_emb)
out_uncond = attn(img_feat, null_text)
eps_cfg = out_uncond + 7.5 * (out_cond - out_uncond)
print(f'Conditional output norm:   {out_cond.norm():.4f}')
print(f'Unconditional output norm: {out_uncond.norm():.4f}')
print(f'CFG output norm (w=7.5):   {eps_cfg.norm():.4f}')
```

## PAG and Guidance Variants

Perturbed Attention Guidance (PAG, 2024) replaces the null condition ∅ with identity self-attention maps — instead of dropping the condition, it degrades attention processing. This produces a different kind of structural guidance that improves fine-grained detail without over-saturating colors. SDXL guidance rescaling (Basile et al. 2023) addresses the color artifact problem at w > 7: the CFG output has a larger standard deviation than the conditional output, so rescaling ε_cfg by std(ε_cond)/std(ε_cfg) before the denoising step prevents over-saturation. Negative prompts are another practical CFG extension: replace ∅ with CLIP(negative_prompt) to actively steer away from undesirable attributes.

## Comparison of Guidance Methods

| Method | Classifier needed | Guidance formula | Optimal w | Artifacts at high w | Inversion support |
| --- | --- | --- | --- | --- | --- |
| No guidance (w=1) | No | ε_θ(x_t, t, c) | N/A | None | Yes (DDIM) |
| Classifier guidance | Yes — noisy p_φ(y|x_t) | ε_θ − s·√(1−ᾱ)·∇ log p_φ(y|x_t) | s=3–5 (ImageNet) | Noisy at high s | No — stochastic |
| CFG (Ho & Salimans 2022) | No — joint training | ε_uncond + w·(ε_cond−ε_uncond) | w=7–10 (text-to-image) | Color saturation, sharpness | Yes — with null cond |
| PAG (2024) | No | ε_identity_attn + w·(ε_cond−ε_identity_attn) | w=3–5 | Fewer artifacts than CFG | Yes |

> **Guidance Scale Tuning Rule of Thumb**: Start with w=7.5 for text-to-image tasks. If samples are over-saturated or have unnatural edges, reduce to w=5.0 and try guidance rescaling. If semantic alignment to the prompt is poor, increase to w=10–12. For class-conditional ImageNet models, optimal FID is usually at w=3–5. Always validate on a held-out prompt set — the optimal w varies across model families.

- CFG trains one network for both conditional and unconditional generation via condition dropout (p=0.1–0.2).
- Inference formula: ε_cfg = ε_uncond + w·(ε_cond − ε_uncond) — just two forward passes.
- w=0: unconditional; w=1: conditional; w>1: extrapolated toward high-class-probability modes.
- Optimal w for text-to-image is 7–10; for class-conditional ImageNet, 3–5.
- Negative prompts replace ∅ with CLIP(negative text), actively steering away from undesired attributes.
- Guidance rescaling (std normalization) fixes the color saturation artifacts seen at high guidance scales.

---

