---
title: "Causal Masking — Autoregressive Attention for Decoder"
slug: "causal-masking-transformer"
description: "How the causal look-ahead mask prevents decoders from seeing future tokens, plus KV cache mechanics for efficient inference and combined causal-plus-padding masks."
tags: ["deep-learning", "transformers"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Transformer decoders generate text one token at a time. During training, teacher forcing presents the entire target sequence at once — but a critical invariant must be preserved: position i must not see any information from positions i+1, i+2, … (future tokens). Without this constraint the model would simply copy future tokens from the input instead of learning to predict them. The mechanism that enforces this invariant is the *causal mask*, also called the look-ahead mask."},{"type":"heading","level":2,"content":"Why Decoders Need Causal Masking"},{"type":"text","content":"In standard scaled dot-product attention, every query position attends to every key position. For encoder self-attention this is desirable — a word can use context from both directions. But for the decoder, this is cheating: position 2 seeing position 5 means the model has been given the answer it is supposed to predict. Causal masking breaks these forward-looking attention paths, restricting each query to attend only to itself and earlier positions."},{"type":"list","ordered":true,"items":["Compute raw attention scores: S = QKᵀ / √d_k, shape (L, L)","Create causal mask M: upper-triangular matrix of -∞ for positions where j \u003e i","Add mask: S_masked = S + M — future positions become -∞","Apply softmax: weights = softmax(S_masked, dim=-1) — -∞ becomes exactly 0","Output: O = weights · V — future tokens contribute zero weight"]},{"type":"callout","variant":"info","title":"Why -∞ and Not Zero?","content":"Setting logits to -∞ before softmax yields exactly zero in the output weights because exp(-∞) = 0. Setting logits to 0 would not mask the position — it would receive a softmax weight of 1/L instead. The -∞ trick exploits softmax normalisation to create perfect masking with no extra computation overhead."},{"type":"heading","level":2,"content":"The Look-Ahead Mask as an Upper Triangular Matrix"},{"type":"text","content":"The causal mask M is an L×L matrix where M[i, j] = -∞ if j \u003e i, else 0. In PyTorch this is created with torch.triu(torch.ones(L, L), diagonal=1) * -float(\u0027inf\u0027). The diagonal=1 argument starts the upper triangle one step above the main diagonal, so position i can still attend to itself (j = i) but not to any position j \u003e i. The resulting attention weight matrix is lower-triangular after softmax."},{"type":"heading","level":2,"content":"KV Cache — Reducing O(L²) to O(L) per Step"},{"type":"text","content":"At inference, the decoder generates tokens sequentially. Without a KV cache, computing attention at step t requires reprocessing all t-1 previous tokens to produce their keys and values — O(t) work per step, O(L²) total across a sequence of length L. With a KV cache, the keys and values for positions 0 through t-1 are stored after their first computation. Step t only computes Q, K, V for the single new token, appends K and V to the cache, and attends against the entire cached K and V. This reduces per-step cost from O(L) recompute to O(1) new computation plus O(L) attention, at the expense of memory proportional to L × 2 × n_heads × d_head."},{"type":"heading","level":2,"content":"Code 1 — Causal Mask from Scratch"},{"type":"text","content":"Building the upper-triangular -∞ mask and applying it inside scaled dot-product attention. Position 0 attends only to itself; position 5 attends to all 6 positions."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nimport math\n\ndef make_causal_mask(seq_len: int, device: str = \u0027cpu\u0027) -\u003e torch.Tensor:\n    \"\"\"Upper-triangular matrix of -inf; positions (i,j) with j\u003ei get -inf.\"\"\"\n    ones = torch.ones(seq_len, seq_len, device=device)\n    mask = torch.triu(ones, diagonal=1)       # 1 where j \u003e i, 0 otherwise\n    return mask * float(\u0027-inf\u0027)               # shape (L, L)\n\ndef causal_attention(Q: torch.Tensor, K: torch.Tensor,\n                     V: torch.Tensor) -\u003e tuple:\n    \"\"\"Scaled dot-product attention with causal mask. Q/K/V: (B, H, L, d).\"\"\"\n    d_k  = Q.size(-1)\n    L    = Q.size(-2)\n    scores = torch.matmul(Q, K.transpose(-2, -1)) / math.sqrt(d_k)\n    mask   = make_causal_mask(L, device=Q.device)\n    scores = scores + mask                    # broadcast over batch and heads\n    weights = F.softmax(scores, dim=-1)\n    return torch.matmul(weights, V), weights\n\n# Demo: batch=2, heads=4, seq_len=6, d_k=16\ntorch.manual_seed(42)\nB, H, L, d = 2, 4, 6, 16\nQ = torch.randn(B, H, L, d)\nK = torch.randn(B, H, L, d)\nV = torch.randn(B, H, L, d)\nout, weights = causal_attention(Q, K, V)\nprint(\u0027Output shape:\u0027, out.shape)             # (2, 4, 6, 16)\nprint(\u0027Pos 0 weights (only self):\u0027, weights[0, 0, 0].detach().numpy().round(3))\nprint(\u0027Pos 5 weights (all six): \u0027, weights[0, 0, 5].detach().numpy().round(3))"},{"type":"heading","level":2,"content":"Code 2 — Verifying Causal Attention Correctness"},{"type":"text","content":"A quantitative check confirming that the future-attention weight sum is effectively zero for every query position, proving the causal invariant holds numerically."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nimport math\nimport numpy as np\n\ndef make_causal_mask(L, device=\u0027cpu\u0027):\n    return torch.triu(torch.ones(L, L, device=device), diagonal=1) * float(\u0027-inf\u0027)\n\ndef causal_sdpa(Q, K, V):\n    d_k = Q.size(-1)\n    L   = Q.size(-2)\n    scores  = Q @ K.transpose(-2, -1) / math.sqrt(d_k)\n    scores += make_causal_mask(L, Q.device)\n    w = F.softmax(scores, dim=-1)\n    return w @ V, w\n\n# Use L=5 for readable output\ntorch.manual_seed(7)\nL = 5\nQ = K = V = torch.randn(1, 1, L, 8)   # shared Q, K, V for simplicity\n_, attn = causal_sdpa(Q, K, V)\nw = attn[0, 0].detach()\n\nprint(\u0027Attention weight matrix (rows=queries, cols=keys):\u0027)\nprint(np.array2string(w.numpy(), precision=3, suppress_small=True))\nprint()\nall_ok = True\nfor i in range(L):\n    future = w[i, i+1:].sum().item()\n    past   = w[i, :i+1].sum().item()\n    ok = future \u003c 1e-6\n    all_ok = all_ok and ok\n    print(f\u0027  pos {i}: past_sum={past:.4f}  future_sum={future:.2e}  ok={ok}\u0027)\nprint(f\u0027Causal invariant holds: {all_ok}\u0027)"},{"type":"heading","level":2,"content":"Code 3 — KV Cache for Autoregressive Inference"},{"type":"text","content":"A minimal attention module that caches keys and values across generation steps, processing one new token per forward pass instead of recomputing all past tokens."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport math\n\nclass CachedSelfAttention(nn.Module):\n    \"\"\"Single-head attention with KV cache for step-by-step inference.\"\"\"\n    def __init__(self, d_model: int):\n        super().__init__()\n        self.d  = d_model\n        self.Wq = nn.Linear(d_model, d_model, bias=False)\n        self.Wk = nn.Linear(d_model, d_model, bias=False)\n        self.Wv = nn.Linear(d_model, d_model, bias=False)\n        self.Wo = nn.Linear(d_model, d_model, bias=False)\n        self.cache_k = self.cache_v = None\n\n    def reset_cache(self):\n        self.cache_k = self.cache_v = None\n\n    def forward(self, x: torch.Tensor) -\u003e torch.Tensor:  # x: (B, 1, d)\n        q, k, v = self.Wq(x), self.Wk(x), self.Wv(x)\n        self.cache_k = k if self.cache_k is None else torch.cat([self.cache_k, k], 1)\n        self.cache_v = v if self.cache_v is None else torch.cat([self.cache_v, v], 1)\n        # Attend: new query vs all cached keys (no causal mask needed: single new Q)\n        scores  = q @ self.cache_k.transpose(-2, -1) / math.sqrt(self.d)\n        weights = torch.softmax(scores, dim=-1)\n        return self.Wo(weights @ self.cache_v)\n\n# Simulate 8-step autoregressive decoding\nmodel = CachedSelfAttention(d_model=64)\nfor step in range(8):\n    tok = torch.randn(1, 1, 64)         # single new token embedding\n    out = model(tok)\n    L_cache = model.cache_k.shape[1]\n    print(f\u0027Step {step+1}: out={tuple(out.shape)}, KV cache length={L_cache}\u0027)\nprint(\u0027Full recompute cost: O(L^2) total; KV cache cost: O(L) per step\u0027)"},{"type":"heading","level":2,"content":"Code 4 — Combined Causal and Padding Mask"},{"type":"text","content":"Batched decoding needs both a causal mask (no future tokens) and a padding mask (no PAD-key attention). Both use additive -∞ masking, so they can be summed directly before softmax."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nimport math\n\ndef make_causal_mask(L: int, device=\u0027cpu\u0027) -\u003e torch.Tensor:\n    return torch.triu(torch.ones(L, L, device=device), diagonal=1) * float(\u0027-inf\u0027)\n\ndef make_padding_mask(seq_lens, max_len: int, device=\u0027cpu\u0027) -\u003e torch.Tensor:\n    \"\"\"Returns (B, 1, max_len) additive mask: -inf at PAD positions.\"\"\"\n    ids   = torch.arange(max_len, device=device).unsqueeze(0)   # (1, L)\n    lens  = torch.tensor(seq_lens, device=device).unsqueeze(1)  # (B, 1)\n    is_pad = (ids \u003e= lens).float() * float(\u0027-inf\u0027)               # (B, L)\n    return is_pad.unsqueeze(1)                                   # (B, 1, L)\n\ndef combined_mask(seq_lens, max_len: int, device=\u0027cpu\u0027) -\u003e torch.Tensor:\n    \"\"\"Returns (B, max_len, max_len) combined additive mask.\"\"\"\n    causal = make_causal_mask(max_len, device)                   # (L, L)\n    pad    = make_padding_mask(seq_lens, max_len, device)        # (B, 1, L)\n    return causal.unsqueeze(0) + pad                             # (B, L, L)\n\n# Batch: seq 0 length=5 (full), seq 1 length=3 (padded to 5)\nseq_lens = [5, 3]\nmask = combined_mask(seq_lens, max_len=5)\nprint(\u0027Mask shape:\u0027, mask.shape)              # (2, 5, 5)\nprint(\u0027\\nSeq 0 (no padding, only causal -inf above diagonal):\u0027)\nprint(mask[0].numpy())\nprint(\u0027\\nSeq 1 (cols 3,4 are -inf everywhere — padding mask + causal):\u0027)\nprint(mask[1].numpy())"},{"type":"heading","level":2,"content":"Mask Variants at a Glance"},{"type":"table","headers":["Mask Type","Architecture","Positions Visible to i","Use Case","KV Cache at Inference"],"rows":[["No mask","Encoder","All positions","BERT, representation models","Not applicable"],["Causal only","Decoder","Current + past (j ≤ i)","GPT, autoregressive LLM","Yes — cache K and V"],["Bidirectional","Encoder","All positions (same as no mask)","Embedding, classification","Not applicable"],["Causal + padding","Decoder (batched)","Past only; PAD keys blocked","Batched text generation","Yes, PAD-aware"]]},{"type":"text","content":"Causal masking is the mechanism that makes autoregressive generation correct. Combined with a KV cache it enables efficient O(L) per-step inference rather than naively recomputing all previous keys and values each step. For production deployments handling very long contexts, KV cache memory management — quantization, eviction policies, sliding-window attention — becomes the primary engineering concern."}]"
---
# Causal Masking — Autoregressive Attention for Decoder

Transformer decoders generate text one token at a time. During training, teacher forcing presents the entire target sequence at once — but a critical invariant must be preserved: position i must not see any information from positions i+1, i+2, … (future tokens). Without this constraint the model would simply copy future tokens from the input instead of learning to predict them. The mechanism that enforces this invariant is the *causal mask*, also called the look-ahead mask.

## Why Decoders Need Causal Masking

In standard scaled dot-product attention, every query position attends to every key position. For encoder self-attention this is desirable — a word can use context from both directions. But for the decoder, this is cheating: position 2 seeing position 5 means the model has been given the answer it is supposed to predict. Causal masking breaks these forward-looking attention paths, restricting each query to attend only to itself and earlier positions.

1. Compute raw attention scores: S = QKᵀ / √d_k, shape (L, L)
2. Create causal mask M: upper-triangular matrix of -∞ for positions where j > i
3. Add mask: S_masked = S + M — future positions become -∞
4. Apply softmax: weights = softmax(S_masked, dim=-1) — -∞ becomes exactly 0
5. Output: O = weights · V — future tokens contribute zero weight

> **Why -∞ and Not Zero?**: Setting logits to -∞ before softmax yields exactly zero in the output weights because exp(-∞) = 0. Setting logits to 0 would not mask the position — it would receive a softmax weight of 1/L instead. The -∞ trick exploits softmax normalisation to create perfect masking with no extra computation overhead.

## The Look-Ahead Mask as an Upper Triangular Matrix

The causal mask M is an L×L matrix where M[i, j] = -∞ if j > i, else 0. In PyTorch this is created with torch.triu(torch.ones(L, L), diagonal=1) * -float('inf'). The diagonal=1 argument starts the upper triangle one step above the main diagonal, so position i can still attend to itself (j = i) but not to any position j > i. The resulting attention weight matrix is lower-triangular after softmax.

## KV Cache — Reducing O(L²) to O(L) per Step

At inference, the decoder generates tokens sequentially. Without a KV cache, computing attention at step t requires reprocessing all t-1 previous tokens to produce their keys and values — O(t) work per step, O(L²) total across a sequence of length L. With a KV cache, the keys and values for positions 0 through t-1 are stored after their first computation. Step t only computes Q, K, V for the single new token, appends K and V to the cache, and attends against the entire cached K and V. This reduces per-step cost from O(L) recompute to O(1) new computation plus O(L) attention, at the expense of memory proportional to L × 2 × n_heads × d_head.

## Code 1 — Causal Mask from Scratch

Building the upper-triangular -∞ mask and applying it inside scaled dot-product attention. Position 0 attends only to itself; position 5 attends to all 6 positions.

```python
import torch
import torch.nn.functional as F
import math

def make_causal_mask(seq_len: int, device: str = 'cpu') -> torch.Tensor:
    """Upper-triangular matrix of -inf; positions (i,j) with j>i get -inf."""
    ones = torch.ones(seq_len, seq_len, device=device)
    mask = torch.triu(ones, diagonal=1)       # 1 where j > i, 0 otherwise
    return mask * float('-inf')               # shape (L, L)

def causal_attention(Q: torch.Tensor, K: torch.Tensor,
                     V: torch.Tensor) -> tuple:
    """Scaled dot-product attention with causal mask. Q/K/V: (B, H, L, d)."""
    d_k  = Q.size(-1)
    L    = Q.size(-2)
    scores = torch.matmul(Q, K.transpose(-2, -1)) / math.sqrt(d_k)
    mask   = make_causal_mask(L, device=Q.device)
    scores = scores + mask                    # broadcast over batch and heads
    weights = F.softmax(scores, dim=-1)
    return torch.matmul(weights, V), weights

# Demo: batch=2, heads=4, seq_len=6, d_k=16
torch.manual_seed(42)
B, H, L, d = 2, 4, 6, 16
Q = torch.randn(B, H, L, d)
K = torch.randn(B, H, L, d)
V = torch.randn(B, H, L, d)
out, weights = causal_attention(Q, K, V)
print('Output shape:', out.shape)             # (2, 4, 6, 16)
print('Pos 0 weights (only self):', weights[0, 0, 0].detach().numpy().round(3))
print('Pos 5 weights (all six): ', weights[0, 0, 5].detach().numpy().round(3))
```

## Code 2 — Verifying Causal Attention Correctness

A quantitative check confirming that the future-attention weight sum is effectively zero for every query position, proving the causal invariant holds numerically.

```python
import torch
import torch.nn.functional as F
import math
import numpy as np

def make_causal_mask(L, device='cpu'):
    return torch.triu(torch.ones(L, L, device=device), diagonal=1) * float('-inf')

def causal_sdpa(Q, K, V):
    d_k = Q.size(-1)
    L   = Q.size(-2)
    scores  = Q @ K.transpose(-2, -1) / math.sqrt(d_k)
    scores += make_causal_mask(L, Q.device)
    w = F.softmax(scores, dim=-1)
    return w @ V, w

# Use L=5 for readable output
torch.manual_seed(7)
L = 5
Q = K = V = torch.randn(1, 1, L, 8)   # shared Q, K, V for simplicity
_, attn = causal_sdpa(Q, K, V)
w = attn[0, 0].detach()

print('Attention weight matrix (rows=queries, cols=keys):')
print(np.array2string(w.numpy(), precision=3, suppress_small=True))
print()
all_ok = True
for i in range(L):
    future = w[i, i+1:].sum().item()
    past   = w[i, :i+1].sum().item()
    ok = future < 1e-6
    all_ok = all_ok and ok
    print(f'  pos {i}: past_sum={past:.4f}  future_sum={future:.2e}  ok={ok}')
print(f'Causal invariant holds: {all_ok}')
```

## Code 3 — KV Cache for Autoregressive Inference

A minimal attention module that caches keys and values across generation steps, processing one new token per forward pass instead of recomputing all past tokens.

```python
import torch
import torch.nn as nn
import math

class CachedSelfAttention(nn.Module):
    """Single-head attention with KV cache for step-by-step inference."""
    def __init__(self, d_model: int):
        super().__init__()
        self.d  = d_model
        self.Wq = nn.Linear(d_model, d_model, bias=False)
        self.Wk = nn.Linear(d_model, d_model, bias=False)
        self.Wv = nn.Linear(d_model, d_model, bias=False)
        self.Wo = nn.Linear(d_model, d_model, bias=False)
        self.cache_k = self.cache_v = None

    def reset_cache(self):
        self.cache_k = self.cache_v = None

    def forward(self, x: torch.Tensor) -> torch.Tensor:  # x: (B, 1, d)
        q, k, v = self.Wq(x), self.Wk(x), self.Wv(x)
        self.cache_k = k if self.cache_k is None else torch.cat([self.cache_k, k], 1)
        self.cache_v = v if self.cache_v is None else torch.cat([self.cache_v, v], 1)
        # Attend: new query vs all cached keys (no causal mask needed: single new Q)
        scores  = q @ self.cache_k.transpose(-2, -1) / math.sqrt(self.d)
        weights = torch.softmax(scores, dim=-1)
        return self.Wo(weights @ self.cache_v)

# Simulate 8-step autoregressive decoding
model = CachedSelfAttention(d_model=64)
for step in range(8):
    tok = torch.randn(1, 1, 64)         # single new token embedding
    out = model(tok)
    L_cache = model.cache_k.shape[1]
    print(f'Step {step+1}: out={tuple(out.shape)}, KV cache length={L_cache}')
print('Full recompute cost: O(L^2) total; KV cache cost: O(L) per step')
```

## Code 4 — Combined Causal and Padding Mask

Batched decoding needs both a causal mask (no future tokens) and a padding mask (no PAD-key attention). Both use additive -∞ masking, so they can be summed directly before softmax.

```python
import torch
import torch.nn.functional as F
import math

def make_causal_mask(L: int, device='cpu') -> torch.Tensor:
    return torch.triu(torch.ones(L, L, device=device), diagonal=1) * float('-inf')

def make_padding_mask(seq_lens, max_len: int, device='cpu') -> torch.Tensor:
    """Returns (B, 1, max_len) additive mask: -inf at PAD positions."""
    ids   = torch.arange(max_len, device=device).unsqueeze(0)   # (1, L)
    lens  = torch.tensor(seq_lens, device=device).unsqueeze(1)  # (B, 1)
    is_pad = (ids >= lens).float() * float('-inf')               # (B, L)
    return is_pad.unsqueeze(1)                                   # (B, 1, L)

def combined_mask(seq_lens, max_len: int, device='cpu') -> torch.Tensor:
    """Returns (B, max_len, max_len) combined additive mask."""
    causal = make_causal_mask(max_len, device)                   # (L, L)
    pad    = make_padding_mask(seq_lens, max_len, device)        # (B, 1, L)
    return causal.unsqueeze(0) + pad                             # (B, L, L)

# Batch: seq 0 length=5 (full), seq 1 length=3 (padded to 5)
seq_lens = [5, 3]
mask = combined_mask(seq_lens, max_len=5)
print('Mask shape:', mask.shape)              # (2, 5, 5)
print('\nSeq 0 (no padding, only causal -inf above diagonal):')
print(mask[0].numpy())
print('\nSeq 1 (cols 3,4 are -inf everywhere — padding mask + causal):')
print(mask[1].numpy())
```

## Mask Variants at a Glance

| Mask Type | Architecture | Positions Visible to i | Use Case | KV Cache at Inference |
| --- | --- | --- | --- | --- |
| No mask | Encoder | All positions | BERT, representation models | Not applicable |
| Causal only | Decoder | Current + past (j ≤ i) | GPT, autoregressive LLM | Yes — cache K and V |
| Bidirectional | Encoder | All positions (same as no mask) | Embedding, classification | Not applicable |
| Causal + padding | Decoder (batched) | Past only; PAD keys blocked | Batched text generation | Yes, PAD-aware |

Causal masking is the mechanism that makes autoregressive generation correct. Combined with a KV cache it enables efficient O(L) per-step inference rather than naively recomputing all previous keys and values each step. For production deployments handling very long contexts, KV cache memory management — quantization, eviction policies, sliding-window attention — becomes the primary engineering concern.

