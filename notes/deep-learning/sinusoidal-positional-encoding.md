---
title: "Sinusoidal Positional Encoding — Vaswani et al. Design"
slug: "sinusoidal-positional-encoding"
description: "Derive Vaswani et al.'s sinusoidal PE formula, prove the linear-shift property, analyse the multi-frequency design, and compare sinusoidal encoding with learned, RoPE, ALiBi, and NoPE variants."
tags: ["deep-learning", "transformers", "attention"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"A vanilla Transformer is permutation equivariant: swapping two tokens in the input produces the same output with those two tokens swapped. This is because dot-product attention treats positions symmetrically — there is no notion of \u0027position 3 comes before position 7\u0027. Positional encoding injects position information by adding a position-dependent vector to the token embedding before it enters the Transformer stack. Vaswani et al. chose a deterministic sinusoidal encoding with specific mathematical properties that motivated the design of all subsequent positional encoding schemes."},{"type":"heading","level":2,"content":"The Permutation Equivariance Problem"},{"type":"text","content":"Formally, let f be a Transformer layer. It is permutation equivariant if f(Px) = Pf(x) for any permutation matrix P. This holds because attention weights Aᵢⱼ = softmax(qᵢ·kⱼ/√dₖ) depend only on the content of positions i and j, not on their indices. Consequently, the Transformer cannot distinguish \u0027the cat ate the fish\u0027 from \u0027the fish ate the cat\u0027 without positional information. Positional encoding breaks this symmetry by making token embeddings position-dependent before they are fed to the first layer."},{"type":"heading","level":2,"content":"Sinusoidal PE Formula"},{"type":"text","content":"Vaswani et al. 2017 defined the positional encoding PE ∈ ℝ^{max_len×d_model} by pairs of sine and cosine functions at geometrically spaced frequencies. For position pos ∈ {0,...,max_len−1} and dimension index i ∈ {0,...,d_model/2−1}: PE(pos, 2i) = sin(pos / 10000^{2i/d_model}) and PE(pos, 2i+1) = cos(pos / 10000^{2i/d_model}). The divisor 10000^{2i/d_model} creates a geometric progression of wavelengths from 2π (at i=0, highest frequency) to 10000·2π (at i=d_model/2−1, lowest frequency). The PE is added (not concatenated) to the token embedding: x = embed(token) + PE[pos]."},{"type":"math","content":"PE(pos, 2i) = \\sin\\!\\left(\\frac{pos}{10000^{2i/d_{\\text{model}}}}\\right), \\qquad PE(pos, 2i+1) = \\cos\\!\\left(\\frac{pos}{10000^{2i/d_{\\text{model}}}}\\right)","display":true},{"type":"code","language":"python","content":"import numpy as np\n\ndef sinusoidal_pe(max_len, d_model):\n    # Returns PE matrix: (max_len, d_model)\n    PE = np.zeros((max_len, d_model))\n    pos = np.arange(max_len)[:, np.newaxis]          # (max_len, 1)\n    i   = np.arange(0, d_model, 2)[np.newaxis, :]   # (1, d_model/2)\n    div = np.power(10000.0, i / d_model)\n    PE[:, 0::2] = np.sin(pos / div)    # even dims: sin\n    PE[:, 1::2] = np.cos(pos / div)    # odd  dims: cos\n    return PE\n\npe = sinusoidal_pe(50, 128)\nprint(\u0027PE shape:\u0027, pe.shape)\nprint(\u0027PE values bounded in [-1, 1]:\u0027, pe.min().round(3), \u0027to\u0027, pe.max().round(3))\nprint(\u0027PE[pos=0, :4]:\u0027, pe[0, :4].round(4))\nprint(\u0027PE[pos=1, :4]:\u0027, pe[1, :4].round(4))\nprint(\u0027PE[pos=10,:4]:\u0027, pe[10, :4].round(4))\n\n# Text heatmap of PE values across positions x selected dimensions\nprint(\u0027\\nHeatmap (+ pos, . near-zero, - neg) rows=pos, cols=dim:\u0027)\nsel_dims = [0, 8, 16, 32, 64, 96, 126]\nprint(\u0027pos\u0027 + \u0027\u0027.join(\u0027 d{:\u003e3}\u0027.format(d) for d in sel_dims))\nfor pos in [0, 5, 10, 20, 30, 40, 49]:\n    row = \u0027  {:\u003e2}:\u0027.format(pos)\n    for d in sel_dims:\n        v = pe[pos, d]\n        row += \u0027  +++\u0027 if v \u003e 0.5 else \u0027  +  \u0027 if v \u003e 0.1 else \u0027  .  \u0027 if abs(v) \u003c 0.1 else \u0027  -  \u0027 if v \u003e -0.5 else \u0027  ---\u0027\n    print(row)"},{"type":"heading","level":2,"content":"Four Key Properties"},{"type":"text","content":"The sinusoidal PE design satisfies four properties that guided the choice over simpler alternatives like integer encoding or learned embeddings. Each position gets a unique vector. The encoding generalises deterministically to positions beyond the training sequence length. Relative distances are recoverable from the encodings via linear combination (proven below). And the encoding values are bounded in [−1, 1], preventing them from dominating the token embedding signal regardless of sequence length."},{"type":"list","ordered":true,"items":["Uniqueness: every position pos has a unique PE vector — proven because the set of frequencies is incommensurate (no two frequencies are rational multiples of each other for typical d_model and max_len values)","Generalisation: the formula is defined for any pos ≥ 0; positions beyond max_len during training get encodings that are smooth continuations of the trained range","Linear-shift property: PE(pos+k) can be expressed as a fixed linear (rotation) function of PE(pos) for any offset k — this allows the model to reason about relative positions via learned linear operations","Bounded magnitude: all PE values lie in [−1, 1], so the added positional signal has the same scale regardless of pos — no position receives a disproportionately large encoding"]},{"type":"callout","variant":"tip","title":"Why Addition, Not Concatenation?","content":"Concatenating the PE to the embedding would double the input dimension to 2·d_model, doubling the cost of every projection matrix. Adding instead keeps dimension d_model while allowing the network to learn to separate the semantic content (primarily encoded in token embedding directions) and positional information (encoded in PE directions) using the projection matrices. In practice the network learns to use different dimensions of d_model for content vs position, achieving the same expressiveness as concatenation without the extra parameters."},{"type":"heading","level":2,"content":"Linear-Shift Property — Proof"},{"type":"text","content":"For dimension pair (2i, 2i+1) with frequency fᵢ = 1/10000^{2i/d_model}, the encodings are sin(pos·fᵢ) and cos(pos·fᵢ). For a fixed offset k: sin((pos+k)·fᵢ) = sin(pos·fᵢ)cos(k·fᵢ) + cos(pos·fᵢ)sin(k·fᵢ) and cos((pos+k)·fᵢ) = cos(pos·fᵢ)cos(k·fᵢ) − sin(pos·fᵢ)sin(k·fᵢ). This is a 2×2 rotation matrix applied to [sin(pos·fᵢ), cos(pos·fᵢ)]ᵀ with rotation angle k·fᵢ. Stacking over all d_model/2 frequency pairs, PE(pos+k) = M_k · PE(pos) where M_k is a block-diagonal rotation matrix that depends only on k, not on pos. This means PE(pos+k) is an exact linear function of PE(pos) for any fixed offset k."},{"type":"code","language":"python","content":"import numpy as np\n\ndef sinusoidal_pe(max_len, d_model):\n    PE = np.zeros((max_len, d_model))\n    pos = np.arange(max_len)[:, np.newaxis]\n    i   = np.arange(0, d_model, 2)[np.newaxis, :]\n    div = np.power(10000.0, i / d_model)\n    PE[:, 0::2] = np.sin(pos / div)\n    PE[:, 1::2] = np.cos(pos / div)\n    return PE\n\ndef linear_shift_matrix(k, d_model):\n    # Block-diagonal rotation matrix M_k such that PE(pos+k) = M_k @ PE(pos)\n    M = np.zeros((d_model, d_model))\n    for idx in range(0, d_model, 2):\n        freq = 10000 ** (idx / d_model)\n        c, s = np.cos(k / freq), np.sin(k / freq)\n        M[idx,   idx]   =  c;  M[idx,   idx+1] = s\n        M[idx+1, idx]   = -s;  M[idx+1, idx+1] = c\n    return M\n\npe = sinusoidal_pe(200, 64)\nprint(\u0027Verifying: PE(pos+k) = M_k @ PE(pos)\u0027)\nfor pos, k in [(5, 3), (20, 7), (50, 13), (100, 25)]:\n    M_k       = linear_shift_matrix(k, 64)\n    predicted = M_k @ pe[pos]\n    actual    = pe[pos + k]\n    err = np.abs(predicted - actual).max()\n    status = \u0027PASS\u0027 if err \u003c 1e-10 else \u0027FAIL\u0027\n    print(\u0027  PE({:\u003e3}+{:\u003e2}) = M_{} @ PE({:\u003e3}): max_err={:.2e}  {}\u0027.format(\n        pos, k, k, pos, err, status))\nprint(\u0027PE(pos+k) is an exact linear function of PE(pos) for any k.\u0027)\nprint(\u0027The model can learn to decode relative offsets via linear attention ops.\u0027)"},{"type":"heading","level":2,"content":"Frequency Analysis — Low vs High Dimensions"},{"type":"text","content":"The lowest-indexed dimensions (i=0,1) use the highest frequency fᵢ=1 (wavelength 2π ≈ 6.3 tokens): these dimensions oscillate rapidly, changing substantially between adjacent positions. The highest-indexed dimensions (i≈d_model/2) use the lowest frequency fᵢ ≈ 1/10000 (wavelength ≈ 62,800 tokens): these dimensions change very slowly, encoding coarse position at the sequence level. The combined multi-scale representation resembles a binary counter generalised to sinusoidal bases: low dimensions encode fine-grained position, high dimensions encode coarse position."},{"type":"heading","level":2,"content":"Generalisation to Longer Sequences"},{"type":"text","content":"Because the PE formula is deterministic and not learned, it produces well-defined values for any position pos regardless of the maximum length seen during training. The encoding at positions beyond max_len_train are smooth continuations of the same sinusoidal curves. In practice, models trained with sinusoidal PE can often process sequences up to 2× the training length without significant degradation, though accuracy does decline because the attention layers have not seen such positions during training. Learned positional embeddings, by contrast, are undefined beyond the training vocabulary and require interpolation or extrapolation heuristics."},{"type":"code","language":"python","content":"import numpy as np\n\ndef sinusoidal_pe(max_len, d_model):\n    PE = np.zeros((max_len, d_model))\n    pos = np.arange(max_len)[:, np.newaxis]\n    i   = np.arange(0, d_model, 2)[np.newaxis, :]\n    PE[:, 0::2] = np.sin(pos / np.power(10000.0, i / d_model))\n    PE[:, 1::2] = np.cos(pos / np.power(10000.0, i / d_model))\n    return PE\n\ntrain_len, d_model = 128, 64\npe_train = sinusoidal_pe(train_len, d_model)\npe_long  = sinusoidal_pe(train_len * 2, d_model)    # 2x longer at test time\n\nassert np.allclose(pe_train, pe_long[:train_len]), \u0027PE within train range must match!\u0027\nprint(\u0027PE[0:{:d}] identical in train and long context: PASS\u0027.format(train_len))\n\ndelta_train = np.diff(pe_train, axis=0)\ndelta_extra = np.diff(pe_long[train_len:], axis=0)\nprint(\u0027Mean |delta| in train region: {:.4f}\u0027.format(np.abs(delta_train).mean()))\nprint(\u0027Mean |delta| in extra region: {:.4f}\u0027.format(np.abs(delta_extra).mean()))\nprint(\u0027Similar -\u003e smooth continuation beyond train length.\u0027)\n\npe_test = pe_long\nnorms = np.linalg.norm(pe_test, axis=1, keepdims=True) + 1e-9\ncos_sim = (pe_test / norms) @ (pe_test / norms).T\nnp.fill_diagonal(cos_sim, 0)\nprint(\u0027Max off-diagonal cos similarity (all positions): {:.4f}\u0027.format(cos_sim.max()))\nprint(\u0027Low -\u003e unique encoding even beyond training length.\u0027)"},{"type":"heading","level":2,"content":"With vs Without Positional Encoding"},{"type":"text","content":"Without positional encoding, the Transformer treats its input as a set rather than a sequence. For any task where the output depends on token order (translation, language modelling, sequence classification based on word order), removing PE causes significant degradation. The degradation is total for tasks where two different orderings map to completely different semantics (e.g., \u0027man bites dog\u0027 vs \u0027dog bites man\u0027). For bag-of-words tasks (sentiment classification of short text) the effect is mild."},{"type":"code","language":"python","content":"import numpy as np\n\ndef softmax(S):\n    S = S - S.max(axis=-1, keepdims=True)\n    e = np.exp(S); return e / e.sum(axis=-1, keepdims=True)\n\ndef sdp_attn(Q, K, V):\n    A = softmax(Q @ K.T / np.sqrt(Q.shape[-1]))\n    return A @ V\n\ndef sinusoidal_pe(n, d):\n    PE = np.zeros((n, d))\n    pos = np.arange(n)[:, np.newaxis]\n    i   = np.arange(0, d, 2)[np.newaxis, :]\n    PE[:, 0::2] = np.sin(pos / np.power(10000.0, i / d))\n    PE[:, 1::2] = np.cos(pos / np.power(10000.0, i / d))\n    return PE\n\nnp.random.seed(0)\nn, d = 8, 32\nW = np.random.randn(d, d) * 0.1\nX = np.random.randn(n, d)\nX_pe = X + sinusoidal_pe(n, d)\n\n# Test: is the output permutation equivariant without PE?\nperm = np.random.permutation(n)\nout_no_pe        = sdp_attn(X @ W, X @ W, X)\nout_perm_no_pe   = sdp_attn((X[perm] @ W), (X[perm] @ W), X[perm])\nno_pe_equiv = np.allclose(out_no_pe[perm], out_perm_no_pe, atol=1e-10)\nprint(\u0027No PE  — permutation equivariant (output reorders with input):\u0027, no_pe_equiv)\n\nout_pe           = sdp_attn(X_pe @ W, X_pe @ W, X_pe)\nX_pe_perm = X[perm] + sinusoidal_pe(n, d)\nout_perm_pe      = sdp_attn(X_pe_perm @ W, X_pe_perm @ W, X_pe_perm)\npe_equiv = np.allclose(out_pe[perm], out_perm_pe, atol=1e-5)\nprint(\u0027With PE — permutation equivariant:\u0027, pe_equiv)\nprint(\u0027PE breaks permutation symmetry: model distinguishes token order.\u0027)"},{"type":"heading","level":2,"content":"Comparison of Positional Encodings"},{"type":"text","content":"Sinusoidal PE was the standard until learned positional embeddings (BERT, GPT-2) showed that data-driven positions improve downstream task performance at the cost of extrapolation ability. RoPE and ALiBi later restored length generalisation with different mechanisms: RoPE rotates Q and K directly in the complex plane (introducing relative position into the attention score), while ALiBi subtracts a linear position bias from attention scores without modifying Q or K. Current best practice for models that need to extend to long contexts is RoPE with frequency interpolation (YaRN, LongRoPE)."},{"type":"table","headers":["Encoding","Extrapolates Beyond Train Len","Relative Position Info","Learnable Params","Used In"],"rows":[["Sinusoidal (Vaswani 2017)","Yes — formula extrapolates smoothly","Implicit via linear-shift property","None","Original Transformer, some encoder-decoder models"],["Learned absolute","No — undefined beyond vocab size","None explicit","max_len × d_model","BERT, GPT-2, ViT"],["RoPE (Su et al. 2021)","Yes with frequency scaling","Yes — explicit rotation by relative angle","None","LLaMA, Mistral, Falcon, Gemma, PaLM 2"],["ALiBi (Press et al. 2022)","Yes — linear bias extrapolates","Yes — linear distance penalty per head","h learnable slopes (or fixed)","BLOOM, MPT, some OPT variants"],["NoPE (no PE)","Yes (no position at all)","None — bag-of-words","None","Some encoder-only models; relative PE in T5"]]},{"type":"text","content":"For new architectures intended to handle variable or long context, RoPE with rope_theta tuning (increasing 10000 to 500,000 for context extension) is the current default. ALiBi offers simpler implementation and strong length generalisation but lacks the relative-position expressiveness of RoPE. Sinusoidal PE remains valuable for understanding — its linear-shift property is the conceptual ancestor of RoPE\u0027s rotation mechanism."},{"type":"divider"}]"
---
# Sinusoidal Positional Encoding — Vaswani et al. Design

A vanilla Transformer is permutation equivariant: swapping two tokens in the input produces the same output with those two tokens swapped. This is because dot-product attention treats positions symmetrically — there is no notion of 'position 3 comes before position 7'. Positional encoding injects position information by adding a position-dependent vector to the token embedding before it enters the Transformer stack. Vaswani et al. chose a deterministic sinusoidal encoding with specific mathematical properties that motivated the design of all subsequent positional encoding schemes.

## The Permutation Equivariance Problem

Formally, let f be a Transformer layer. It is permutation equivariant if f(Px) = Pf(x) for any permutation matrix P. This holds because attention weights Aᵢⱼ = softmax(qᵢ·kⱼ/√dₖ) depend only on the content of positions i and j, not on their indices. Consequently, the Transformer cannot distinguish 'the cat ate the fish' from 'the fish ate the cat' without positional information. Positional encoding breaks this symmetry by making token embeddings position-dependent before they are fed to the first layer.

## Sinusoidal PE Formula

Vaswani et al. 2017 defined the positional encoding PE ∈ ℝ^{max_len×d_model} by pairs of sine and cosine functions at geometrically spaced frequencies. For position pos ∈ {0,...,max_len−1} and dimension index i ∈ {0,...,d_model/2−1}: PE(pos, 2i) = sin(pos / 10000^{2i/d_model}) and PE(pos, 2i+1) = cos(pos / 10000^{2i/d_model}). The divisor 10000^{2i/d_model} creates a geometric progression of wavelengths from 2π (at i=0, highest frequency) to 10000·2π (at i=d_model/2−1, lowest frequency). The PE is added (not concatenated) to the token embedding: x = embed(token) + PE[pos].

$$PE(pos, 2i) = \sin\!\left(\frac{pos}{10000^{2i/d_{\text{model}}}}\right), \qquad PE(pos, 2i+1) = \cos\!\left(\frac{pos}{10000^{2i/d_{\text{model}}}}\right)$$

```python
import numpy as np

def sinusoidal_pe(max_len, d_model):
    # Returns PE matrix: (max_len, d_model)
    PE = np.zeros((max_len, d_model))
    pos = np.arange(max_len)[:, np.newaxis]          # (max_len, 1)
    i   = np.arange(0, d_model, 2)[np.newaxis, :]   # (1, d_model/2)
    div = np.power(10000.0, i / d_model)
    PE[:, 0::2] = np.sin(pos / div)    # even dims: sin
    PE[:, 1::2] = np.cos(pos / div)    # odd  dims: cos
    return PE

pe = sinusoidal_pe(50, 128)
print('PE shape:', pe.shape)
print('PE values bounded in [-1, 1]:', pe.min().round(3), 'to', pe.max().round(3))
print('PE[pos=0, :4]:', pe[0, :4].round(4))
print('PE[pos=1, :4]:', pe[1, :4].round(4))
print('PE[pos=10,:4]:', pe[10, :4].round(4))

# Text heatmap of PE values across positions x selected dimensions
print('\nHeatmap (+ pos, . near-zero, - neg) rows=pos, cols=dim:')
sel_dims = [0, 8, 16, 32, 64, 96, 126]
print('pos' + ''.join(' d{:>3}'.format(d) for d in sel_dims))
for pos in [0, 5, 10, 20, 30, 40, 49]:
    row = '  {:>2}:'.format(pos)
    for d in sel_dims:
        v = pe[pos, d]
        row += '  +++' if v > 0.5 else '  +  ' if v > 0.1 else '  .  ' if abs(v) < 0.1 else '  -  ' if v > -0.5 else '  ---'
    print(row)
```

## Four Key Properties

The sinusoidal PE design satisfies four properties that guided the choice over simpler alternatives like integer encoding or learned embeddings. Each position gets a unique vector. The encoding generalises deterministically to positions beyond the training sequence length. Relative distances are recoverable from the encodings via linear combination (proven below). And the encoding values are bounded in [−1, 1], preventing them from dominating the token embedding signal regardless of sequence length.

1. Uniqueness: every position pos has a unique PE vector — proven because the set of frequencies is incommensurate (no two frequencies are rational multiples of each other for typical d_model and max_len values)
2. Generalisation: the formula is defined for any pos ≥ 0; positions beyond max_len during training get encodings that are smooth continuations of the trained range
3. Linear-shift property: PE(pos+k) can be expressed as a fixed linear (rotation) function of PE(pos) for any offset k — this allows the model to reason about relative positions via learned linear operations
4. Bounded magnitude: all PE values lie in [−1, 1], so the added positional signal has the same scale regardless of pos — no position receives a disproportionately large encoding

> **Why Addition, Not Concatenation?**: Concatenating the PE to the embedding would double the input dimension to 2·d_model, doubling the cost of every projection matrix. Adding instead keeps dimension d_model while allowing the network to learn to separate the semantic content (primarily encoded in token embedding directions) and positional information (encoded in PE directions) using the projection matrices. In practice the network learns to use different dimensions of d_model for content vs position, achieving the same expressiveness as concatenation without the extra parameters.

## Linear-Shift Property — Proof

For dimension pair (2i, 2i+1) with frequency fᵢ = 1/10000^{2i/d_model}, the encodings are sin(pos·fᵢ) and cos(pos·fᵢ). For a fixed offset k: sin((pos+k)·fᵢ) = sin(pos·fᵢ)cos(k·fᵢ) + cos(pos·fᵢ)sin(k·fᵢ) and cos((pos+k)·fᵢ) = cos(pos·fᵢ)cos(k·fᵢ) − sin(pos·fᵢ)sin(k·fᵢ). This is a 2×2 rotation matrix applied to [sin(pos·fᵢ), cos(pos·fᵢ)]ᵀ with rotation angle k·fᵢ. Stacking over all d_model/2 frequency pairs, PE(pos+k) = M_k · PE(pos) where M_k is a block-diagonal rotation matrix that depends only on k, not on pos. This means PE(pos+k) is an exact linear function of PE(pos) for any fixed offset k.

```python
import numpy as np

def sinusoidal_pe(max_len, d_model):
    PE = np.zeros((max_len, d_model))
    pos = np.arange(max_len)[:, np.newaxis]
    i   = np.arange(0, d_model, 2)[np.newaxis, :]
    div = np.power(10000.0, i / d_model)
    PE[:, 0::2] = np.sin(pos / div)
    PE[:, 1::2] = np.cos(pos / div)
    return PE

def linear_shift_matrix(k, d_model):
    # Block-diagonal rotation matrix M_k such that PE(pos+k) = M_k @ PE(pos)
    M = np.zeros((d_model, d_model))
    for idx in range(0, d_model, 2):
        freq = 10000 ** (idx / d_model)
        c, s = np.cos(k / freq), np.sin(k / freq)
        M[idx,   idx]   =  c;  M[idx,   idx+1] = s
        M[idx+1, idx]   = -s;  M[idx+1, idx+1] = c
    return M

pe = sinusoidal_pe(200, 64)
print('Verifying: PE(pos+k) = M_k @ PE(pos)')
for pos, k in [(5, 3), (20, 7), (50, 13), (100, 25)]:
    M_k       = linear_shift_matrix(k, 64)
    predicted = M_k @ pe[pos]
    actual    = pe[pos + k]
    err = np.abs(predicted - actual).max()
    status = 'PASS' if err < 1e-10 else 'FAIL'
    print('  PE({:>3}+{:>2}) = M_{} @ PE({:>3}): max_err={:.2e}  {}'.format(
        pos, k, k, pos, err, status))
print('PE(pos+k) is an exact linear function of PE(pos) for any k.')
print('The model can learn to decode relative offsets via linear attention ops.')
```

## Frequency Analysis — Low vs High Dimensions

The lowest-indexed dimensions (i=0,1) use the highest frequency fᵢ=1 (wavelength 2π ≈ 6.3 tokens): these dimensions oscillate rapidly, changing substantially between adjacent positions. The highest-indexed dimensions (i≈d_model/2) use the lowest frequency fᵢ ≈ 1/10000 (wavelength ≈ 62,800 tokens): these dimensions change very slowly, encoding coarse position at the sequence level. The combined multi-scale representation resembles a binary counter generalised to sinusoidal bases: low dimensions encode fine-grained position, high dimensions encode coarse position.

## Generalisation to Longer Sequences

Because the PE formula is deterministic and not learned, it produces well-defined values for any position pos regardless of the maximum length seen during training. The encoding at positions beyond max_len_train are smooth continuations of the same sinusoidal curves. In practice, models trained with sinusoidal PE can often process sequences up to 2× the training length without significant degradation, though accuracy does decline because the attention layers have not seen such positions during training. Learned positional embeddings, by contrast, are undefined beyond the training vocabulary and require interpolation or extrapolation heuristics.

```python
import numpy as np

def sinusoidal_pe(max_len, d_model):
    PE = np.zeros((max_len, d_model))
    pos = np.arange(max_len)[:, np.newaxis]
    i   = np.arange(0, d_model, 2)[np.newaxis, :]
    PE[:, 0::2] = np.sin(pos / np.power(10000.0, i / d_model))
    PE[:, 1::2] = np.cos(pos / np.power(10000.0, i / d_model))
    return PE

train_len, d_model = 128, 64
pe_train = sinusoidal_pe(train_len, d_model)
pe_long  = sinusoidal_pe(train_len * 2, d_model)    # 2x longer at test time

assert np.allclose(pe_train, pe_long[:train_len]), 'PE within train range must match!'
print('PE[0:{:d}] identical in train and long context: PASS'.format(train_len))

delta_train = np.diff(pe_train, axis=0)
delta_extra = np.diff(pe_long[train_len:], axis=0)
print('Mean |delta| in train region: {:.4f}'.format(np.abs(delta_train).mean()))
print('Mean |delta| in extra region: {:.4f}'.format(np.abs(delta_extra).mean()))
print('Similar -> smooth continuation beyond train length.')

pe_test = pe_long
norms = np.linalg.norm(pe_test, axis=1, keepdims=True) + 1e-9
cos_sim = (pe_test / norms) @ (pe_test / norms).T
np.fill_diagonal(cos_sim, 0)
print('Max off-diagonal cos similarity (all positions): {:.4f}'.format(cos_sim.max()))
print('Low -> unique encoding even beyond training length.')
```

## With vs Without Positional Encoding

Without positional encoding, the Transformer treats its input as a set rather than a sequence. For any task where the output depends on token order (translation, language modelling, sequence classification based on word order), removing PE causes significant degradation. The degradation is total for tasks where two different orderings map to completely different semantics (e.g., 'man bites dog' vs 'dog bites man'). For bag-of-words tasks (sentiment classification of short text) the effect is mild.

```python
import numpy as np

def softmax(S):
    S = S - S.max(axis=-1, keepdims=True)
    e = np.exp(S); return e / e.sum(axis=-1, keepdims=True)

def sdp_attn(Q, K, V):
    A = softmax(Q @ K.T / np.sqrt(Q.shape[-1]))
    return A @ V

def sinusoidal_pe(n, d):
    PE = np.zeros((n, d))
    pos = np.arange(n)[:, np.newaxis]
    i   = np.arange(0, d, 2)[np.newaxis, :]
    PE[:, 0::2] = np.sin(pos / np.power(10000.0, i / d))
    PE[:, 1::2] = np.cos(pos / np.power(10000.0, i / d))
    return PE

np.random.seed(0)
n, d = 8, 32
W = np.random.randn(d, d) * 0.1
X = np.random.randn(n, d)
X_pe = X + sinusoidal_pe(n, d)

# Test: is the output permutation equivariant without PE?
perm = np.random.permutation(n)
out_no_pe        = sdp_attn(X @ W, X @ W, X)
out_perm_no_pe   = sdp_attn((X[perm] @ W), (X[perm] @ W), X[perm])
no_pe_equiv = np.allclose(out_no_pe[perm], out_perm_no_pe, atol=1e-10)
print('No PE  — permutation equivariant (output reorders with input):', no_pe_equiv)

out_pe           = sdp_attn(X_pe @ W, X_pe @ W, X_pe)
X_pe_perm = X[perm] + sinusoidal_pe(n, d)
out_perm_pe      = sdp_attn(X_pe_perm @ W, X_pe_perm @ W, X_pe_perm)
pe_equiv = np.allclose(out_pe[perm], out_perm_pe, atol=1e-5)
print('With PE — permutation equivariant:', pe_equiv)
print('PE breaks permutation symmetry: model distinguishes token order.')
```

## Comparison of Positional Encodings

Sinusoidal PE was the standard until learned positional embeddings (BERT, GPT-2) showed that data-driven positions improve downstream task performance at the cost of extrapolation ability. RoPE and ALiBi later restored length generalisation with different mechanisms: RoPE rotates Q and K directly in the complex plane (introducing relative position into the attention score), while ALiBi subtracts a linear position bias from attention scores without modifying Q or K. Current best practice for models that need to extend to long contexts is RoPE with frequency interpolation (YaRN, LongRoPE).

| Encoding | Extrapolates Beyond Train Len | Relative Position Info | Learnable Params | Used In |
| --- | --- | --- | --- | --- |
| Sinusoidal (Vaswani 2017) | Yes — formula extrapolates smoothly | Implicit via linear-shift property | None | Original Transformer, some encoder-decoder models |
| Learned absolute | No — undefined beyond vocab size | None explicit | max_len × d_model | BERT, GPT-2, ViT |
| RoPE (Su et al. 2021) | Yes with frequency scaling | Yes — explicit rotation by relative angle | None | LLaMA, Mistral, Falcon, Gemma, PaLM 2 |
| ALiBi (Press et al. 2022) | Yes — linear bias extrapolates | Yes — linear distance penalty per head | h learnable slopes (or fixed) | BLOOM, MPT, some OPT variants |
| NoPE (no PE) | Yes (no position at all) | None — bag-of-words | None | Some encoder-only models; relative PE in T5 |

For new architectures intended to handle variable or long context, RoPE with rope_theta tuning (increasing 10000 to 500,000 for context extension) is the current default. ALiBi offers simpler implementation and strong length generalisation but lacks the relative-position expressiveness of RoPE. Sinusoidal PE remains valuable for understanding — its linear-shift property is the conceptual ancestor of RoPE's rotation mechanism.

---

