---
title: "Self-Attention vs Cross-Attention — Encoder and Decoder Patterns"
slug: "self-vs-cross-attention"
description: "Contrast self-attention (Q=K=V from same sequence) with cross-attention (Q from decoder, K/V from encoder), implement both from scratch, and trace their roles in BERT, GPT, T5, and diffusion models."
tags: ["deep-learning", "transformers", "attention"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Attention mechanisms differ fundamentally in where their Q, K, and V inputs come from. Self-attention takes all three from the same sequence, allowing each position to attend to every other position in that same sequence. Cross-attention takes Q from one sequence and K, V from a different sequence, bridging information between two separate representations. These two variants are not interchangeable — each is used in specific architectural positions with specific computational purposes."},{"type":"heading","level":2,"content":"Self-Attention — Definition and Properties"},{"type":"text","content":"In self-attention Q = X·WQ, K = X·WK, V = X·WV where X is the same input sequence. Every position produces a query that is scored against keys from all other positions in X — the attention matrix A ∈ ℝ^{n×n} is square. Bidirectional self-attention allows each position to attend to all others (including future positions), making the representations context-aware in both directions. Causal (masked) self-attention applies an upper-triangular mask of −∞ to the score matrix before softmax, preventing position i from attending to positions j \u003e i. This preserves the autoregressive property required for text generation."},{"type":"code","language":"python","content":"import numpy as np\n\ndef self_attention(X, W_Q, W_K, W_V, causal=False):\n    # X: (n, d_model); Q=K=V all derived from same X\n    Q = X @ W_Q    # (n, dk)\n    K = X @ W_K    # (n, dk)\n    V = X @ W_V    # (n, dv)\n    dk = Q.shape[-1]\n    S = Q @ K.T / np.sqrt(dk)    # (n, n) — square matrix\n    if causal:\n        # Upper triangle -\u003e -inf so softmax gives 0 weight\n        mask = np.triu(np.ones_like(S), k=1) * -1e9\n        S = S + mask\n    S -= S.max(axis=-1, keepdims=True)\n    A = np.exp(S); A /= A.sum(axis=-1, keepdims=True)\n    return A @ V, A\n\nnp.random.seed(42)\nn, d_model, dk, dv = 6, 64, 32, 32\nX = np.random.randn(n, d_model)\nW_Q = np.random.randn(d_model, dk) * 0.1\nW_K = np.random.randn(d_model, dk) * 0.1\nW_V = np.random.randn(d_model, dv) * 0.1\n\n_, A_bi  = self_attention(X, W_Q, W_K, W_V, causal=False)\n_, A_cau = self_attention(X, W_Q, W_K, W_V, causal=True)\nprint(\u0027Bidirectional SA shape:\u0027, A_bi.shape, \u0027(n x n, square)\u0027)\nprint(\u0027Upper triangle zero in causal SA:\u0027, np.allclose(np.triu(A_cau, 1), 0))\nprint(\u0027Causal: position 0 attends only to itself:\u0027, A_cau[0].round(4))\nprint(\u0027Causal: position 5 attends to all 6:\u0027, (A_cau[5] \u003e 1e-6).sum(), \u0027positions\u0027)"},{"type":"heading","level":2,"content":"Cross-Attention — Definition and Properties"},{"type":"text","content":"In cross-attention the query Q comes from one sequence (e.g., decoder states) while keys K and values V come from a second sequence (e.g., encoder output). Queries and keys must share the same inner dimension dₖ but the two sequences can have different lengths: nq ≠ nk. The attention matrix A ∈ ℝ^{nq×nk} is rectangular — each of the nq query positions attends over all nk key-value positions. No causal masking is needed (and none is applied) because the query sequence is attending to a fully-observed context sequence, not to its own future."},{"type":"code","language":"python","content":"import numpy as np\n\ndef cross_attention(Q_seq, KV_seq, W_Q, W_K, W_V):\n    # Q_seq: (nq, d_q) — decoder states; KV_seq: (nk, d_kv) — encoder output\n    Q = Q_seq  @ W_Q    # (nq, dk)\n    K = KV_seq @ W_K    # (nk, dk)\n    V = KV_seq @ W_V    # (nk, dv)\n    dk = Q.shape[-1]\n    S = Q @ K.T / np.sqrt(dk)    # (nq, nk) — RECTANGULAR, nq != nk\n    S -= S.max(axis=-1, keepdims=True)\n    A = np.exp(S); A /= A.sum(axis=-1, keepdims=True)\n    return A @ V, A              # output: (nq, dv), weights: (nq, nk)\n\nnp.random.seed(7)\nnq, nk, d_model, dk, dv = 4, 10, 64, 32, 32\ndec_states = np.random.randn(nq, d_model)   # short target sequence\nenc_states  = np.random.randn(nk, d_model)  # longer source sequence\nW_Q = np.random.randn(d_model, dk) * 0.1\nW_K = np.random.randn(d_model, dk) * 0.1\nW_V = np.random.randn(d_model, dv) * 0.1\n\nout, A = cross_attention(dec_states, enc_states, W_Q, W_K, W_V)\nprint(\u0027Dec states:\u0027, dec_states.shape, \u0027  Enc states:\u0027, enc_states.shape)\nprint(\u0027Attention matrix:\u0027, A.shape, \u0027\u003c- rectangular (nq x nk)\u0027)\nprint(\u0027Output:\u0027, out.shape)\nprint(\u0027Row sums (should be 1):\u0027, A.sum(axis=1).round(5))"},{"type":"callout","variant":"warning","title":"Key Difference — Where Q, K, V Come From","content":"Self-attention: Q, K, V all from the same tensor X — the attention matrix is always square (n×n). Cross-attention: Q from sequence A, K and V from sequence B — the attention matrix is rectangular (nA×nB) and nA can differ from nB. Confusing these causes shape errors: if you pass a cross-attention decoder query (nq=8) against encoder keys (nk=100) and expect a square matrix, you will get a (8×100) matrix — correct for cross-attention, not for self-attention."},{"type":"heading","level":2,"content":"Encoder Self-Attention — Bidirectional Context"},{"type":"text","content":"Transformer encoders (BERT, RoBERTa, ViT) use bidirectional self-attention throughout. Every token/patch position attends to every other position in the same sequence with no masking. This allows each position to integrate context from both its left and right neighbours in every layer, building representations that are conditioned on the full input sequence. The encoder output H ∈ ℝ^{n×d_model} is a contextualised representation of every input position — it is then passed as the K and V source to the decoder\u0027s cross-attention."},{"type":"heading","level":2,"content":"Decoder Attention Patterns — Causal Self + Cross"},{"type":"text","content":"A standard Transformer decoder (T5, BART, original seq2seq) contains two attention sub-layers per block. First, causal self-attention: the decoder\u0027s own generated tokens attend only to previously generated tokens (positions 0..t-1 for position t), enforcing autoregressive left-to-right generation. Second, cross-attention: the decoder queries attend over the full encoder output to pull in source-sequence information. This cross-attention is the information bridge that replaced the RNN context vector in pre-Transformer seq2seq models."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass EncDecBlock(nn.Module):\n    def __init__(self, d, h, ff):\n        super().__init__()\n        self.enc_sa   = nn.MultiheadAttention(d, h, batch_first=True)\n        self.dec_sa   = nn.MultiheadAttention(d, h, batch_first=True)\n        self.dec_ca   = nn.MultiheadAttention(d, h, batch_first=True)\n        self.enc_ff   = nn.Sequential(nn.Linear(d, ff), nn.ReLU(), nn.Linear(ff, d))\n        self.dec_ff   = nn.Sequential(nn.Linear(d, ff), nn.ReLU(), nn.Linear(ff, d))\n        self.norms    = nn.ModuleList([nn.LayerNorm(d) for _ in range(5)])\n\n    def encode(self, src):\n        a, _ = self.enc_sa(src, src, src)              # bidirectional self-attn\n        x = self.norms[0](src + a)\n        return self.norms[1](x + self.enc_ff(x))\n\n    def decode(self, tgt, enc_out, causal_mask=None):\n        a, _ = self.dec_sa(tgt, tgt, tgt, attn_mask=causal_mask)  # causal\n        x = self.norms[2](tgt + a)\n        a, cross_w = self.dec_ca(x, enc_out, enc_out)              # cross-attn\n        x = self.norms[3](x + a)\n        return self.norms[4](x + self.dec_ff(x)), cross_w\n\ntorch.manual_seed(3)\nd, h, ff = 128, 4, 256\nmodel = EncDecBlock(d, h, ff)\nsrc = torch.randn(2, 15, d)   # batch=2, src_len=15\ntgt = torch.randn(2,  8, d)   # batch=2, tgt_len=8\nenc_out        = model.encode(src)\ndec_out, cross_w = model.decode(tgt, enc_out)\nprint(\u0027Encoder output:\u0027, tuple(enc_out.shape))\nprint(\u0027Decoder output:\u0027, tuple(dec_out.shape))\nprint(\u0027Cross-attention weights:\u0027, tuple(cross_w.shape), \u0027(batch x tgt x src)\u0027)"},{"type":"heading","level":2,"content":"Cross-Attention Alignment Visualisation"},{"type":"text","content":"In seq2seq models, the cross-attention weight matrix is an alignment: entry A[i,j] is how much decoder position i (target token) attends to encoder position j (source token). For translation, this roughly recovers monotonic alignment for similar-language pairs and reordering alignment for distant-language pairs. In image captioning, A[i,j] shows which image patch decoder step i focuses on when generating word i. In text-to-speech, it provides a soft alignment between phoneme output frames and input character positions."},{"type":"code","language":"python","content":"import numpy as np\n\ndef cross_attn(dec_Q, enc_KV, W_Q, W_K, W_V):\n    Q = dec_Q @ W_Q; K = enc_KV @ W_K; V = enc_KV @ W_V\n    S = Q @ K.T / np.sqrt(W_Q.shape[1])\n    S -= S.max(1, keepdims=True)\n    A = np.exp(S); A /= A.sum(1, keepdims=True)\n    return A @ V, A\n\nnp.random.seed(11)\nsrc_tok = [\u0027Le\u0027, \u0027chat\u0027, \u0027est\u0027, \u0027assis\u0027, \u0027sur\u0027, \u0027le\u0027, \u0027tapis\u0027, \u0027.\u0027]\ntgt_tok = [\u0027The\u0027, \u0027cat\u0027, \u0027sat\u0027, \u0027on\u0027, \u0027the\u0027, \u0027mat\u0027, \u0027.\u0027]\nnq, nk, d, dk = len(tgt_tok), len(src_tok), 32, 16\nW_Q = np.random.randn(d, dk) * 0.3\nW_K = np.random.randn(d, dk) * 0.3\nW_V = np.random.randn(d, dk) * 0.3\ndec_states = np.random.randn(nq, d)\nenc_states  = np.random.randn(nk, d)\n_, A = cross_attn(dec_states, enc_states, W_Q, W_K, W_V)\n\ncol_w = max(len(t) for t in src_tok) + 1\nprint(\u0027Cross-attention alignment (rows=target, cols=source):\u0027)\nprint(\u0027{:\u003e8}\u0027.format(\u0027\u0027) + \u0027\u0027.join(\u0027{:\u003e{w}}\u0027.format(t, w=col_w) for t in src_tok))\nprint(\u0027-\u0027 * (8 + col_w * nk))\nfor i, tgt in enumerate(tgt_tok):\n    row = A[i]\n    cells = \u0027\u0027.join(\n        \u0027{:\u003e{w}}\u0027.format(\u0027##\u0027 if j == row.argmax() else \u0027--\u0027 if row[j] \u003e 0.15 else \u0027  \u0027, w=col_w)\n        for j in range(nk))\n    print(\u0027{:\u003e8}{} peak-\u003e{}\u0027.format(tgt, cells, src_tok[row.argmax()]))\nprint(\u0027Alignment shape:\u0027, A.shape, \u0027(nq={} x nk={})\u0027.format(nq, nk))"},{"type":"heading","level":2,"content":"Usage Across Architectures"},{"type":"text","content":"BERT and encoder-only models use bidirectional self-attention exclusively — no cross-attention, no causal mask. GPT and decoder-only models use causal self-attention exclusively — no cross-attention, no encoder. T5 and BART are encoder-decoder models with both: the encoder stack uses bidirectional self-attention and the decoder uses causal self-attention plus cross-attention to the encoder output. Vision Transformers (ViT) use bidirectional self-attention among image patches; cross-attention is added in decoder heads for dense prediction tasks (DETR, Mask2Former)."},{"type":"table","headers":["Property","Self-Attention","Cross-Attention"],"rows":[["Q source","Same sequence X as K and V","Different sequence (e.g., decoder states)"],["K, V source","Same sequence X as Q","Different sequence (e.g., encoder output)"],["Attention matrix shape","n × n (square)","nq × nk (rectangular, nq ≠ nk in general)"],["Directionality","Bidirectional or causal (masked)","Unrestricted — all nk encoder positions visible"],["Used in","BERT (bidir), GPT (causal), ViT (bidir)","T5, BART, classic seq2seq, DETR, ControlNet"],["Computational role","Build contextual representations within one sequence","Bridge information across two different sequences"],["Can attend to its own future?","Yes (bidir) or no (causal mask)","N/A — K/V come from a separate fully-observed sequence"]]},{"type":"heading","level":2,"content":"Cross-Attention Beyond NLP"},{"type":"text","content":"Cross-attention has become a general mechanism for conditioning one modality on another. In diffusion models (Stable Diffusion), the denoising U-Net uses cross-attention at each resolution to condition image features on text embeddings — the image features provide queries, the CLIP text encoder output provides keys and values. ControlNet adds a copy of the U-Net encoder with additional cross-attention inputs from spatial conditioning signals (depth maps, pose, edges). In multimodal LLMs (Flamingo, LLaVA), cross-attention allows the language model to attend to visual patch embeddings from a frozen vision encoder."},{"type":"list","ordered":false,"items":["Diffusion U-Net: image patch queries attend over CLIP text embedding keys/values for text-to-image generation","ControlNet: spatial control signals (edge, depth, pose) provide additional cross-attention conditioning to U-Net","Flamingo / LLaVA: language decoder cross-attends to visual patch embeddings from a ViT vision encoder","DETR object detection: object query embeddings cross-attend to CNN feature maps for end-to-end detection","AlphaFold2 (Evoformer): sequence-structure cross-attention; cross-attention between MSA rows and pair representations","Perceiver IO: latent array cross-attends to arbitrary-modality input arrays, enabling modality-agnostic processing"]},{"type":"divider"}]"
---
# Self-Attention vs Cross-Attention — Encoder and Decoder Patterns

Attention mechanisms differ fundamentally in where their Q, K, and V inputs come from. Self-attention takes all three from the same sequence, allowing each position to attend to every other position in that same sequence. Cross-attention takes Q from one sequence and K, V from a different sequence, bridging information between two separate representations. These two variants are not interchangeable — each is used in specific architectural positions with specific computational purposes.

## Self-Attention — Definition and Properties

In self-attention Q = X·WQ, K = X·WK, V = X·WV where X is the same input sequence. Every position produces a query that is scored against keys from all other positions in X — the attention matrix A ∈ ℝ^{n×n} is square. Bidirectional self-attention allows each position to attend to all others (including future positions), making the representations context-aware in both directions. Causal (masked) self-attention applies an upper-triangular mask of −∞ to the score matrix before softmax, preventing position i from attending to positions j > i. This preserves the autoregressive property required for text generation.

```python
import numpy as np

def self_attention(X, W_Q, W_K, W_V, causal=False):
    # X: (n, d_model); Q=K=V all derived from same X
    Q = X @ W_Q    # (n, dk)
    K = X @ W_K    # (n, dk)
    V = X @ W_V    # (n, dv)
    dk = Q.shape[-1]
    S = Q @ K.T / np.sqrt(dk)    # (n, n) — square matrix
    if causal:
        # Upper triangle -> -inf so softmax gives 0 weight
        mask = np.triu(np.ones_like(S), k=1) * -1e9
        S = S + mask
    S -= S.max(axis=-1, keepdims=True)
    A = np.exp(S); A /= A.sum(axis=-1, keepdims=True)
    return A @ V, A

np.random.seed(42)
n, d_model, dk, dv = 6, 64, 32, 32
X = np.random.randn(n, d_model)
W_Q = np.random.randn(d_model, dk) * 0.1
W_K = np.random.randn(d_model, dk) * 0.1
W_V = np.random.randn(d_model, dv) * 0.1

_, A_bi  = self_attention(X, W_Q, W_K, W_V, causal=False)
_, A_cau = self_attention(X, W_Q, W_K, W_V, causal=True)
print('Bidirectional SA shape:', A_bi.shape, '(n x n, square)')
print('Upper triangle zero in causal SA:', np.allclose(np.triu(A_cau, 1), 0))
print('Causal: position 0 attends only to itself:', A_cau[0].round(4))
print('Causal: position 5 attends to all 6:', (A_cau[5] > 1e-6).sum(), 'positions')
```

## Cross-Attention — Definition and Properties

In cross-attention the query Q comes from one sequence (e.g., decoder states) while keys K and values V come from a second sequence (e.g., encoder output). Queries and keys must share the same inner dimension dₖ but the two sequences can have different lengths: nq ≠ nk. The attention matrix A ∈ ℝ^{nq×nk} is rectangular — each of the nq query positions attends over all nk key-value positions. No causal masking is needed (and none is applied) because the query sequence is attending to a fully-observed context sequence, not to its own future.

```python
import numpy as np

def cross_attention(Q_seq, KV_seq, W_Q, W_K, W_V):
    # Q_seq: (nq, d_q) — decoder states; KV_seq: (nk, d_kv) — encoder output
    Q = Q_seq  @ W_Q    # (nq, dk)
    K = KV_seq @ W_K    # (nk, dk)
    V = KV_seq @ W_V    # (nk, dv)
    dk = Q.shape[-1]
    S = Q @ K.T / np.sqrt(dk)    # (nq, nk) — RECTANGULAR, nq != nk
    S -= S.max(axis=-1, keepdims=True)
    A = np.exp(S); A /= A.sum(axis=-1, keepdims=True)
    return A @ V, A              # output: (nq, dv), weights: (nq, nk)

np.random.seed(7)
nq, nk, d_model, dk, dv = 4, 10, 64, 32, 32
dec_states = np.random.randn(nq, d_model)   # short target sequence
enc_states  = np.random.randn(nk, d_model)  # longer source sequence
W_Q = np.random.randn(d_model, dk) * 0.1
W_K = np.random.randn(d_model, dk) * 0.1
W_V = np.random.randn(d_model, dv) * 0.1

out, A = cross_attention(dec_states, enc_states, W_Q, W_K, W_V)
print('Dec states:', dec_states.shape, '  Enc states:', enc_states.shape)
print('Attention matrix:', A.shape, '<- rectangular (nq x nk)')
print('Output:', out.shape)
print('Row sums (should be 1):', A.sum(axis=1).round(5))
```

> **Key Difference — Where Q, K, V Come From**: Self-attention: Q, K, V all from the same tensor X — the attention matrix is always square (n×n). Cross-attention: Q from sequence A, K and V from sequence B — the attention matrix is rectangular (nA×nB) and nA can differ from nB. Confusing these causes shape errors: if you pass a cross-attention decoder query (nq=8) against encoder keys (nk=100) and expect a square matrix, you will get a (8×100) matrix — correct for cross-attention, not for self-attention.

## Encoder Self-Attention — Bidirectional Context

Transformer encoders (BERT, RoBERTa, ViT) use bidirectional self-attention throughout. Every token/patch position attends to every other position in the same sequence with no masking. This allows each position to integrate context from both its left and right neighbours in every layer, building representations that are conditioned on the full input sequence. The encoder output H ∈ ℝ^{n×d_model} is a contextualised representation of every input position — it is then passed as the K and V source to the decoder's cross-attention.

## Decoder Attention Patterns — Causal Self + Cross

A standard Transformer decoder (T5, BART, original seq2seq) contains two attention sub-layers per block. First, causal self-attention: the decoder's own generated tokens attend only to previously generated tokens (positions 0..t-1 for position t), enforcing autoregressive left-to-right generation. Second, cross-attention: the decoder queries attend over the full encoder output to pull in source-sequence information. This cross-attention is the information bridge that replaced the RNN context vector in pre-Transformer seq2seq models.

```python
import torch
import torch.nn as nn

class EncDecBlock(nn.Module):
    def __init__(self, d, h, ff):
        super().__init__()
        self.enc_sa   = nn.MultiheadAttention(d, h, batch_first=True)
        self.dec_sa   = nn.MultiheadAttention(d, h, batch_first=True)
        self.dec_ca   = nn.MultiheadAttention(d, h, batch_first=True)
        self.enc_ff   = nn.Sequential(nn.Linear(d, ff), nn.ReLU(), nn.Linear(ff, d))
        self.dec_ff   = nn.Sequential(nn.Linear(d, ff), nn.ReLU(), nn.Linear(ff, d))
        self.norms    = nn.ModuleList([nn.LayerNorm(d) for _ in range(5)])

    def encode(self, src):
        a, _ = self.enc_sa(src, src, src)              # bidirectional self-attn
        x = self.norms[0](src + a)
        return self.norms[1](x + self.enc_ff(x))

    def decode(self, tgt, enc_out, causal_mask=None):
        a, _ = self.dec_sa(tgt, tgt, tgt, attn_mask=causal_mask)  # causal
        x = self.norms[2](tgt + a)
        a, cross_w = self.dec_ca(x, enc_out, enc_out)              # cross-attn
        x = self.norms[3](x + a)
        return self.norms[4](x + self.dec_ff(x)), cross_w

torch.manual_seed(3)
d, h, ff = 128, 4, 256
model = EncDecBlock(d, h, ff)
src = torch.randn(2, 15, d)   # batch=2, src_len=15
tgt = torch.randn(2,  8, d)   # batch=2, tgt_len=8
enc_out        = model.encode(src)
dec_out, cross_w = model.decode(tgt, enc_out)
print('Encoder output:', tuple(enc_out.shape))
print('Decoder output:', tuple(dec_out.shape))
print('Cross-attention weights:', tuple(cross_w.shape), '(batch x tgt x src)')
```

## Cross-Attention Alignment Visualisation

In seq2seq models, the cross-attention weight matrix is an alignment: entry A[i,j] is how much decoder position i (target token) attends to encoder position j (source token). For translation, this roughly recovers monotonic alignment for similar-language pairs and reordering alignment for distant-language pairs. In image captioning, A[i,j] shows which image patch decoder step i focuses on when generating word i. In text-to-speech, it provides a soft alignment between phoneme output frames and input character positions.

```python
import numpy as np

def cross_attn(dec_Q, enc_KV, W_Q, W_K, W_V):
    Q = dec_Q @ W_Q; K = enc_KV @ W_K; V = enc_KV @ W_V
    S = Q @ K.T / np.sqrt(W_Q.shape[1])
    S -= S.max(1, keepdims=True)
    A = np.exp(S); A /= A.sum(1, keepdims=True)
    return A @ V, A

np.random.seed(11)
src_tok = ['Le', 'chat', 'est', 'assis', 'sur', 'le', 'tapis', '.']
tgt_tok = ['The', 'cat', 'sat', 'on', 'the', 'mat', '.']
nq, nk, d, dk = len(tgt_tok), len(src_tok), 32, 16
W_Q = np.random.randn(d, dk) * 0.3
W_K = np.random.randn(d, dk) * 0.3
W_V = np.random.randn(d, dk) * 0.3
dec_states = np.random.randn(nq, d)
enc_states  = np.random.randn(nk, d)
_, A = cross_attn(dec_states, enc_states, W_Q, W_K, W_V)

col_w = max(len(t) for t in src_tok) + 1
print('Cross-attention alignment (rows=target, cols=source):')
print('{:>8}'.format('') + ''.join('{:>{w}}'.format(t, w=col_w) for t in src_tok))
print('-' * (8 + col_w * nk))
for i, tgt in enumerate(tgt_tok):
    row = A[i]
    cells = ''.join(
        '{:>{w}}'.format('##' if j == row.argmax() else '--' if row[j] > 0.15 else '  ', w=col_w)
        for j in range(nk))
    print('{:>8}{} peak->{}'.format(tgt, cells, src_tok[row.argmax()]))
print('Alignment shape:', A.shape, '(nq={} x nk={})'.format(nq, nk))
```

## Usage Across Architectures

BERT and encoder-only models use bidirectional self-attention exclusively — no cross-attention, no causal mask. GPT and decoder-only models use causal self-attention exclusively — no cross-attention, no encoder. T5 and BART are encoder-decoder models with both: the encoder stack uses bidirectional self-attention and the decoder uses causal self-attention plus cross-attention to the encoder output. Vision Transformers (ViT) use bidirectional self-attention among image patches; cross-attention is added in decoder heads for dense prediction tasks (DETR, Mask2Former).

| Property | Self-Attention | Cross-Attention |
| --- | --- | --- |
| Q source | Same sequence X as K and V | Different sequence (e.g., decoder states) |
| K, V source | Same sequence X as Q | Different sequence (e.g., encoder output) |
| Attention matrix shape | n × n (square) | nq × nk (rectangular, nq ≠ nk in general) |
| Directionality | Bidirectional or causal (masked) | Unrestricted — all nk encoder positions visible |
| Used in | BERT (bidir), GPT (causal), ViT (bidir) | T5, BART, classic seq2seq, DETR, ControlNet |
| Computational role | Build contextual representations within one sequence | Bridge information across two different sequences |
| Can attend to its own future? | Yes (bidir) or no (causal mask) | N/A — K/V come from a separate fully-observed sequence |

## Cross-Attention Beyond NLP

Cross-attention has become a general mechanism for conditioning one modality on another. In diffusion models (Stable Diffusion), the denoising U-Net uses cross-attention at each resolution to condition image features on text embeddings — the image features provide queries, the CLIP text encoder output provides keys and values. ControlNet adds a copy of the U-Net encoder with additional cross-attention inputs from spatial conditioning signals (depth maps, pose, edges). In multimodal LLMs (Flamingo, LLaVA), cross-attention allows the language model to attend to visual patch embeddings from a frozen vision encoder.

- Diffusion U-Net: image patch queries attend over CLIP text embedding keys/values for text-to-image generation
- ControlNet: spatial control signals (edge, depth, pose) provide additional cross-attention conditioning to U-Net
- Flamingo / LLaVA: language decoder cross-attends to visual patch embeddings from a ViT vision encoder
- DETR object detection: object query embeddings cross-attend to CNN feature maps for end-to-end detection
- AlphaFold2 (Evoformer): sequence-structure cross-attention; cross-attention between MSA rows and pair representations
- Perceiver IO: latent array cross-attends to arbitrary-modality input arrays, enabling modality-agnostic processing

---

