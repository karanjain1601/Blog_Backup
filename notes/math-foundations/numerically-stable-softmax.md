---
title: "Numerically Stable Softmax and Log-Softmax"
slug: "numerically-stable-softmax"
description: "Derivation of naive softmax instabilities, the max-shift stabilization, log-softmax, PyTorch F.cross_entropy internals, temperature scaling, and online softmax for streaming inference."
tags: ["numerical-methods", "math", "foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type": "text", "content": "Softmax is the most widely used normalization function in deep learning — it appears in output layers, attention mechanisms, mixture models, and policy networks. Despite its simple formula, naive softmax implementations fail catastrophically for large or small logits. Understanding why softmax is numerically unstable, how the max-shift trick fixes it, and how log-softmax and cross-entropy compose into a safe pipeline is essential for anyone implementing custom attention, loss functions, or inference kernels. The online softmax algorithm, used by FlashAttention, further shows how to compute softmax in a single streaming pass without materializing the full denominator."}, {"type": "heading", "level": 2, "content": "Core Definition"}, {"type": "text", "content": "Given a vector x = (x₁, …, xₙ), softmax produces a probability distribution:\n\nsoftmax(x)ᵢ = exp(xᵢ) / Σⱼ exp(xⱼ)\n\nProperties: all outputs are in (0,1), outputs sum to 1, translation-invariant (softmax(x+c) = softmax(x) for any scalar c), and preserves relative ordering.\n\nNaive implementation problems:\n- If any xᵢ > 88.72 in fp32, exp(xᵢ) = ∞, making the denominator ∞, and 0/∞ = NaN or ∞/∞ = NaN.\n- If all xᵢ < −87.34 in fp32, all exp(xᵢ) underflow to 0, giving 0/0 = NaN.\n- These failures are common in early training (random initialization can produce large logits), with temperature T < 1, and in attention with large d_k.\n\nThe fix: exploit translation invariance. Subtract m = max(x) before exponentiating."}, {"type": "code", "language": "python", "content": "import numpy as np\nimport torch\nimport torch.nn.functional as F\n\n# Naive softmax fails with large or small logits\ndef naive_softmax(x):\n    e = np.exp(x)\n    return e / e.sum()\n\n# Stable softmax: subtract max first\ndef stable_softmax(x):\n    e = np.exp(x - x.max())\n    return e / e.sum()\n\n# Test cases\ntest_cases = {\n    \"normal\":      np.array([1.0, 2.0, 3.0]),\n    \"large pos\":   np.array([100.0, 101.0, 102.0]),\n    \"extreme pos\": np.array([1000.0, 1001.0, 1002.0]),\n    \"large neg\":   np.array([-100.0, -101.0, -102.0]),\n}\n\nprint(f\"{'Case':<15} {'naive':<25} {'stable':<25}\")\nprint(\"-\" * 65)\nfor name, x in test_cases.items():\n    naive  = naive_softmax(x)\n    stable = stable_softmax(x)\n    print(f\"{name:<15} {str(np.round(naive,4)):<25} {str(np.round(stable,4)):<25}\")\n\n# Mathematical equivalence: softmax(x) = softmax(x - c) for any c\nx = np.array([1.0, 2.0, 3.0])\nprint(\"\\n=== Mathematical Equivalence ===\")\nprint(f\"softmax(x):     {stable_softmax(x)}\")\nprint(f\"softmax(x-100): {stable_softmax(x - 100.0)}\")\nprint(f\"softmax(x+100): {stable_softmax(x + 100.0)}\")\n# All identical — softmax is translation-invariant"}, {"type": "heading", "level": 2, "content": "Mathematical Derivation of Stability"}, {"type": "text", "content": "The translation invariance of softmax is the key insight:\n\nsoftmax(x)ᵢ = exp(xᵢ) / Σⱼ exp(xⱼ)\n             = exp(xᵢ − m) × exp(m) / [Σⱼ exp(xⱼ − m) × exp(m)]   (multiply num/denom by exp(−m))\n             = exp(xᵢ − m) / Σⱼ exp(xⱼ − m)\n\nWith m = max(x):\n- The largest exponent argument is xₘₐₓ − m = 0, so exp(0) = 1. No overflow.\n- All other arguments are ≤ 0, so all exp values are in (0, 1]. No overflow.\n- The minimum argument is x_min − m. For typical logit ranges (< 100 units), exp(−100) ≈ 3.7×10⁻⁴⁴ in fp32, which is close to the underflow threshold but the underflowed-to-zero terms contribute negligibly to the denominator anyway.\n\nThis algebraic identity comes at no accuracy cost and requires only one extra pass to find the maximum."}, {"type": "heading", "level": 2, "content": "Log-Softmax and Cross-Entropy"}, {"type": "text", "content": "Log-softmax is log applied to softmax:\n\nlog softmax(x)ᵢ = log(exp(xᵢ) / Σⱼ exp(xⱼ))\n               = xᵢ − log Σⱼ exp(xⱼ)\n               = xᵢ − logsumexp(x)\n               = xᵢ − m − log Σⱼ exp(xⱼ − m)    (stable form)\n\nThis is a pure subtraction on the output — no exp on the result side. The only exp calls are in computing Σⱼ exp(xⱼ − m), which is safe because all arguments are ≤ 0.\n\nNegative log-likelihood (NLL) loss for class c: loss = −log softmax(x)_c = −log softmax(x)[c].\n\nPyTorch's F.cross_entropy(logits, target) implements exactly this: it computes log_softmax stably and then selects the negative value at the target index. It is the preferred pattern and should be used instead of manual softmax → log → index."}, {"type": "code", "language": "python", "content": "import torch\nimport torch.nn.functional as F\nimport numpy as np\n\n# Stable log-softmax from scratch\ndef stable_log_softmax(x):\n    \"\"\"Numerically stable log-softmax using logsumexp trick.\"\"\"\n    m = x.max()\n    log_Z = m + np.log(np.sum(np.exp(x - m)))  # stable logsumexp\n    return x - log_Z\n\n# Comparison: unstable vs stable log-softmax\nlogits = np.array([1000.0, 1001.0, 1002.0], dtype=np.float32)\n\n# Naive: log(softmax(x)) — two-step, fails\nnaive_sm  = np.exp(logits) / np.sum(np.exp(logits))   # overflow\nprint(\"Naive softmax:     \", naive_sm)                  # nan\n\n# Stable from scratch\nprint(\"Stable log_softmax:\", stable_log_softmax(logits))  # [-2.408, -1.408, -0.408]\n\n# PyTorch (use this in practice)\nlogits_t = torch.tensor(logits)\nprint(\"F.log_softmax:     \", F.log_softmax(logits_t, dim=0).numpy())\n\n# Cross-entropy: fused stable operation\nbatch   = torch.tensor([[1000.0, 1001.0, 1002.0]])\ntarget  = torch.tensor([2])  # correct class = 2\n\n# WRONG: manual pipeline\nprobs = torch.softmax(batch, dim=1)         # nan\nloss_bad = -torch.log(probs[:, 2])\nprint(\"\\nManual softmax->log->NLL:\", loss_bad.item())   # nan\n\n# CORRECT: fused\nloss_good = F.cross_entropy(batch, target)\nprint(\"F.cross_entropy:         \", loss_good.item())    # 0.4076\n\n# Internals of F.cross_entropy\nlog_sm   = F.log_softmax(batch, dim=1)\nloss_nll = F.nll_loss(log_sm, target)\nprint(\"log_softmax + NLL:       \", loss_nll.item())     # 0.4076 (same)"}, {"type": "heading", "level": 2, "content": "Temperature Scaling"}, {"type": "text", "content": "Temperature scaling modifies softmax sharpness:\n\nsoftmax(x/T)ᵢ = exp(xᵢ/T) / Σⱼ exp(xⱼ/T)\n\n- T → 0: argmax (one-hot distribution)\n- T = 1: standard softmax\n- T → ∞: uniform distribution\n\nSmall T < 1 (sharpening) divides logits by T, amplifying their magnitude by 1/T. This increases overflow risk significantly. For temperature T = 0.1 and initial logits near 50 (not unusual in large models), the effective logits become 500 — far above the fp32 overflow threshold of 88.72.\n\nThe stable implementation: apply the max-shift trick after dividing by T. PyTorch's F.softmax(logits / T) does this correctly because F.softmax is internally stable. A manual implementation must explicitly subtract the max after dividing."}, {"type": "code", "language": "python", "content": "import numpy as np\nimport torch\nimport torch.nn.functional as F\n\n# Temperature scaling\ndef temp_softmax(x, T=1.0):\n    \"\"\"Numerically stable temperature-scaled softmax.\"\"\"\n    scaled = x / T\n    scaled = scaled - scaled.max()  # max-shift AFTER temperature scaling\n    e = np.exp(scaled)\n    return e / e.sum()\n\nx = np.array([1.0, 2.0, 3.0, 4.0, 5.0])\nprint(\"=== Effect of Temperature ===\")\nfor T in [0.1, 0.5, 1.0, 2.0, 10.0]:\n    s = temp_softmax(x, T)\n    print(f\"T={T:4.1f}: {np.round(s, 3)}\")\n# T=0.1 → very peaked; T=10 → nearly uniform\n\n# Overflow with naive temperature scaling\nx_large = np.array([50.0, 60.0, 70.0], dtype=np.float32)\nT = 0.1\nprint(\"\\n=== Overflow with small T ===\")\nscaled_naive = x_large / T   # [500, 600, 700] — far above fp32 overflow threshold\nprint(f\"Logits / T = {scaled_naive}\")\nprint(f\"np.exp(700) = {np.exp(np.float32(700))}\")  # inf\nnaive = np.exp(scaled_naive); print(f\"Naive softmax: {naive / naive.sum()}\")  # nan\n\n# Stable: subtract max AFTER dividing by T\nscaled_stable = scaled_naive - scaled_naive.max()\ne = np.exp(scaled_stable); print(f\"Stable softmax: {np.round(e / e.sum(), 4)}\")\n\n# PyTorch F.softmax is always stable\nlogits_t = torch.tensor(x_large)\nprint(f\"F.softmax(x/T=0.1): {F.softmax(logits_t / T, dim=0).numpy()}\")"}, {"type": "heading", "level": 2, "content": "Online Softmax for Streaming Inference"}, {"type": "text", "content": "Standard softmax requires two passes over the input: one to find the maximum (for stability), and one to compute exp and normalize. For memory-constrained inference (e.g., FlashAttention processing attention scores in tiles), an online one-pass algorithm is needed.\n\nThe online softmax algorithm maintains a running maximum m and a running sum s. When a new element xₜ arrives:\n- m_new = max(m_old, xₜ)\n- s_new = s_old × exp(m_old − m_new) + exp(xₜ − m_new)\n\nThe correction factor exp(m_old − m_new) rescales previously accumulated exp values to the new running maximum. At each step, the current estimate softmax(x_{1:t}) can be computed as exp(xᵢ − m_t) / s_t for any previous xᵢ, though in practice FlashAttention computes the weighted value accumulation online without materializing individual softmax values."}, {"type": "code", "language": "python", "content": "import numpy as np\nimport torch\n\ndef online_softmax(x):\n    \"\"\"\n    Online (one-pass) softmax — the algorithm behind FlashAttention.\n    Returns softmax values with numerically stable running max/sum.\n    \"\"\"\n    m = -np.inf   # running maximum\n    s = 0.0       # running sum of exp(xᵢ - m)\n    for xi in x:\n        m_new = max(m, xi)\n        s = s * np.exp(m - m_new) + np.exp(xi - m_new)  # rescale old, add new\n        m = m_new\n    return np.array([np.exp(xi - m) / s for xi in x])\n\ndef two_pass_softmax(x):\n    \"\"\"Standard two-pass stable softmax for comparison.\"\"\"\n    e = np.exp(x - x.max())\n    return e / e.sum()\n\n# Verify correctness\ntest_cases = [\n    np.array([1.0, 2.0, 3.0]),\n    np.array([1000.0, 1001.0, 1002.0]),\n    np.array([-100.0, -50.0, 0.0, 50.0]),\n]\nprint(\"=== Online vs Two-Pass Softmax ===\")\nfor x in test_cases:\n    online    = online_softmax(x)\n    two_pass  = two_pass_softmax(x)\n    max_diff  = np.max(np.abs(online - two_pass))\n    print(f\"x~[{x[0]:.0f}..{x[-1]:.0f}]: online={np.round(online,4)}  max_diff={max_diff:.2e}\")\n\n# Online softmax for attention (simplified FlashAttention pattern)\ndef flash_attention_simple(Q, K, V, scale):\n    \"\"\"Single-head attention with online softmax (no materialized attention matrix).\"\"\"\n    T_q, T_k = Q.shape[0], K.shape[0]\n    output = np.zeros_like(Q)\n    for i in range(T_q):\n        scores = (Q[i] @ K.T) * scale   # (T_k,)\n        attn   = online_softmax(scores)  # online stable softmax\n        output[i] = attn @ V\n    return output\n\nnp.random.seed(42)\nd, T = 8, 4\nQ = np.random.randn(T, d); K = np.random.randn(T, d); V = np.random.randn(T, d)\nout = flash_attention_simple(Q, K, V, scale=1.0/np.sqrt(d))\nprint(f\"\\nAttention output shape: {out.shape}, norm: {np.linalg.norm(out):.4f}\")"}, {"type": "heading", "level": 2, "content": "Pitfalls"}, {"type": "text", "content": "Common softmax implementation mistakes:\n\n1. **Computing log(softmax(x)) in two steps**: always use log_softmax or F.cross_entropy instead.\n\n2. **Forgetting max-shift after temperature scaling**: temperature < 1 amplifies logits before the max-shift is applied in naive implementations.\n\n3. **Using fp16 for attention scores without overflow check**: Q@K^T/√d can produce values above the fp16 overflow threshold of ~11 for large models with high-dimensional keys.\n\n4. **Applying softmax along the wrong dimension**: in batched settings, softmax must be applied along dim=1 (over classes) not dim=0 (over batch). A bug here produces valid-looking outputs with wrong semantics."}, {"type": "heading", "level": 2, "content": "Practical Guidance"}, {"type": "text", "content": "Best practices for softmax in production:\n\n- **For classification**: always use F.cross_entropy(logits, target), never compute softmax probabilities manually and then log them.\n- **For inference probabilities**: use F.softmax(logits, dim=-1) — PyTorch's implementation is internally stable.\n- **For temperature sampling**: compute F.softmax(logits / T, dim=-1) in one step rather than dividing after softmax.\n- **For custom attention**: ensure the softmax is computed over the correct sequence dimension and consider using F.scaled_dot_product_attention which handles numerical stability internally.\n- **For numerical testing**: verify that your implementation matches F.softmax on both normal inputs [1,2,3] and extreme inputs [1000,1001,1002]."}, {"type": "callout", "variant": "tip", "title": "Use F.scaled_dot_product_attention", "content": "PyTorch 2.0+ includes F.scaled_dot_product_attention which dispatches to FlashAttention when possible, handling numerical stability (online softmax), memory efficiency (no materialized attention matrix), and mask handling correctly. Unless implementing a custom attention variant, prefer this over manual Q@K^T / sqrt(d) + softmax patterns."}, {"type": "table", "headers": ["Pattern", "Numerically Safe?", "Preferred Alternative"], "rows": [["np.exp(x)/np.exp(x).sum()", "No (overflow)", "stable_softmax(x - x.max())"], ["torch.log(torch.softmax(x,d))", "No (nan chain)", "F.log_softmax(x, dim=d)"], ["-log(softmax(x)[target])", "No (two-step)", "F.cross_entropy(x, target)"], ["softmax(x/T) with T<1 (manual)", "No (overflow)", "F.softmax(x/T, dim=-1)"], ["Q@K.T/sqrt(d) + softmax manually", "Risky in fp16", "F.scaled_dot_product_attention"], ["logaddexp.reduce(x)", "Yes", "torch.logsumexp(x, dim=0)"]]}, {"type": "divider"}, {"type": "heading", "level": 2, "content": "Key Takeaways"}, {"type": "list", "ordered": false, "items": ["Naive softmax overflows for x_i > 88.72 (fp32) or > 11.09 (fp16) and underflows to NaN when all logits are very negative.", "The max-shift trick softmax(x − max(x)) is mathematically identical to softmax(x) but numerically safe; it costs one extra pass to find the maximum.", "Log-softmax = x − logsumexp(x) = xᵢ − m − log Σ exp(xⱼ − m); the final output is a pure subtraction with no overflow risk.", "Always use F.cross_entropy in PyTorch — it fuses log_softmax and NLL loss in one stable operation.", "Temperature T < 1 amplifies logits by 1/T before the max-shift — always apply the max-shift after temperature scaling, not before.", "Online softmax maintains a running (max, sum) pair and rescales previously seen values when a new maximum is encountered — this is the algorithm behind FlashAttention's tiled computation.", "For production inference, use F.scaled_dot_product_attention (PyTorch 2.0+) which dispatches to FlashAttention and handles all stability and memory concerns automatically."]}]"
---
# Numerically Stable Softmax and Log-Softmax

Softmax is the most widely used normalization function in deep learning — it appears in output layers, attention mechanisms, mixture models, and policy networks. Despite its simple formula, naive softmax implementations fail catastrophically for large or small logits. Understanding why softmax is numerically unstable, how the max-shift trick fixes it, and how log-softmax and cross-entropy compose into a safe pipeline is essential for anyone implementing custom attention, loss functions, or inference kernels. The online softmax algorithm, used by FlashAttention, further shows how to compute softmax in a single streaming pass without materializing the full denominator.

## Core Definition

Given a vector x = (x₁, …, xₙ), softmax produces a probability distribution:

softmax(x)ᵢ = exp(xᵢ) / Σⱼ exp(xⱼ)

Properties: all outputs are in (0,1), outputs sum to 1, translation-invariant (softmax(x+c) = softmax(x) for any scalar c), and preserves relative ordering.

Naive implementation problems:
- If any xᵢ > 88.72 in fp32, exp(xᵢ) = ∞, making the denominator ∞, and 0/∞ = NaN or ∞/∞ = NaN.
- If all xᵢ < −87.34 in fp32, all exp(xᵢ) underflow to 0, giving 0/0 = NaN.
- These failures are common in early training (random initialization can produce large logits), with temperature T < 1, and in attention with large d_k.

The fix: exploit translation invariance. Subtract m = max(x) before exponentiating.

```python
import numpy as np
import torch
import torch.nn.functional as F

# Naive softmax fails with large or small logits
def naive_softmax(x):
    e = np.exp(x)
    return e / e.sum()

# Stable softmax: subtract max first
def stable_softmax(x):
    e = np.exp(x - x.max())
    return e / e.sum()

# Test cases
test_cases = {
    "normal":      np.array([1.0, 2.0, 3.0]),
    "large pos":   np.array([100.0, 101.0, 102.0]),
    "extreme pos": np.array([1000.0, 1001.0, 1002.0]),
    "large neg":   np.array([-100.0, -101.0, -102.0]),
}

print(f"{'Case':<15} {'naive':<25} {'stable':<25}")
print("-" * 65)
for name, x in test_cases.items():
    naive  = naive_softmax(x)
    stable = stable_softmax(x)
    print(f"{name:<15} {str(np.round(naive,4)):<25} {str(np.round(stable,4)):<25}")

# Mathematical equivalence: softmax(x) = softmax(x - c) for any c
x = np.array([1.0, 2.0, 3.0])
print("\n=== Mathematical Equivalence ===")
print(f"softmax(x):     {stable_softmax(x)}")
print(f"softmax(x-100): {stable_softmax(x - 100.0)}")
print(f"softmax(x+100): {stable_softmax(x + 100.0)}")
# All identical — softmax is translation-invariant
```

## Mathematical Derivation of Stability

The translation invariance of softmax is the key insight:

softmax(x)ᵢ = exp(xᵢ) / Σⱼ exp(xⱼ)
             = exp(xᵢ − m) × exp(m) / [Σⱼ exp(xⱼ − m) × exp(m)]   (multiply num/denom by exp(−m))
             = exp(xᵢ − m) / Σⱼ exp(xⱼ − m)

With m = max(x):
- The largest exponent argument is xₘₐₓ − m = 0, so exp(0) = 1. No overflow.
- All other arguments are ≤ 0, so all exp values are in (0, 1]. No overflow.
- The minimum argument is x_min − m. For typical logit ranges (< 100 units), exp(−100) ≈ 3.7×10⁻⁴⁴ in fp32, which is close to the underflow threshold but the underflowed-to-zero terms contribute negligibly to the denominator anyway.

This algebraic identity comes at no accuracy cost and requires only one extra pass to find the maximum.

## Log-Softmax and Cross-Entropy

Log-softmax is log applied to softmax:

log softmax(x)ᵢ = log(exp(xᵢ) / Σⱼ exp(xⱼ))
               = xᵢ − log Σⱼ exp(xⱼ)
               = xᵢ − logsumexp(x)
               = xᵢ − m − log Σⱼ exp(xⱼ − m)    (stable form)

This is a pure subtraction on the output — no exp on the result side. The only exp calls are in computing Σⱼ exp(xⱼ − m), which is safe because all arguments are ≤ 0.

Negative log-likelihood (NLL) loss for class c: loss = −log softmax(x)_c = −log softmax(x)[c].

PyTorch's F.cross_entropy(logits, target) implements exactly this: it computes log_softmax stably and then selects the negative value at the target index. It is the preferred pattern and should be used instead of manual softmax → log → index.

```python
import torch
import torch.nn.functional as F
import numpy as np

# Stable log-softmax from scratch
def stable_log_softmax(x):
    """Numerically stable log-softmax using logsumexp trick."""
    m = x.max()
    log_Z = m + np.log(np.sum(np.exp(x - m)))  # stable logsumexp
    return x - log_Z

# Comparison: unstable vs stable log-softmax
logits = np.array([1000.0, 1001.0, 1002.0], dtype=np.float32)

# Naive: log(softmax(x)) — two-step, fails
naive_sm  = np.exp(logits) / np.sum(np.exp(logits))   # overflow
print("Naive softmax:     ", naive_sm)                  # nan

# Stable from scratch
print("Stable log_softmax:", stable_log_softmax(logits))  # [-2.408, -1.408, -0.408]

# PyTorch (use this in practice)
logits_t = torch.tensor(logits)
print("F.log_softmax:     ", F.log_softmax(logits_t, dim=0).numpy())

# Cross-entropy: fused stable operation
batch   = torch.tensor([[1000.0, 1001.0, 1002.0]])
target  = torch.tensor([2])  # correct class = 2

# WRONG: manual pipeline
probs = torch.softmax(batch, dim=1)         # nan
loss_bad = -torch.log(probs[:, 2])
print("\nManual softmax->log->NLL:", loss_bad.item())   # nan

# CORRECT: fused
loss_good = F.cross_entropy(batch, target)
print("F.cross_entropy:         ", loss_good.item())    # 0.4076

# Internals of F.cross_entropy
log_sm   = F.log_softmax(batch, dim=1)
loss_nll = F.nll_loss(log_sm, target)
print("log_softmax + NLL:       ", loss_nll.item())     # 0.4076 (same)
```

## Temperature Scaling

Temperature scaling modifies softmax sharpness:

softmax(x/T)ᵢ = exp(xᵢ/T) / Σⱼ exp(xⱼ/T)

- T → 0: argmax (one-hot distribution)
- T = 1: standard softmax
- T → ∞: uniform distribution

Small T < 1 (sharpening) divides logits by T, amplifying their magnitude by 1/T. This increases overflow risk significantly. For temperature T = 0.1 and initial logits near 50 (not unusual in large models), the effective logits become 500 — far above the fp32 overflow threshold of 88.72.

The stable implementation: apply the max-shift trick after dividing by T. PyTorch's F.softmax(logits / T) does this correctly because F.softmax is internally stable. A manual implementation must explicitly subtract the max after dividing.

```python
import numpy as np
import torch
import torch.nn.functional as F

# Temperature scaling
def temp_softmax(x, T=1.0):
    """Numerically stable temperature-scaled softmax."""
    scaled = x / T
    scaled = scaled - scaled.max()  # max-shift AFTER temperature scaling
    e = np.exp(scaled)
    return e / e.sum()

x = np.array([1.0, 2.0, 3.0, 4.0, 5.0])
print("=== Effect of Temperature ===")
for T in [0.1, 0.5, 1.0, 2.0, 10.0]:
    s = temp_softmax(x, T)
    print(f"T={T:4.1f}: {np.round(s, 3)}")
# T=0.1 → very peaked; T=10 → nearly uniform

# Overflow with naive temperature scaling
x_large = np.array([50.0, 60.0, 70.0], dtype=np.float32)
T = 0.1
print("\n=== Overflow with small T ===")
scaled_naive = x_large / T   # [500, 600, 700] — far above fp32 overflow threshold
print(f"Logits / T = {scaled_naive}")
print(f"np.exp(700) = {np.exp(np.float32(700))}")  # inf
naive = np.exp(scaled_naive); print(f"Naive softmax: {naive / naive.sum()}")  # nan

# Stable: subtract max AFTER dividing by T
scaled_stable = scaled_naive - scaled_naive.max()
e = np.exp(scaled_stable); print(f"Stable softmax: {np.round(e / e.sum(), 4)}")

# PyTorch F.softmax is always stable
logits_t = torch.tensor(x_large)
print(f"F.softmax(x/T=0.1): {F.softmax(logits_t / T, dim=0).numpy()}")
```

## Online Softmax for Streaming Inference

Standard softmax requires two passes over the input: one to find the maximum (for stability), and one to compute exp and normalize. For memory-constrained inference (e.g., FlashAttention processing attention scores in tiles), an online one-pass algorithm is needed.

The online softmax algorithm maintains a running maximum m and a running sum s. When a new element xₜ arrives:
- m_new = max(m_old, xₜ)
- s_new = s_old × exp(m_old − m_new) + exp(xₜ − m_new)

The correction factor exp(m_old − m_new) rescales previously accumulated exp values to the new running maximum. At each step, the current estimate softmax(x_{1:t}) can be computed as exp(xᵢ − m_t) / s_t for any previous xᵢ, though in practice FlashAttention computes the weighted value accumulation online without materializing individual softmax values.

```python
import numpy as np
import torch

def online_softmax(x):
    """
    Online (one-pass) softmax — the algorithm behind FlashAttention.
    Returns softmax values with numerically stable running max/sum.
    """
    m = -np.inf   # running maximum
    s = 0.0       # running sum of exp(xᵢ - m)
    for xi in x:
        m_new = max(m, xi)
        s = s * np.exp(m - m_new) + np.exp(xi - m_new)  # rescale old, add new
        m = m_new
    return np.array([np.exp(xi - m) / s for xi in x])

def two_pass_softmax(x):
    """Standard two-pass stable softmax for comparison."""
    e = np.exp(x - x.max())
    return e / e.sum()

# Verify correctness
test_cases = [
    np.array([1.0, 2.0, 3.0]),
    np.array([1000.0, 1001.0, 1002.0]),
    np.array([-100.0, -50.0, 0.0, 50.0]),
]
print("=== Online vs Two-Pass Softmax ===")
for x in test_cases:
    online    = online_softmax(x)
    two_pass  = two_pass_softmax(x)
    max_diff  = np.max(np.abs(online - two_pass))
    print(f"x~[{x[0]:.0f}..{x[-1]:.0f}]: online={np.round(online,4)}  max_diff={max_diff:.2e}")

# Online softmax for attention (simplified FlashAttention pattern)
def flash_attention_simple(Q, K, V, scale):
    """Single-head attention with online softmax (no materialized attention matrix)."""
    T_q, T_k = Q.shape[0], K.shape[0]
    output = np.zeros_like(Q)
    for i in range(T_q):
        scores = (Q[i] @ K.T) * scale   # (T_k,)
        attn   = online_softmax(scores)  # online stable softmax
        output[i] = attn @ V
    return output

np.random.seed(42)
d, T = 8, 4
Q = np.random.randn(T, d); K = np.random.randn(T, d); V = np.random.randn(T, d)
out = flash_attention_simple(Q, K, V, scale=1.0/np.sqrt(d))
print(f"\nAttention output shape: {out.shape}, norm: {np.linalg.norm(out):.4f}")
```

## Pitfalls

Common softmax implementation mistakes:

1. **Computing log(softmax(x)) in two steps**: always use log_softmax or F.cross_entropy instead.

2. **Forgetting max-shift after temperature scaling**: temperature < 1 amplifies logits before the max-shift is applied in naive implementations.

3. **Using fp16 for attention scores without overflow check**: Q@K^T/√d can produce values above the fp16 overflow threshold of ~11 for large models with high-dimensional keys.

4. **Applying softmax along the wrong dimension**: in batched settings, softmax must be applied along dim=1 (over classes) not dim=0 (over batch). A bug here produces valid-looking outputs with wrong semantics.

## Practical Guidance

Best practices for softmax in production:

- **For classification**: always use F.cross_entropy(logits, target), never compute softmax probabilities manually and then log them.
- **For inference probabilities**: use F.softmax(logits, dim=-1) — PyTorch's implementation is internally stable.
- **For temperature sampling**: compute F.softmax(logits / T, dim=-1) in one step rather than dividing after softmax.
- **For custom attention**: ensure the softmax is computed over the correct sequence dimension and consider using F.scaled_dot_product_attention which handles numerical stability internally.
- **For numerical testing**: verify that your implementation matches F.softmax on both normal inputs [1,2,3] and extreme inputs [1000,1001,1002].

> **TIP: Use F.scaled_dot_product_attention**
>
> PyTorch 2.0+ includes F.scaled_dot_product_attention which dispatches to FlashAttention when possible, handling numerical stability (online softmax), memory efficiency (no materialized attention matrix), and mask handling correctly. Unless implementing a custom attention variant, prefer this over manual Q@K^T / sqrt(d) + softmax patterns.

| Pattern | Numerically Safe? | Preferred Alternative |
| --- | --- | --- |
| np.exp(x)/np.exp(x).sum() | No (overflow) | stable_softmax(x - x.max()) |
| torch.log(torch.softmax(x,d)) | No (nan chain) | F.log_softmax(x, dim=d) |
| -log(softmax(x)[target]) | No (two-step) | F.cross_entropy(x, target) |
| softmax(x/T) with T<1 (manual) | No (overflow) | F.softmax(x/T, dim=-1) |
| Q@K.T/sqrt(d) + softmax manually | Risky in fp16 | F.scaled_dot_product_attention |
| logaddexp.reduce(x) | Yes | torch.logsumexp(x, dim=0) |

---

## Key Takeaways

- Naive softmax overflows for x_i > 88.72 (fp32) or > 11.09 (fp16) and underflows to NaN when all logits are very negative.
- The max-shift trick softmax(x − max(x)) is mathematically identical to softmax(x) but numerically safe; it costs one extra pass to find the maximum.
- Log-softmax = x − logsumexp(x) = xᵢ − m − log Σ exp(xⱼ − m); the final output is a pure subtraction with no overflow risk.
- Always use F.cross_entropy in PyTorch — it fuses log_softmax and NLL loss in one stable operation.
- Temperature T < 1 amplifies logits by 1/T before the max-shift — always apply the max-shift after temperature scaling, not before.
- Online softmax maintains a running (max, sum) pair and rescales previously seen values when a new maximum is encountered — this is the algorithm behind FlashAttention's tiled computation.
- For production inference, use F.scaled_dot_product_attention (PyTorch 2.0+) which dispatches to FlashAttention and handles all stability and memory concerns automatically.
