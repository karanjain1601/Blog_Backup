---
title: "Luong Attention — Multiplicative Attention"
slug: "luong-attention"
description: "Luong's multiplicative attention variants — dot, general, and concat scoring — plus global vs local attention windows and input-feeding for state-aware decoding."
tags: ["deep-learning", "rnns", "sequence-models", "state-space-models"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Luong et al. (2015) published attention mechanisms that complemented and extended Bahdanau\u0027s original formulation. Where Bahdanau uses the previous decoder state sⱼ₋₁ to compute alignment, Luong uses the current decoder state sⱼ after it has already incorporated the encoded input. Luong also introduced three distinct scoring functions — dot, general, and concat — evaluated them empirically, and proposed local attention as a computationally cheaper alternative to global (all-encoder) attention. Their input-feeding technique further improved results by making the decoder aware of previous attention decisions."},{"type":"heading","level":2,"content":"Three Scoring Functions"},{"type":"text","content":"Luong\u0027s three scoring functions each represent a different trade-off between expressiveness and computation. The dot product score eᵢⱼ = sⱼᵀhᵢ is the simplest and fastest — it requires no learned parameters and works well when encoder and decoder hidden dimensions match. The general score eᵢⱼ = sⱼᵀWₐhᵢ introduces a learnable weight matrix Wₐ, enabling the model to project encoder and decoder states into a shared alignment space. The concat score eᵢⱼ = vᵀ tanh(Wₐ[sⱼ;hᵢ]) concatenates the states before projecting — equivalent to Bahdanau\u0027s formulation but using the current state sⱼ rather than the previous sⱼ₋₁."},{"type":"list","ordered":false,"items":["Dot: eᵢⱼ = sⱼᵀhᵢ — no parameters, O(H) per pair, requires same hidden dim","General: eᵢⱼ = sⱼᵀWₐhᵢ — learnable Wₐ ∈ ℝ^{dec_h × enc_h}, O(H²) params","Concat: eᵢⱼ = vᵀ tanh(Wₐ[sⱼ;hᵢ]) — same as Bahdanau but uses current decoder state","All three: αᵢⱼ = softmax(eᵢⱼ), cⱼ = Σᵢ αᵢⱼhᵢ — same context aggregation step","Luong uses sⱼ (after step), Bahdanau uses sⱼ₋₁ (before step) — key difference"]},{"type":"heading","level":2,"content":"Code 1 — Luong Dot, General, and Concat Attention"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass LuongAttention(nn.Module):\n    \"\"\"Luong attention with dot, general, or concat scoring.\"\"\"\n    def __init__(self, mode, hidden_dim):\n        super().__init__()\n        self.mode = mode\n        if mode == \u0027general\u0027:\n            self.W = nn.Linear(hidden_dim, hidden_dim, bias=False)\n        elif mode == \u0027concat\u0027:\n            self.W = nn.Linear(hidden_dim * 2, hidden_dim, bias=False)\n            self.v = nn.Linear(hidden_dim, 1, bias=False)\n\n    def score(self, s, h):\n        # s: (batch, hidden), h: (batch, src_len, hidden)\n        if self.mode == \u0027dot\u0027:\n            return torch.bmm(h, s.unsqueeze(-1)).squeeze(-1)      # (B, T)\n        elif self.mode == \u0027general\u0027:\n            return torch.bmm(h, self.W(s).unsqueeze(-1)).squeeze(-1)\n        elif self.mode == \u0027concat\u0027:\n            s_exp = s.unsqueeze(1).expand_as(h)\n            return self.v(torch.tanh(self.W(torch.cat([s_exp, h], dim=-1)))).squeeze(-1)\n\n    def forward(self, s, enc_outputs):\n        energy  = self.score(s, enc_outputs)           # (B, T)\n        alpha   = F.softmax(energy, dim=-1)\n        context = (alpha.unsqueeze(-1) * enc_outputs).sum(1)\n        return context, alpha\n\n# Compare all three modes on random tensors\nB, T, H = 4, 20, 256\nenc = torch.randn(B, T, H)\ndec_s = torch.randn(B, H)\nfor mode in [\u0027dot\u0027, \u0027general\u0027, \u0027concat\u0027]:\n    attn = LuongAttention(mode, H)\n    ctx, a = attn(dec_s, enc)\n    print(f\"{mode:8s} | context={ctx.shape} | weights_sum={a.sum(-1).mean():.3f}\")"},{"type":"heading","level":2,"content":"Global vs Local Attention"},{"type":"text","content":"Global attention attends over all Ts encoder positions at every decoder step — this is what Bahdanau uses and what most implementations default to. Luong proposed local attention as a computationally cheaper alternative: predict an aligned position pt for each decoder step, then attend only within a window [pt - D, pt + D] of 2D+1 encoder positions. The window position pt is predicted by the decoder state: pt = Ts · sigmoid(vₚᵀ tanh(Wₚsⱼ)). A Gaussian distribution G(pt, (D/2)²) further down-weights positions far from the center, encouraging smooth localized attention."},{"type":"list","ordered":false,"items":["Global: attends all Ts encoder positions — O(Ts) per step, full coverage","Local-m: monotone alignment, window shifts incrementally — no position prediction","Local-p: predict pt from decoder state, Gaussian penalty within window of width 2D+1","Local attention reduces computation from O(Ts·Tt) to O(D·Tt) — useful for long sources","Typical D = 10 captures ±10 positions, sufficient for most translation pairs"]},{"type":"callout","variant":"tip","title":"When to Use Local vs Global Attention","content":"Use global attention for standard sentence-level NMT — it is simpler and the O(T²) cost is negligible for T \u003c 200. Prefer local attention when encoding very long sequences (documents, audio frames) where attending every position at every step is prohibitive. For inference speed, local attention with a fixed window also enables more predictable latency."},{"type":"heading","level":2,"content":"Code 2 — Local Attention with Gaussian Window"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass LocalAttention(nn.Module):\n    \"\"\"Luong local-p attention: predict window center, apply Gaussian penalty.\"\"\"\n    def __init__(self, hidden_dim, window_D=5):\n        super().__init__()\n        self.D    = window_D\n        self.W_p  = nn.Linear(hidden_dim, hidden_dim)\n        self.v_p  = nn.Linear(hidden_dim, 1)\n        self.W_a  = nn.Linear(hidden_dim * 2, hidden_dim, bias=False)\n        self.v_a  = nn.Linear(hidden_dim, 1, bias=False)\n\n    def forward(self, s, enc_outputs, src_len):\n        # Predict aligned position pt in [0, src_len]\n        pt = src_len * torch.sigmoid(self.v_p(torch.tanh(self.W_p(s)))).squeeze(-1)  # (B,)\n        positions = torch.arange(src_len, dtype=torch.float32, device=s.device)      # (T,)\n        sigma = self.D / 2.0\n        gauss = torch.exp(-(positions - pt.unsqueeze(1))**2 / (2 * sigma**2))        # (B, T)\n        # Attention score\n        s_exp = s.unsqueeze(1).expand_as(enc_outputs)\n        e = self.v_a(torch.tanh(self.W_a(torch.cat([s_exp, enc_outputs], dim=-1)))).squeeze(-1)\n        alpha = F.softmax(e, dim=-1) * gauss\n        alpha = alpha / (alpha.sum(-1, keepdim=True) + 1e-9)   # renormalize\n        context = (alpha.unsqueeze(-1) * enc_outputs).sum(1)\n        return context, alpha, pt\n\nB, T, H = 2, 30, 128\nenc = torch.randn(B, T, H)\ns   = torch.randn(B, H)\nlocal_attn = LocalAttention(H, window_D=5)\nctx, weights, pos = local_attn(s, enc, T)\nprint(f\"Context: {ctx.shape}, Predicted positions: {[f\u0027{p:.1f}\u0027 for p in pos.tolist()]}\")"},{"type":"heading","level":2,"content":"Code 3 — Input-Feeding"},{"type":"text","content":"Input-feeding is Luong\u0027s key contribution beyond the scoring functions: at each decoder step, the previous attention vector (context vector) is concatenated to the current decoder input embedding before passing through the RNN cell. This makes the decoder aware of what it attended to in the previous step — modeling the alignment history rather than treating each step independently. Input-feeding consistently improves translation quality and is now standard practice."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass InputFeedingDecoder(nn.Module):\n    \"\"\"Luong decoder with input-feeding: previous context concatenated to input.\"\"\"\n    def __init__(self, vocab_size, embed_dim, hidden_dim):\n        super().__init__()\n        self.embed   = nn.Embedding(vocab_size, embed_dim)\n        # Input = embedding + previous attention context\n        self.rnn     = nn.GRUCell(embed_dim + hidden_dim, hidden_dim)\n        self.W_attn  = nn.Linear(hidden_dim, hidden_dim, bias=False)\n        self.W_c     = nn.Linear(hidden_dim * 2, hidden_dim)\n        self.fc      = nn.Linear(hidden_dim, vocab_size)\n\n    def attend(self, s, enc_out):\n        # Luong general attention using current state s\n        e     = torch.bmm(enc_out, self.W_attn(s).unsqueeze(-1)).squeeze(-1)\n        alpha = F.softmax(e, dim=-1)\n        return (alpha.unsqueeze(-1) * enc_out).sum(1), alpha\n\n    def forward(self, token, s, enc_out, prev_ctx):\n        emb       = self.embed(token)\n        s_new     = self.rnn(torch.cat([emb, prev_ctx], dim=-1), s)  # input-feeding\n        ctx, alpha = self.attend(s_new, enc_out)\n        h_tilde   = torch.tanh(self.W_c(torch.cat([s_new, ctx], dim=-1)))\n        return self.fc(h_tilde), s_new, ctx, alpha\n\nV, E, H, B, T = 8000, 128, 256, 2, 15\ndec     = InputFeedingDecoder(V, E, H)\nenc_out = torch.randn(B, T, H)\ns0, ctx0 = torch.randn(B, H), torch.zeros(B, H)\ntok     = torch.randint(0, V, (B,))\nlogits, s1, ctx1, a = dec(tok, s0, enc_out, ctx0)\nprint(f\"logits={logits.shape}, s={s1.shape}, ctx={ctx1.shape}, alpha_sum={a.sum(-1)}\")"},{"type":"heading","level":2,"content":"Code 4 — Bahdanau vs Luong Comparison"},{"type":"code","language":"python","content":"import numpy as np\nimport matplotlib.pyplot as plt\n\n# Simulated BLEU vs sentence length (based on Luong et al. 2015 findings)\nconfigs = {\n    \u0027No attention\u0027:           [21.5, 19.8, 17.2, 14.1, 10.3],\n    \u0027Bahdanau additive\u0027:      [26.1, 25.3, 23.9, 22.0, 19.5],\n    \u0027Luong dot\u0027:              [25.8, 25.0, 23.5, 21.7, 19.1],\n    \u0027Luong general\u0027:          [26.3, 25.6, 24.2, 22.4, 19.9],\n    \u0027Luong concat\u0027:           [25.9, 25.2, 23.8, 21.9, 19.4],\n    \u0027Luong + input-feeding\u0027:  [27.1, 26.4, 25.0, 23.3, 20.8],\n}\nlengths = [10, 20, 30, 40, 50]\ncolors  = [\u0027gray\u0027, \u0027steelblue\u0027, \u0027tomato\u0027, \u0027forestgreen\u0027, \u0027orange\u0027, \u0027purple\u0027]\nmarkers = [\u0027x\u0027, \u0027s\u0027, \u0027o\u0027, \u0027^\u0027, \u0027D\u0027, \u0027*\u0027]\n\nfig, ax = plt.subplots(figsize=(10, 6))\nfor (name, scores), color, marker in zip(configs.items(), colors, markers):\n    ax.plot(lengths, scores, marker=marker, color=color,\n            label=name, linewidth=2, markersize=7)\nax.set_xlabel(\u0027Sentence length (tokens)\u0027, fontsize=12)\nax.set_ylabel(\u0027BLEU Score\u0027, fontsize=12)\nax.set_title(\u0027Bahdanau vs Luong Attention Variants — BLEU vs Length\u0027, fontsize=13)\nax.legend(fontsize=9, loc=\u0027upper right\u0027)\nax.grid(True, alpha=0.3)\nplt.tight_layout()\nplt.savefig(\u0027attention_comparison.png\u0027, dpi=150)\nplt.show()\nprint(\"Luong + input-feeding outperforms all variants on long sequences.\")"},{"type":"heading","level":2,"content":"Key Differences from Bahdanau"},{"type":"text","content":"While Bahdanau and Luong attention share the weighted-sum context mechanism, they differ in four important ways. First, the decoder state timing: Bahdanau uses sⱼ₋₁ (before generating step j) to compute alignment, while Luong uses sⱼ (after running the RNN for step j) — Luong\u0027s approach gives the alignment network access to more up-to-date information. Second, the score functions: Bahdanau only defines the additive form; Luong systematically compares dot, general, and concat. Third, local vs global: Bahdanau uses global attention only. Fourth, input-feeding: Luong explicitly models alignment history by feeding the previous context vector back as decoder input."},{"type":"table","headers":["Property","Bahdanau","Luong dot","Luong general","Luong concat"],"rows":[["Decoder state used","sⱼ₋₁ (prev)","sⱼ (current)","sⱼ (current)","sⱼ (current)"],["Score formula","vᵀ tanh(W₁s+W₂h)","sᵀh","sᵀWh","vᵀ tanh(W[s;h])"],["Learnable params","W₁, W₂, v","None","W","W, v"],["Local attention","No","Yes","Yes","Yes"],["Input-feeding","No","Optional","Optional","Optional"],["Speed (relative)","Slow","Fastest","Fast","Moderate"]]},{"type":"text","content":"In practice, Luong dot and general attention with input-feeding are the most commonly adopted variants due to their simplicity and strong empirical performance. The dot product score is especially attractive because it requires no additional parameters and maps naturally to the scaled dot-product attention in the Transformer — simply divide by √d_k to stabilize gradients for larger hidden dimensions."},{"type":"list","ordered":false,"items":["Luong dot → scaled dot-product → Transformer attention (√d_k scaling added)","Multi-head attention applies H parallel dot-product attention heads with different projections","Input-feeding principle survives in Transformer as causal masking over past attention","Local attention concept re-emerges in Longformer and BigBird as sliding window attention","General attention with Wₐ = I reduces to dot attention — the bias-variance tradeoff in scoring"]}]"
---
# Luong Attention — Multiplicative Attention

Luong et al. (2015) published attention mechanisms that complemented and extended Bahdanau's original formulation. Where Bahdanau uses the previous decoder state sⱼ₋₁ to compute alignment, Luong uses the current decoder state sⱼ after it has already incorporated the encoded input. Luong also introduced three distinct scoring functions — dot, general, and concat — evaluated them empirically, and proposed local attention as a computationally cheaper alternative to global (all-encoder) attention. Their input-feeding technique further improved results by making the decoder aware of previous attention decisions.

## Three Scoring Functions

Luong's three scoring functions each represent a different trade-off between expressiveness and computation. The dot product score eᵢⱼ = sⱼᵀhᵢ is the simplest and fastest — it requires no learned parameters and works well when encoder and decoder hidden dimensions match. The general score eᵢⱼ = sⱼᵀWₐhᵢ introduces a learnable weight matrix Wₐ, enabling the model to project encoder and decoder states into a shared alignment space. The concat score eᵢⱼ = vᵀ tanh(Wₐ[sⱼ;hᵢ]) concatenates the states before projecting — equivalent to Bahdanau's formulation but using the current state sⱼ rather than the previous sⱼ₋₁.

- Dot: eᵢⱼ = sⱼᵀhᵢ — no parameters, O(H) per pair, requires same hidden dim
- General: eᵢⱼ = sⱼᵀWₐhᵢ — learnable Wₐ ∈ ℝ^{dec_h × enc_h}, O(H²) params
- Concat: eᵢⱼ = vᵀ tanh(Wₐ[sⱼ;hᵢ]) — same as Bahdanau but uses current decoder state
- All three: αᵢⱼ = softmax(eᵢⱼ), cⱼ = Σᵢ αᵢⱼhᵢ — same context aggregation step
- Luong uses sⱼ (after step), Bahdanau uses sⱼ₋₁ (before step) — key difference

## Code 1 — Luong Dot, General, and Concat Attention

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class LuongAttention(nn.Module):
    """Luong attention with dot, general, or concat scoring."""
    def __init__(self, mode, hidden_dim):
        super().__init__()
        self.mode = mode
        if mode == 'general':
            self.W = nn.Linear(hidden_dim, hidden_dim, bias=False)
        elif mode == 'concat':
            self.W = nn.Linear(hidden_dim * 2, hidden_dim, bias=False)
            self.v = nn.Linear(hidden_dim, 1, bias=False)

    def score(self, s, h):
        # s: (batch, hidden), h: (batch, src_len, hidden)
        if self.mode == 'dot':
            return torch.bmm(h, s.unsqueeze(-1)).squeeze(-1)      # (B, T)
        elif self.mode == 'general':
            return torch.bmm(h, self.W(s).unsqueeze(-1)).squeeze(-1)
        elif self.mode == 'concat':
            s_exp = s.unsqueeze(1).expand_as(h)
            return self.v(torch.tanh(self.W(torch.cat([s_exp, h], dim=-1)))).squeeze(-1)

    def forward(self, s, enc_outputs):
        energy  = self.score(s, enc_outputs)           # (B, T)
        alpha   = F.softmax(energy, dim=-1)
        context = (alpha.unsqueeze(-1) * enc_outputs).sum(1)
        return context, alpha

# Compare all three modes on random tensors
B, T, H = 4, 20, 256
enc = torch.randn(B, T, H)
dec_s = torch.randn(B, H)
for mode in ['dot', 'general', 'concat']:
    attn = LuongAttention(mode, H)
    ctx, a = attn(dec_s, enc)
    print(f"{mode:8s} | context={ctx.shape} | weights_sum={a.sum(-1).mean():.3f}")
```

## Global vs Local Attention

Global attention attends over all Ts encoder positions at every decoder step — this is what Bahdanau uses and what most implementations default to. Luong proposed local attention as a computationally cheaper alternative: predict an aligned position pt for each decoder step, then attend only within a window [pt - D, pt + D] of 2D+1 encoder positions. The window position pt is predicted by the decoder state: pt = Ts · sigmoid(vₚᵀ tanh(Wₚsⱼ)). A Gaussian distribution G(pt, (D/2)²) further down-weights positions far from the center, encouraging smooth localized attention.

- Global: attends all Ts encoder positions — O(Ts) per step, full coverage
- Local-m: monotone alignment, window shifts incrementally — no position prediction
- Local-p: predict pt from decoder state, Gaussian penalty within window of width 2D+1
- Local attention reduces computation from O(Ts·Tt) to O(D·Tt) — useful for long sources
- Typical D = 10 captures ±10 positions, sufficient for most translation pairs

> **When to Use Local vs Global Attention**: Use global attention for standard sentence-level NMT — it is simpler and the O(T²) cost is negligible for T < 200. Prefer local attention when encoding very long sequences (documents, audio frames) where attending every position at every step is prohibitive. For inference speed, local attention with a fixed window also enables more predictable latency.

## Code 2 — Local Attention with Gaussian Window

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class LocalAttention(nn.Module):
    """Luong local-p attention: predict window center, apply Gaussian penalty."""
    def __init__(self, hidden_dim, window_D=5):
        super().__init__()
        self.D    = window_D
        self.W_p  = nn.Linear(hidden_dim, hidden_dim)
        self.v_p  = nn.Linear(hidden_dim, 1)
        self.W_a  = nn.Linear(hidden_dim * 2, hidden_dim, bias=False)
        self.v_a  = nn.Linear(hidden_dim, 1, bias=False)

    def forward(self, s, enc_outputs, src_len):
        # Predict aligned position pt in [0, src_len]
        pt = src_len * torch.sigmoid(self.v_p(torch.tanh(self.W_p(s)))).squeeze(-1)  # (B,)
        positions = torch.arange(src_len, dtype=torch.float32, device=s.device)      # (T,)
        sigma = self.D / 2.0
        gauss = torch.exp(-(positions - pt.unsqueeze(1))**2 / (2 * sigma**2))        # (B, T)
        # Attention score
        s_exp = s.unsqueeze(1).expand_as(enc_outputs)
        e = self.v_a(torch.tanh(self.W_a(torch.cat([s_exp, enc_outputs], dim=-1)))).squeeze(-1)
        alpha = F.softmax(e, dim=-1) * gauss
        alpha = alpha / (alpha.sum(-1, keepdim=True) + 1e-9)   # renormalize
        context = (alpha.unsqueeze(-1) * enc_outputs).sum(1)
        return context, alpha, pt

B, T, H = 2, 30, 128
enc = torch.randn(B, T, H)
s   = torch.randn(B, H)
local_attn = LocalAttention(H, window_D=5)
ctx, weights, pos = local_attn(s, enc, T)
print(f"Context: {ctx.shape}, Predicted positions: {[f'{p:.1f}' for p in pos.tolist()]}")
```

## Code 3 — Input-Feeding

Input-feeding is Luong's key contribution beyond the scoring functions: at each decoder step, the previous attention vector (context vector) is concatenated to the current decoder input embedding before passing through the RNN cell. This makes the decoder aware of what it attended to in the previous step — modeling the alignment history rather than treating each step independently. Input-feeding consistently improves translation quality and is now standard practice.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class InputFeedingDecoder(nn.Module):
    """Luong decoder with input-feeding: previous context concatenated to input."""
    def __init__(self, vocab_size, embed_dim, hidden_dim):
        super().__init__()
        self.embed   = nn.Embedding(vocab_size, embed_dim)
        # Input = embedding + previous attention context
        self.rnn     = nn.GRUCell(embed_dim + hidden_dim, hidden_dim)
        self.W_attn  = nn.Linear(hidden_dim, hidden_dim, bias=False)
        self.W_c     = nn.Linear(hidden_dim * 2, hidden_dim)
        self.fc      = nn.Linear(hidden_dim, vocab_size)

    def attend(self, s, enc_out):
        # Luong general attention using current state s
        e     = torch.bmm(enc_out, self.W_attn(s).unsqueeze(-1)).squeeze(-1)
        alpha = F.softmax(e, dim=-1)
        return (alpha.unsqueeze(-1) * enc_out).sum(1), alpha

    def forward(self, token, s, enc_out, prev_ctx):
        emb       = self.embed(token)
        s_new     = self.rnn(torch.cat([emb, prev_ctx], dim=-1), s)  # input-feeding
        ctx, alpha = self.attend(s_new, enc_out)
        h_tilde   = torch.tanh(self.W_c(torch.cat([s_new, ctx], dim=-1)))
        return self.fc(h_tilde), s_new, ctx, alpha

V, E, H, B, T = 8000, 128, 256, 2, 15
dec     = InputFeedingDecoder(V, E, H)
enc_out = torch.randn(B, T, H)
s0, ctx0 = torch.randn(B, H), torch.zeros(B, H)
tok     = torch.randint(0, V, (B,))
logits, s1, ctx1, a = dec(tok, s0, enc_out, ctx0)
print(f"logits={logits.shape}, s={s1.shape}, ctx={ctx1.shape}, alpha_sum={a.sum(-1)}")
```

## Code 4 — Bahdanau vs Luong Comparison

```python
import numpy as np
import matplotlib.pyplot as plt

# Simulated BLEU vs sentence length (based on Luong et al. 2015 findings)
configs = {
    'No attention':           [21.5, 19.8, 17.2, 14.1, 10.3],
    'Bahdanau additive':      [26.1, 25.3, 23.9, 22.0, 19.5],
    'Luong dot':              [25.8, 25.0, 23.5, 21.7, 19.1],
    'Luong general':          [26.3, 25.6, 24.2, 22.4, 19.9],
    'Luong concat':           [25.9, 25.2, 23.8, 21.9, 19.4],
    'Luong + input-feeding':  [27.1, 26.4, 25.0, 23.3, 20.8],
}
lengths = [10, 20, 30, 40, 50]
colors  = ['gray', 'steelblue', 'tomato', 'forestgreen', 'orange', 'purple']
markers = ['x', 's', 'o', '^', 'D', '*']

fig, ax = plt.subplots(figsize=(10, 6))
for (name, scores), color, marker in zip(configs.items(), colors, markers):
    ax.plot(lengths, scores, marker=marker, color=color,
            label=name, linewidth=2, markersize=7)
ax.set_xlabel('Sentence length (tokens)', fontsize=12)
ax.set_ylabel('BLEU Score', fontsize=12)
ax.set_title('Bahdanau vs Luong Attention Variants — BLEU vs Length', fontsize=13)
ax.legend(fontsize=9, loc='upper right')
ax.grid(True, alpha=0.3)
plt.tight_layout()
plt.savefig('attention_comparison.png', dpi=150)
plt.show()
print("Luong + input-feeding outperforms all variants on long sequences.")
```

## Key Differences from Bahdanau

While Bahdanau and Luong attention share the weighted-sum context mechanism, they differ in four important ways. First, the decoder state timing: Bahdanau uses sⱼ₋₁ (before generating step j) to compute alignment, while Luong uses sⱼ (after running the RNN for step j) — Luong's approach gives the alignment network access to more up-to-date information. Second, the score functions: Bahdanau only defines the additive form; Luong systematically compares dot, general, and concat. Third, local vs global: Bahdanau uses global attention only. Fourth, input-feeding: Luong explicitly models alignment history by feeding the previous context vector back as decoder input.

| Property | Bahdanau | Luong dot | Luong general | Luong concat |
| --- | --- | --- | --- | --- |
| Decoder state used | sⱼ₋₁ (prev) | sⱼ (current) | sⱼ (current) | sⱼ (current) |
| Score formula | vᵀ tanh(W₁s+W₂h) | sᵀh | sᵀWh | vᵀ tanh(W[s;h]) |
| Learnable params | W₁, W₂, v | None | W | W, v |
| Local attention | No | Yes | Yes | Yes |
| Input-feeding | No | Optional | Optional | Optional |
| Speed (relative) | Slow | Fastest | Fast | Moderate |

In practice, Luong dot and general attention with input-feeding are the most commonly adopted variants due to their simplicity and strong empirical performance. The dot product score is especially attractive because it requires no additional parameters and maps naturally to the scaled dot-product attention in the Transformer — simply divide by √d_k to stabilize gradients for larger hidden dimensions.

- Luong dot → scaled dot-product → Transformer attention (√d_k scaling added)
- Multi-head attention applies H parallel dot-product attention heads with different projections
- Input-feeding principle survives in Transformer as causal masking over past attention
- Local attention concept re-emerges in Longformer and BigBird as sliding window attention
- General attention with Wₐ = I reduces to dot attention — the bias-variance tradeoff in scoring

