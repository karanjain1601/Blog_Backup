---
title: "IA3 — Learned Rescaling of Keys, Values, and FFN Activations"
slug: "ia3"
description: "IA3 (Liu et al., 2022) multiplies attention keys, values, and FFN intermediate activations by learned vectors — multiplicative rather than additive adaptation. Covers the three insertion points, trainable parameter count (~483K for LLaMA-7B), identity init, weight merging, and few-shot performance vs LoRA and adapters."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"IA3 (Infused Adapter by Inhibiting and Amplifying Inner Activations, Liu et al., 2022) is a parameter-efficient fine-tuning method that scales existing activations by learned vectors rather than adding new activations or weight offsets. Instead of inserting bottleneck layers or decomposing weight matrices, IA3 places element-wise multiplication by a learned vector at three strategic points in each transformer layer. This multiplicative design gives IA3 an extremely low parameter count while retaining the ability to selectively amplify or suppress specific activation dimensions."},{"type":"heading","level":2,"content":"Three Insertion Points"},{"type":"text","content":"IA3 introduces three learned scale vectors per transformer layer: (1) l_k ∈ ℝ^(d_k) scales the attention keys: K ← l_k ⊙ K, where ⊙ is element-wise multiplication. This modulates which key dimensions are amplified or suppressed during attention score computation. (2) l_v ∈ ℝ^(d_v) scales the attention values: V ← l_v ⊙ V. This controls which value dimensions are passed through to the output. (3) l_ff ∈ ℝ^(d_ff) scales the intermediate FFN activation (after the first linear + activation): x ← l_ff ⊙ σ(W_1 x). All other activations and all weight matrices remain unchanged. All scale vectors are initialized to ones, ensuring identity behavior at the start of training."},{"type":"text","content":"Parameter count for LLaMA-7B: with 32 attention heads of dimension 64, d_k_total = d_v_total = 32×64 = 2048. FFN intermediate d_ff = 11008. Per layer: 2048 + 2048 + 11008 = 15104 scalars. With 32 layers: 32×15104 = 483,328 ≈ 0.48M parameters. This is roughly 100× fewer parameters than LoRA with r=8 on the same model (which has approximately 50M trainable params across all Q, K, V, O projections). At 16-bit precision, the IA3 parameters occupy less than 1MB of storage."},{"type":"heading","level":2,"content":"IA3 Attention Implementation"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass IA3Attention(nn.Module):\n    \"\"\"\n    Multi-head attention with IA3 scaling on keys and values.\n    Backbone Q, K, V projections are frozen; only l_k, l_v are trained.\n    \"\"\"\n\n    def __init__(self, d_model: int, n_heads: int, freeze_backbone: bool = True):\n        super().__init__()\n        assert d_model % n_heads == 0\n        self.n_heads = n_heads\n        self.head_dim = d_model // n_heads\n        self.scale = self.head_dim ** -0.5\n        self.q_proj = nn.Linear(d_model, d_model, bias=False)\n        self.k_proj = nn.Linear(d_model, d_model, bias=False)\n        self.v_proj = nn.Linear(d_model, d_model, bias=False)\n        self.out_proj = nn.Linear(d_model, d_model, bias=False)\n        if freeze_backbone:\n            for module in [self.q_proj, self.k_proj, self.v_proj, self.out_proj]:\n                for param in module.parameters():\n                    param.requires_grad = False\n        # IA3 learned scales -- init to 1 (identity at start)\n        self.l_k = nn.Parameter(torch.ones(d_model))\n        self.l_v = nn.Parameter(torch.ones(d_model))\n\n    def forward(self, x: torch.Tensor) -\u003e torch.Tensor:\n        bsz, seq, d = x.shape\n        Q = self.q_proj(x)                 # no scaling on Q\n        K = self.k_proj(x) * self.l_k     # IA3 scale keys\n        V = self.v_proj(x) * self.l_v     # IA3 scale values\n        def split(t): return t.view(bsz, seq, self.n_heads, self.head_dim).transpose(1, 2)\n        Q, K, V = split(Q), split(K), split(V)\n        attn = F.softmax((Q @ K.transpose(-2, -1)) * self.scale, dim=-1)\n        out = (attn @ V).transpose(1, 2).contiguous().view(bsz, seq, d)\n        return self.out_proj(out)\n\nattn = IA3Attention(512, 8)\ntrainable = [(n, p.shape) for n, p in attn.named_parameters() if p.requires_grad]\nprint(f\u0027Trainable params: {trainable}\u0027)  # only l_k, l_v"},{"type":"heading","level":2,"content":"IA3 FFN and Parameter Count"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass IA3FFN(nn.Module):\n    \"\"\"\n    Feed-forward network with IA3 scaling on intermediate activation.\n    l_ff scales the output of the first linear + activation.\n    \"\"\"\n\n    def __init__(self, d_model: int, d_ff: int, freeze_backbone: bool = True):\n        super().__init__()\n        self.linear1 = nn.Linear(d_model, d_ff)\n        self.linear2 = nn.Linear(d_ff, d_model)\n        self.act = nn.GELU()\n        if freeze_backbone:\n            for p in self.parameters():\n                p.requires_grad = False\n        self.l_ff = nn.Parameter(torch.ones(d_ff))  # init=1 (identity)\n\n    def forward(self, x: torch.Tensor) -\u003e torch.Tensor:\n        h = self.act(self.linear1(x))  # (bsz, seq, d_ff)\n        h = h * self.l_ff             # IA3 scale\n        return self.linear2(h)\n\n# Parameter count across model sizes\nconfigs = [\n    (\u0027BERT-base\u0027,  768,  3072, 12),\n    (\u0027T5-Large\u0027,  1024,  4096, 24),\n    (\u0027LLaMA-7B\u0027,  4096, 11008, 32),\n    (\u0027LLaMA-13B\u0027, 5120, 13824, 40),\n]\nprint(f\u0027{\"Model\":\u003c14} {\"d_model\":\u003e8} {\"d_ff\":\u003e7} {\"Layers\":\u003e7} {\"IA3 Params\":\u003e12}\u0027)\nprint(\u0027-\u0027 * 55)\nfor name, d, dff, L in configs:\n    per_layer = d + d + dff  # l_k + l_v + l_ff\n    total = per_layer * L\n    print(f\u0027{name:\u003c14} {d:\u003e8} {dff:\u003e7} {L:\u003e7} {total:\u003e12,}\u0027)"},{"type":"heading","level":2,"content":"Weight Merging at Inference"},{"type":"text","content":"IA3 scaling vectors can be folded into the underlying weight matrices before deployment, eliminating any inference overhead. The key insight: multiplying activations by a learned vector is equivalent to scaling the corresponding rows of the projection matrix that produces those activations. Specifically: K ← l_k ⊙ W_K x is equivalent to K ← (diag(l_k) W_K) x. So W_K_merged = diag(l_k) @ W_K, i.e., multiply each row i of W_K by l_k[i]. Similarly for W_V. For l_ff scaling the FFN intermediate, it is equivalent to scaling the rows of W_2 (the second linear): W_2_merged[i, :] = l_ff[i] × W_2[i, :]."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ndef merge_ia3_into_weights(k_proj_weight: torch.Tensor,\n                           v_proj_weight: torch.Tensor,\n                           ffn2_weight: torch.Tensor,\n                           l_k: torch.Tensor,\n                           l_v: torch.Tensor,\n                           l_ff: torch.Tensor):\n    \"\"\"\n    Fold IA3 scaling vectors into projection weight matrices.\n    After merging, model uses standard linear layers with no inference overhead.\n    K_merged[i, :] = l_k[i] * k_proj_weight[i, :]\n    V_merged[i, :] = l_v[i] * v_proj_weight[i, :]\n    FFN2_merged[i, :] = l_ff[i] * ffn2_weight[i, :]   (linear2 rows)\n    \"\"\"\n    # Scale output rows of K and V projection weights\n    K_merged   = k_proj_weight * l_k.unsqueeze(1)    # (d_model, d_model)\n    V_merged   = v_proj_weight * l_v.unsqueeze(1)    # (d_model, d_model)\n    FFN2_merged = ffn2_weight  * l_ff.unsqueeze(1)   # (d_model, d_ff)\n    print(f\u0027K diff vs original: {(K_merged - k_proj_weight).abs().mean():.4f}\u0027)\n    return K_merged, V_merged, FFN2_merged\n\nd_model, d_ff = 512, 2048\nk_w = torch.randn(d_model, d_model)\nv_w = torch.randn(d_model, d_model)\nffn2_w = torch.randn(d_model, d_ff)\nl_k  = torch.ones(d_model) + 0.1 * torch.randn(d_model)\nl_v  = torch.ones(d_model) + 0.1 * torch.randn(d_model)\nl_ff = torch.ones(d_ff) + 0.1 * torch.randn(d_ff)\nK_m, V_m, FFN_m = merge_ia3_into_weights(k_w, v_w, ffn2_w, l_k, l_v, l_ff)\nprint(f\u0027Merged shapes: K={K_m.shape}, V={V_m.shape}, FFN2={FFN_m.shape}\u0027)"},{"type":"heading","level":2,"content":"Few-Shot Learning Comparison"},{"type":"text","content":"IA3 was designed specifically for few-shot fine-tuning in the T-Few paper (Liu et al., 2022). The key intuition: with very few labeled examples (10–50), methods with more trainable parameters overfit more easily. IA3\u0027s ≈480K parameters for a 7B model provides a much lower-capacity learner than LoRA\u0027s ≈50M, reducing the risk of memorizing the few training examples rather than learning generalizable patterns."},{"type":"code","language":"python","content":"import numpy as np\n\n# Approximate accuracy from T-Few paper (Liu et al. 2022)\n# T5-Large (770M) backbone, averaged over SuperGLUE-style tasks\nshot_counts = [10, 50, 100, 500]\nia3_acc     = [67.3, 74.8, 78.2, 82.1]\nlora_acc    = [63.1, 72.4, 77.1, 82.5]  # LoRA r=8\nadapter_acc = [61.4, 71.8, 76.8, 82.0]  # Pfeiffer adapters m=64\nfull_ft_acc = [58.2, 70.1, 76.3, 83.0]  # prone to overfitting at low shot\n\nprint(f\u0027{\"Shots\":\u003e8} | {\"IA3\":\u003e8} | {\"LoRA r=8\":\u003e10} | {\"Adapters\":\u003e10} | {\"Full FT\":\u003e9}\u0027)\nprint(\u0027-\u0027 * 55)\nfor s, ia, lo, ad, fft in zip(shot_counts, ia3_acc, lora_acc, adapter_acc, full_ft_acc):\n    print(f\u0027{s:\u003e8} | {ia:\u003e8.1f} | {lo:\u003e10.1f} | {ad:\u003e10.1f} | {fft:\u003e9.1f}\u0027)\n\nprint()\nprint(\u0027IA3 advantage is largest at low shot counts (10-50):\u0027)\nfor s, ia, lo in zip(shot_counts[:2], ia3_acc[:2], lora_acc[:2]):\n    print(f\u0027  {s}-shot: IA3 {ia:.1f} vs LoRA {lo:.1f} (+{ia-lo:.1f})\u0027)"},{"type":"heading","level":2,"content":"IA3 vs Other PEFT Methods"},{"type":"table","headers":["Method","Trainable Params (7B)","Insertion Type","Multiplicative/Additive","Merge at Inference","Few-Shot Suitability"],"rows":[["IA3","~483K (3 vectors/layer)","K, V, FFN intermediate scaling","Multiplicative","Yes — fold l into weight rows","Excellent — lowest overfit risk"],["LoRA (r=8)","~50M (2 matrices/layer)","W += BA (low-rank additive)","Additive","Yes — W_merged = W + BA","Good — moderate params"],["VeRA","~65K (shared random B, A)","W += λ_b diag(b) B diag(a) A","Additive with scaling","Yes — merge like LoRA","Very good — very few params"],["Adapter (Pfeiffer)","~200M (bottleneck FFN)","Serial FFN after each sub-layer","Additive","No — adds extra compute path","Moderate — more params to overfit"],["Prompt Tuning","~100K (input prefix only)","Input embedding prefix","Neither (input modification)","N/A — prefix always present","Poor at \u003c10B scale"]]},{"type":"heading","level":2,"content":"T-Few: IA3 with Task-Specific Pretraining"},{"type":"text","content":"The T-Few paper (Liu et al., 2022) demonstrates that IA3 combined with multitask pretraining (T0 model) achieves state-of-the-art few-shot performance with far fewer trainable parameters than GPT-3 (175B) despite using T5-Large (770M). The T-Few recipe: (1) start from T0, a T5-Large pretrained on 35 NLP datasets with natural language prompts; (2) apply IA3 and train on K examples per task; (3) use unlikelihood training to improve calibration. At 10-shot, T-Few (770M params, 483K IA3 params fine-tuned) outperforms GPT-3 (175B, zero-shot) on 9 of 11 benchmarks."},{"type":"heading","level":2,"content":"Using IA3 with the PEFT Library"},{"type":"text","content":"The HuggingFace PEFT library provides native IA3 support via IA3Config. The key parameters are target_modules (which projection matrices to apply l_k and l_v to, typically [\u0027k_proj\u0027, \u0027v_proj\u0027]) and feedforward_modules (which FFN layers to apply l_ff to, typically [\u0027down_proj\u0027] for LLaMA-style models or [\u0027fc2\u0027] for BERT-style). After training, call model.merge_adapter() to fold the scale vectors into the base weights for zero-overhead inference. The merged model is indistinguishable from a standard model and can be served without the PEFT library."},{"type":"callout","variant":"info","title":"Multiplicative vs Additive","content":"IA3\u0027s multiplicative scaling preserves the subspace structure of pretrained activations — unlike additive adapters (LoRA, adapters), IA3 can only scale existing features, not create new ones. This makes it ideal for task-specific emphasis but weaker for structural adaptation."},{"type":"heading","level":2,"content":"Practical Recommendations"},{"type":"list","ordered":false,"items":["IA3 init: l_k = l_v = l_ff = 1 (ones vector) — ensures identity mapping at the start of training.","Parameter count: ~360–480K for 7B models — roughly 100× fewer than LoRA r=8.","Weight merging: fold l_k into K projection rows, l_v into V projection rows, l_ff into linear2 rows at inference.","Few-shot regime: IA3 outperforms LoRA and adapters at 10–50 shots due to lower parameter count reducing overfitting.","IA3 cannot introduce new feature directions — if the task requires new representations, LoRA or adapters are preferable.","Use peft library: IA3Config with target_modules=[\u0027k_proj\u0027,\u0027v_proj\u0027] and feedforward_modules=[\u0027down_proj\u0027].","For instruction-following fine-tuning at 10B+ scale, IA3 is competitive with LoRA at 100× fewer parameters."]},{"type":"divider"}]"
---
# IA3 — Learned Rescaling of Keys, Values, and FFN Activations

IA3 (Infused Adapter by Inhibiting and Amplifying Inner Activations, Liu et al., 2022) is a parameter-efficient fine-tuning method that scales existing activations by learned vectors rather than adding new activations or weight offsets. Instead of inserting bottleneck layers or decomposing weight matrices, IA3 places element-wise multiplication by a learned vector at three strategic points in each transformer layer. This multiplicative design gives IA3 an extremely low parameter count while retaining the ability to selectively amplify or suppress specific activation dimensions.

## Three Insertion Points

IA3 introduces three learned scale vectors per transformer layer: (1) l_k ∈ ℝ^(d_k) scales the attention keys: K ← l_k ⊙ K, where ⊙ is element-wise multiplication. This modulates which key dimensions are amplified or suppressed during attention score computation. (2) l_v ∈ ℝ^(d_v) scales the attention values: V ← l_v ⊙ V. This controls which value dimensions are passed through to the output. (3) l_ff ∈ ℝ^(d_ff) scales the intermediate FFN activation (after the first linear + activation): x ← l_ff ⊙ σ(W_1 x). All other activations and all weight matrices remain unchanged. All scale vectors are initialized to ones, ensuring identity behavior at the start of training.

Parameter count for LLaMA-7B: with 32 attention heads of dimension 64, d_k_total = d_v_total = 32×64 = 2048. FFN intermediate d_ff = 11008. Per layer: 2048 + 2048 + 11008 = 15104 scalars. With 32 layers: 32×15104 = 483,328 ≈ 0.48M parameters. This is roughly 100× fewer parameters than LoRA with r=8 on the same model (which has approximately 50M trainable params across all Q, K, V, O projections). At 16-bit precision, the IA3 parameters occupy less than 1MB of storage.

## IA3 Attention Implementation

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class IA3Attention(nn.Module):
    """
    Multi-head attention with IA3 scaling on keys and values.
    Backbone Q, K, V projections are frozen; only l_k, l_v are trained.
    """

    def __init__(self, d_model: int, n_heads: int, freeze_backbone: bool = True):
        super().__init__()
        assert d_model % n_heads == 0
        self.n_heads = n_heads
        self.head_dim = d_model // n_heads
        self.scale = self.head_dim ** -0.5
        self.q_proj = nn.Linear(d_model, d_model, bias=False)
        self.k_proj = nn.Linear(d_model, d_model, bias=False)
        self.v_proj = nn.Linear(d_model, d_model, bias=False)
        self.out_proj = nn.Linear(d_model, d_model, bias=False)
        if freeze_backbone:
            for module in [self.q_proj, self.k_proj, self.v_proj, self.out_proj]:
                for param in module.parameters():
                    param.requires_grad = False
        # IA3 learned scales -- init to 1 (identity at start)
        self.l_k = nn.Parameter(torch.ones(d_model))
        self.l_v = nn.Parameter(torch.ones(d_model))

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        bsz, seq, d = x.shape
        Q = self.q_proj(x)                 # no scaling on Q
        K = self.k_proj(x) * self.l_k     # IA3 scale keys
        V = self.v_proj(x) * self.l_v     # IA3 scale values
        def split(t): return t.view(bsz, seq, self.n_heads, self.head_dim).transpose(1, 2)
        Q, K, V = split(Q), split(K), split(V)
        attn = F.softmax((Q @ K.transpose(-2, -1)) * self.scale, dim=-1)
        out = (attn @ V).transpose(1, 2).contiguous().view(bsz, seq, d)
        return self.out_proj(out)

attn = IA3Attention(512, 8)
trainable = [(n, p.shape) for n, p in attn.named_parameters() if p.requires_grad]
print(f'Trainable params: {trainable}')  # only l_k, l_v
```

## IA3 FFN and Parameter Count

```python
import torch
import torch.nn as nn

class IA3FFN(nn.Module):
    """
    Feed-forward network with IA3 scaling on intermediate activation.
    l_ff scales the output of the first linear + activation.
    """

    def __init__(self, d_model: int, d_ff: int, freeze_backbone: bool = True):
        super().__init__()
        self.linear1 = nn.Linear(d_model, d_ff)
        self.linear2 = nn.Linear(d_ff, d_model)
        self.act = nn.GELU()
        if freeze_backbone:
            for p in self.parameters():
                p.requires_grad = False
        self.l_ff = nn.Parameter(torch.ones(d_ff))  # init=1 (identity)

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        h = self.act(self.linear1(x))  # (bsz, seq, d_ff)
        h = h * self.l_ff             # IA3 scale
        return self.linear2(h)

# Parameter count across model sizes
configs = [
    ('BERT-base',  768,  3072, 12),
    ('T5-Large',  1024,  4096, 24),
    ('LLaMA-7B',  4096, 11008, 32),
    ('LLaMA-13B', 5120, 13824, 40),
]
print(f'{"Model":<14} {"d_model":>8} {"d_ff":>7} {"Layers":>7} {"IA3 Params":>12}')
print('-' * 55)
for name, d, dff, L in configs:
    per_layer = d + d + dff  # l_k + l_v + l_ff
    total = per_layer * L
    print(f'{name:<14} {d:>8} {dff:>7} {L:>7} {total:>12,}')
```

## Weight Merging at Inference

IA3 scaling vectors can be folded into the underlying weight matrices before deployment, eliminating any inference overhead. The key insight: multiplying activations by a learned vector is equivalent to scaling the corresponding rows of the projection matrix that produces those activations. Specifically: K ← l_k ⊙ W_K x is equivalent to K ← (diag(l_k) W_K) x. So W_K_merged = diag(l_k) @ W_K, i.e., multiply each row i of W_K by l_k[i]. Similarly for W_V. For l_ff scaling the FFN intermediate, it is equivalent to scaling the rows of W_2 (the second linear): W_2_merged[i, :] = l_ff[i] × W_2[i, :].

```python
import torch
import torch.nn as nn

def merge_ia3_into_weights(k_proj_weight: torch.Tensor,
                           v_proj_weight: torch.Tensor,
                           ffn2_weight: torch.Tensor,
                           l_k: torch.Tensor,
                           l_v: torch.Tensor,
                           l_ff: torch.Tensor):
    """
    Fold IA3 scaling vectors into projection weight matrices.
    After merging, model uses standard linear layers with no inference overhead.
    K_merged[i, :] = l_k[i] * k_proj_weight[i, :]
    V_merged[i, :] = l_v[i] * v_proj_weight[i, :]
    FFN2_merged[i, :] = l_ff[i] * ffn2_weight[i, :]   (linear2 rows)
    """
    # Scale output rows of K and V projection weights
    K_merged   = k_proj_weight * l_k.unsqueeze(1)    # (d_model, d_model)
    V_merged   = v_proj_weight * l_v.unsqueeze(1)    # (d_model, d_model)
    FFN2_merged = ffn2_weight  * l_ff.unsqueeze(1)   # (d_model, d_ff)
    print(f'K diff vs original: {(K_merged - k_proj_weight).abs().mean():.4f}')
    return K_merged, V_merged, FFN2_merged

d_model, d_ff = 512, 2048
k_w = torch.randn(d_model, d_model)
v_w = torch.randn(d_model, d_model)
ffn2_w = torch.randn(d_model, d_ff)
l_k  = torch.ones(d_model) + 0.1 * torch.randn(d_model)
l_v  = torch.ones(d_model) + 0.1 * torch.randn(d_model)
l_ff = torch.ones(d_ff) + 0.1 * torch.randn(d_ff)
K_m, V_m, FFN_m = merge_ia3_into_weights(k_w, v_w, ffn2_w, l_k, l_v, l_ff)
print(f'Merged shapes: K={K_m.shape}, V={V_m.shape}, FFN2={FFN_m.shape}')
```

## Few-Shot Learning Comparison

IA3 was designed specifically for few-shot fine-tuning in the T-Few paper (Liu et al., 2022). The key intuition: with very few labeled examples (10–50), methods with more trainable parameters overfit more easily. IA3's ≈480K parameters for a 7B model provides a much lower-capacity learner than LoRA's ≈50M, reducing the risk of memorizing the few training examples rather than learning generalizable patterns.

```python
import numpy as np

# Approximate accuracy from T-Few paper (Liu et al. 2022)
# T5-Large (770M) backbone, averaged over SuperGLUE-style tasks
shot_counts = [10, 50, 100, 500]
ia3_acc     = [67.3, 74.8, 78.2, 82.1]
lora_acc    = [63.1, 72.4, 77.1, 82.5]  # LoRA r=8
adapter_acc = [61.4, 71.8, 76.8, 82.0]  # Pfeiffer adapters m=64
full_ft_acc = [58.2, 70.1, 76.3, 83.0]  # prone to overfitting at low shot

print(f'{"Shots":>8} | {"IA3":>8} | {"LoRA r=8":>10} | {"Adapters":>10} | {"Full FT":>9}')
print('-' * 55)
for s, ia, lo, ad, fft in zip(shot_counts, ia3_acc, lora_acc, adapter_acc, full_ft_acc):
    print(f'{s:>8} | {ia:>8.1f} | {lo:>10.1f} | {ad:>10.1f} | {fft:>9.1f}')

print()
print('IA3 advantage is largest at low shot counts (10-50):')
for s, ia, lo in zip(shot_counts[:2], ia3_acc[:2], lora_acc[:2]):
    print(f'  {s}-shot: IA3 {ia:.1f} vs LoRA {lo:.1f} (+{ia-lo:.1f})')
```

## IA3 vs Other PEFT Methods

| Method | Trainable Params (7B) | Insertion Type | Multiplicative/Additive | Merge at Inference | Few-Shot Suitability |
| --- | --- | --- | --- | --- | --- |
| IA3 | ~483K (3 vectors/layer) | K, V, FFN intermediate scaling | Multiplicative | Yes — fold l into weight rows | Excellent — lowest overfit risk |
| LoRA (r=8) | ~50M (2 matrices/layer) | W += BA (low-rank additive) | Additive | Yes — W_merged = W + BA | Good — moderate params |
| VeRA | ~65K (shared random B, A) | W += λ_b diag(b) B diag(a) A | Additive with scaling | Yes — merge like LoRA | Very good — very few params |
| Adapter (Pfeiffer) | ~200M (bottleneck FFN) | Serial FFN after each sub-layer | Additive | No — adds extra compute path | Moderate — more params to overfit |
| Prompt Tuning | ~100K (input prefix only) | Input embedding prefix | Neither (input modification) | N/A — prefix always present | Poor at <10B scale |

## T-Few: IA3 with Task-Specific Pretraining

The T-Few paper (Liu et al., 2022) demonstrates that IA3 combined with multitask pretraining (T0 model) achieves state-of-the-art few-shot performance with far fewer trainable parameters than GPT-3 (175B) despite using T5-Large (770M). The T-Few recipe: (1) start from T0, a T5-Large pretrained on 35 NLP datasets with natural language prompts; (2) apply IA3 and train on K examples per task; (3) use unlikelihood training to improve calibration. At 10-shot, T-Few (770M params, 483K IA3 params fine-tuned) outperforms GPT-3 (175B, zero-shot) on 9 of 11 benchmarks.

## Using IA3 with the PEFT Library

The HuggingFace PEFT library provides native IA3 support via IA3Config. The key parameters are target_modules (which projection matrices to apply l_k and l_v to, typically ['k_proj', 'v_proj']) and feedforward_modules (which FFN layers to apply l_ff to, typically ['down_proj'] for LLaMA-style models or ['fc2'] for BERT-style). After training, call model.merge_adapter() to fold the scale vectors into the base weights for zero-overhead inference. The merged model is indistinguishable from a standard model and can be served without the PEFT library.

> **Multiplicative vs Additive**: IA3's multiplicative scaling preserves the subspace structure of pretrained activations — unlike additive adapters (LoRA, adapters), IA3 can only scale existing features, not create new ones. This makes it ideal for task-specific emphasis but weaker for structural adaptation.

## Practical Recommendations

- IA3 init: l_k = l_v = l_ff = 1 (ones vector) — ensures identity mapping at the start of training.
- Parameter count: ~360–480K for 7B models — roughly 100× fewer than LoRA r=8.
- Weight merging: fold l_k into K projection rows, l_v into V projection rows, l_ff into linear2 rows at inference.
- Few-shot regime: IA3 outperforms LoRA and adapters at 10–50 shots due to lower parameter count reducing overfitting.
- IA3 cannot introduce new feature directions — if the task requires new representations, LoRA or adapters are preferable.
- Use peft library: IA3Config with target_modules=['k_proj','v_proj'] and feedforward_modules=['down_proj'].
- For instruction-following fine-tuning at 10B+ scale, IA3 is competitive with LoRA at 100× fewer parameters.

---

