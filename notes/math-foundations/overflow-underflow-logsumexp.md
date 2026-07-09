---
title: "Overflow, Underflow, and the Log-Sum-Exp Trick"
slug: "overflow-underflow-logsumexp"
description: "Floating-point overflow and underflow in exp-based computations, the log-sum-exp trick derivation, numerically stable softmax and log-softmax, and applications in attention, CTC, HMMs, and beam search."
tags: ["numerical-methods", "math", "foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type": "text", "content": "Overflow and underflow are the two modes of catastrophic failure in floating-point computation. Overflow occurs when a computed value exceeds the maximum representable number, producing infinity; underflow collapses a value to zero. Both are silent — computation continues but produces wrong answers. These failures appear constantly in ML: softmax with large logits, log-probabilities over long sequences, normalizing-flow log-determinants, CTC alignment marginalization, and attention over high-dimensional queries. The log-sum-exp trick is arguably the single most important numerical technique in ML, solving both problems simultaneously in the critical context of softmax and log-probability computations."}, {"type": "heading", "level": 2, "content": "Overflow and Underflow Thresholds"}, {"type": "text", "content": "Overflow occurs when a computed value exceeds the maximum representable floating-point number. For the exp() function:\n\n- fp32: exp(x) overflows to ∞ for x > 88.72 (max fp32 ≈ 3.4×10³⁸)\n- fp16: exp(x) overflows for x > 11.09 (max fp16 = 65504)\n- bf16: same exponent range as fp32, so threshold ≈ 88.72\n\nUnderflow occurs when a value is smaller than the minimum normal number and rounds to zero (via subnormals or directly):\n\n- fp32: exp(x) → 0 for x < −87.34\n- fp16: exp(x) → 0 for x < −9.70\n\nIn softmax: if any x_i > 88.72 in fp32, then exp(x_i) = ∞, the denominator is ∞, and 0/∞ or ∞/∞ = NaN. In log-softmax: if all x_i are very negative, Σ exp(x_j) underflows to 0, then log(0) = −∞, making the loss infinite. Both failures are especially common in early training when logits are large or when using fp16."}, {"type": "heading", "level": 2, "content": "The Log-Sum-Exp Trick"}, {"type": "text", "content": "The logsumexp trick provides numerically stable computation of log(Σᵢ exp(xᵢ)) by exploiting the following algebraic identity:\n\nlog Σᵢ exp(xᵢ) = m + log Σᵢ exp(xᵢ − m),  where m = max(x)\n\nProof: log Σᵢ exp(xᵢ) = log[exp(m) × Σᵢ exp(xᵢ − m)] = m + log Σᵢ exp(xᵢ − m).\n\nBy subtracting m = max(x) before exponentiating:\n- The maximum term becomes exp(0) = 1 — no overflow possible.\n- All other terms are ≤ 1 — no overflow.\n- The minimum term is exp(xᵢ − m) ≥ exp(−range) where range is the dynamic range of x — typically no severe underflow unless logits span hundreds of units.\n\nThe result is mathematically identical to the original but numerically safe. This is the foundation of numerically stable softmax, log-softmax, and cross-entropy."}, {"type": "code", "language": "python", "content": "import numpy as np\nimport torch\nimport torch.nn.functional as F\n\n# Problem: naive logsumexp overflows\ndef naive_logsumexp(x):\n    return np.log(np.sum(np.exp(x)))\n\nx = np.array([1000.0, 1001.0, 1002.0], dtype=np.float32)\nprint(\"Naive logsumexp:\", naive_logsumexp(x))  # inf (overflow)\n\n# Solution: stable logsumexp\ndef stable_logsumexp(x):\n    m = np.max(x)\n    return m + np.log(np.sum(np.exp(x - m)))\n\nprint(\"Stable logsumexp:\", stable_logsumexp(x))   # 1002.4076 (correct)\n\n# Verify: mathematically identical for normal inputs\nx2 = np.array([1.0, 2.0, 3.0])\nprint(f\"naive={naive_logsumexp(x2):.6f}  stable={stable_logsumexp(x2):.6f}\")\n\n# PyTorch built-in (use this in production)\nprint(\"torch.logsumexp:\", torch.logsumexp(torch.tensor(x), dim=0))  # 1002.4076\n\n# Underflow: naive log-softmax fails for very negative logits\nx_neg = np.array([-1000.0, -1001.0, -1002.0], dtype=np.float32)\nprint(\"\\n--- Underflow demo ---\")\nprint(\"np.exp(x_neg):\", np.exp(x_neg))     # [0. 0. 0.] — all underflow to 0\nprint(\"naive log(sum(exp)):\", np.log(np.sum(np.exp(x_neg))))  # -inf\nprint(\"stable_logsumexp:\", stable_logsumexp(x_neg))  # -1000.4076 (correct)\n\n# Numerically stable softmax\ndef stable_softmax(x):\n    e = np.exp(x - np.max(x))\n    return e / e.sum()\n\nprint(\"\\n--- Stable softmax ---\")\nprint(\"stable_softmax([1000,1001,1002]):\", np.round(stable_softmax(x), 4))"}, {"type": "heading", "level": 2, "content": "Numerically Stable Softmax and Log-Softmax"}, {"type": "text", "content": "Stable softmax = subtract max before exponentiating:\n\nsoftmax(x)ᵢ = exp(xᵢ − m) / Σⱼ exp(xⱼ − m),  m = max(x)\n\nThis is mathematically equivalent to the original because both numerator and denominator are multiplied by exp(−m), which cancels. The operation costs one additional pass over x (to find the maximum) but is entirely safe.\n\nStable log-softmax builds on stable logsumexp:\n\nlog softmax(x)ᵢ = xᵢ − logsumexp(x) = xᵢ − m − log Σⱼ exp(xⱼ − m)\n\nNote that this is just subtraction — no exp on the output side, so no overflow or underflow on the final values. The only exp calls are in computing Σⱼ exp(xⱼ − m), which is safe because all arguments are ≤ 0.\n\nCross-entropy loss = NLL(log_softmax(logits), targets). PyTorch's F.cross_entropy combines both steps in a single numerically stable fused operation."}, {"type": "code", "language": "python", "content": "import torch\nimport torch.nn.functional as F\nimport numpy as np\n\n# Stable log-softmax from scratch\ndef stable_log_softmax(x):\n    \"\"\"log(exp(xi) / sum(exp(xj))) = xi - logsumexp(x).\"\"\"\n    m = x.max()\n    log_sum = m + np.log(np.sum(np.exp(x - m)))\n    return x - log_sum\n\n# Demonstration with extreme logits\nlogits_np = np.array([1000.0, 1001.0, 1002.0], dtype=np.float32)\nlogits_t  = torch.tensor(logits_np)\n\nprint(\"=== Log-Softmax Comparison ===\")\n# Naive: log(softmax(x)) — two-step, unstable\nnaive_sm  = np.exp(logits_np) / np.sum(np.exp(logits_np))  # inf/inf = nan\nprint(\"naive softmax:\", naive_sm)\n\n# Stable from scratch\nprint(\"stable log_softmax:\", stable_log_softmax(logits_np))\n\n# PyTorch F.log_softmax (stable by design)\nprint(\"F.log_softmax:\", F.log_softmax(logits_t, dim=0).numpy())\n\n# Cross-entropy: always use F.cross_entropy, not manual softmax -> log -> NLL\nprint(\"\\n=== Cross-Entropy Stability ===\")\nbatch_logits = torch.tensor([[1000.0, 1001.0, 1002.0]])\ntarget       = torch.tensor([2])  # class 2 is correct\n\n# WRONG: manual softmax -> log -> NLL\nprobs = torch.softmax(batch_logits, dim=1)  # [0, 0, nan] or similar\nloss_wrong = -torch.log(probs[0, target[0]])\nprint(f\"Wrong (softmax->log->NLL): {loss_wrong.item()}\")  # nan or inf\n\n# CORRECT: F.cross_entropy (fused stable operation)\nloss_correct = F.cross_entropy(batch_logits, target)\nprint(f\"Correct (F.cross_entropy): {loss_correct.item():.6f}\")  # ~0.4076\n\n# Verify: same result with normal logits\nnormal_logits = torch.tensor([[1.0, 2.0, 3.0]])\nprint(\"\\nNormal logits comparison:\")\nprint(f\"  Manual:         {-torch.log(torch.softmax(normal_logits, dim=1)[0, 2]).item():.6f}\")\nprint(f\"  F.cross_entropy:{F.cross_entropy(normal_logits, target).item():.6f}\")"}, {"type": "heading", "level": 2, "content": "Variants and Special Cases"}, {"type": "text", "content": "Log-domain arithmetic is needed whenever multiplying many probabilities, since products underflow rapidly. For a sequence of T tokens each with probability ~0.1, the joint probability is 0.1^T which underflows to 0 for T > 45 in fp32. Log-domain: sum log-probabilities instead.\n\nTemperature scaling softmax(x/T):\n- T < 1 (sharpening): divides by T < 1, which multiplies logit magnitudes by 1/T — making overflow more likely. Always apply the max-shift trick.\n- T > 1 (softening): reduces logit magnitudes, less overflow risk.\n\nlog-sum-exp with two terms: log(exp(a) + exp(b)) = max(a,b) + log(1 + exp(−|a−b|)). This is the logaddexp function in numpy and log1p(exp(x)) for softplus. Both appear frequently in probabilistic models."}, {"type": "heading", "level": 2, "content": "Log-Domain HMM Forward Algorithm"}, {"type": "text", "content": "The HMM forward algorithm computes the probability of an observed sequence by marginalizing over all hidden state sequences. The product of T emission and transition probabilities underflows to zero for long sequences. The log-domain forward algorithm maintains log α_t(s) = log P(x₁,...,xₜ, state_t = s) and performs all summations using logsumexp:\n\nlog α_t(s') = log P(xₜ | s') + logsumexp_s[log α_{t-1}(s) + log A(s→s')]\n\nThis is O(T × S²) in time (same as standard forward algorithm) but stable for sequences of any length."}, {"type": "code", "language": "python", "content": "import numpy as np\n\ndef log_forward_hmm(log_emission, log_transition, log_init):\n    \"\"\"\n    Log-domain HMM forward algorithm (numerically stable).\n    log_emission:   (T, S) log P(x_t | state_s)\n    log_transition: (S, S) log P(state_s' | state_s)\n    log_init:       (S,)   log P(state_s at t=0)\n    Returns: log P(observation sequence)\n    \"\"\"\n    T, S = log_emission.shape\n    log_alpha = log_init + log_emission[0]  # (S,) — init at t=0\n\n    for t in range(1, T):\n        # log_alpha[s'] = log sum_s exp(log_alpha[s] + log_A[s,s'])\n        # Shape broadcast: log_alpha (S,1) + log_transition (S,S) -> (S,S)\n        log_trans_contrib = log_alpha[:, None] + log_transition  # (S, S)\n        log_alpha = np.logaddexp.reduce(log_trans_contrib, axis=0) + log_emission[t]\n\n    # Total log probability: sum over final states\n    return np.logaddexp.reduce(log_alpha)\n\n# Demo: 3-state HMM, 50-step sequence\nnp.random.seed(42)\nS, T = 3, 50\nlog_A = np.log(np.array([[0.7, 0.2, 0.1],\n                           [0.1, 0.6, 0.3],\n                           [0.2, 0.3, 0.5]]))\nlog_B = np.random.randn(T, S) - np.log(S)  # random emission log-probs\nlog_pi = np.log(np.ones(S) / S)\n\nlog_prob = log_forward_hmm(log_B, log_A, log_pi)\nprint(f\"Log P(sequence): {log_prob:.4f}\")\nprint(f\"P(sequence) = exp({log_prob:.4f}) = {np.exp(log_prob):.4e}\")\n# Without log-domain, P would underflow to 0 for T=50 steps"}, {"type": "heading", "level": 2, "content": "Pitfalls"}, {"type": "text", "content": "Common mistakes with overflow/underflow:\n\n1. **Manual softmax before log**: computing log(softmax(x)) in two steps instead of using log_softmax. The intermediate softmax may produce NaN that log then propagates.\n\n2. **Forgetting max-shift when scaling**: dividing logits by temperature < 1 before softmax inflates magnitudes. Always apply temperature first, then use stable softmax.\n\n3. **Using fp16 for attention without max-shift**: attention scores Q@K^T/√d can easily exceed 11 in fp16, causing overflow. Use bf16 or ensure FlashAttention's tiled softmax is active.\n\n4. **Accumulating probabilities across tokens**: multiplying per-token probabilities instead of adding log-probabilities causes rapid underflow for sequences longer than ~50 tokens in fp32."}, {"type": "heading", "level": 2, "content": "Practical Guidance"}, {"type": "text", "content": "Rules for numerically safe computation:\n\n- **Always use F.cross_entropy** in PyTorch, never manual softmax → log → NLL.\n- **Use torch.logsumexp** rather than implementing logsumexp manually.\n- **In custom normalizing-flow implementations**, compute log-determinants as sums of log|diag(J)|, not products of |diag(J)|.\n- **For beam search**, maintain log-probabilities and add per-step log-probs; only convert to probability for final output.\n- **Validate with small test cases**: verify that naive and stable implementations agree on normal logits before testing on extreme inputs."}, {"type": "callout", "variant": "warning", "title": "Temperature < 1 Amplifies Overflow Risk", "content": "Temperature scaling computes softmax(x/T). For T < 1 (sharpening), logits are multiplied by 1/T, increasing their magnitude. With logits already near the fp32 overflow threshold (~88), dividing by T = 0.1 gives logits near 880 — certain overflow. Always apply the max-shift trick explicitly when using temperatures other than 1.0, or use F.softmax(logits / T) which does so internally."}, {"type": "callout", "variant": "tip", "title": "Log-Domain Arithmetic for Long Sequences", "content": "When computing probability of a sequence (product of conditionals), always work in log-domain: add log-probabilities instead of multiplying probabilities. For N tokens each with probability ~0.1, joint probability 0.1^N underflows for N > 45 in fp32. In log-domain, N × log(0.1) ≈ −N × 2.303 remains perfectly representable for any N."}, {"type": "table", "headers": ["Computation", "Naive Failure", "Stable Solution"], "rows": [["logsumexp(x)", "exp overflow", "m + log Σ exp(x-m), m=max(x)"], ["softmax(x)", "exp overflow → NaN", "softmax(x - max(x))"], ["log_softmax(x)", "log(0) when denominator underflows", "x - logsumexp(x)"], ["cross_entropy", "chain of instabilities", "F.cross_entropy (fused)"], ["sequence probability", "product underflows", "sum of log-probs"], ["HMM forward", "α_t → 0 for long T", "log-domain with logaddexp"]]}, {"type": "divider"}, {"type": "heading", "level": 2, "content": "Key Takeaways"}, {"type": "list", "ordered": false, "items": ["exp(x) overflows in fp32 for x > 88.72 and underflows to 0 for x < −87.34; fp16 thresholds are much tighter (±11).", "The log-sum-exp trick log Σ exp(xᵢ) = m + log Σ exp(xᵢ−m) with m = max(x) is mathematically identical but numerically safe.", "Stable softmax subtracts max before exponentiating; stable log-softmax computes xᵢ − logsumexp(x).", "Always use F.cross_entropy (PyTorch) — it fuses log_softmax + NLL in one stable operation.", "Temperature T < 1 amplifies logit magnitudes by 1/T, increasing overflow risk — always use the max-shift trick.", "For long sequences, maintain and accumulate log-probabilities instead of multiplying probabilities (which underflow past ~45 tokens in fp32).", "The log-domain forward algorithm (using logaddexp reductions) enables stable HMM inference over arbitrarily long sequences."]}]"
---
# Overflow, Underflow, and the Log-Sum-Exp Trick

Overflow and underflow are the two modes of catastrophic failure in floating-point computation. Overflow occurs when a computed value exceeds the maximum representable number, producing infinity; underflow collapses a value to zero. Both are silent — computation continues but produces wrong answers. These failures appear constantly in ML: softmax with large logits, log-probabilities over long sequences, normalizing-flow log-determinants, CTC alignment marginalization, and attention over high-dimensional queries. The log-sum-exp trick is arguably the single most important numerical technique in ML, solving both problems simultaneously in the critical context of softmax and log-probability computations.

## Overflow and Underflow Thresholds

Overflow occurs when a computed value exceeds the maximum representable floating-point number. For the exp() function:

- fp32: exp(x) overflows to ∞ for x > 88.72 (max fp32 ≈ 3.4×10³⁸)
- fp16: exp(x) overflows for x > 11.09 (max fp16 = 65504)
- bf16: same exponent range as fp32, so threshold ≈ 88.72

Underflow occurs when a value is smaller than the minimum normal number and rounds to zero (via subnormals or directly):

- fp32: exp(x) → 0 for x < −87.34
- fp16: exp(x) → 0 for x < −9.70

In softmax: if any x_i > 88.72 in fp32, then exp(x_i) = ∞, the denominator is ∞, and 0/∞ or ∞/∞ = NaN. In log-softmax: if all x_i are very negative, Σ exp(x_j) underflows to 0, then log(0) = −∞, making the loss infinite. Both failures are especially common in early training when logits are large or when using fp16.

## The Log-Sum-Exp Trick

The logsumexp trick provides numerically stable computation of log(Σᵢ exp(xᵢ)) by exploiting the following algebraic identity:

log Σᵢ exp(xᵢ) = m + log Σᵢ exp(xᵢ − m),  where m = max(x)

Proof: log Σᵢ exp(xᵢ) = log[exp(m) × Σᵢ exp(xᵢ − m)] = m + log Σᵢ exp(xᵢ − m).

By subtracting m = max(x) before exponentiating:
- The maximum term becomes exp(0) = 1 — no overflow possible.
- All other terms are ≤ 1 — no overflow.
- The minimum term is exp(xᵢ − m) ≥ exp(−range) where range is the dynamic range of x — typically no severe underflow unless logits span hundreds of units.

The result is mathematically identical to the original but numerically safe. This is the foundation of numerically stable softmax, log-softmax, and cross-entropy.

```python
import numpy as np
import torch
import torch.nn.functional as F

# Problem: naive logsumexp overflows
def naive_logsumexp(x):
    return np.log(np.sum(np.exp(x)))

x = np.array([1000.0, 1001.0, 1002.0], dtype=np.float32)
print("Naive logsumexp:", naive_logsumexp(x))  # inf (overflow)

# Solution: stable logsumexp
def stable_logsumexp(x):
    m = np.max(x)
    return m + np.log(np.sum(np.exp(x - m)))

print("Stable logsumexp:", stable_logsumexp(x))   # 1002.4076 (correct)

# Verify: mathematically identical for normal inputs
x2 = np.array([1.0, 2.0, 3.0])
print(f"naive={naive_logsumexp(x2):.6f}  stable={stable_logsumexp(x2):.6f}")

# PyTorch built-in (use this in production)
print("torch.logsumexp:", torch.logsumexp(torch.tensor(x), dim=0))  # 1002.4076

# Underflow: naive log-softmax fails for very negative logits
x_neg = np.array([-1000.0, -1001.0, -1002.0], dtype=np.float32)
print("\n--- Underflow demo ---")
print("np.exp(x_neg):", np.exp(x_neg))     # [0. 0. 0.] — all underflow to 0
print("naive log(sum(exp)):", np.log(np.sum(np.exp(x_neg))))  # -inf
print("stable_logsumexp:", stable_logsumexp(x_neg))  # -1000.4076 (correct)

# Numerically stable softmax
def stable_softmax(x):
    e = np.exp(x - np.max(x))
    return e / e.sum()

print("\n--- Stable softmax ---")
print("stable_softmax([1000,1001,1002]):", np.round(stable_softmax(x), 4))
```

## Numerically Stable Softmax and Log-Softmax

Stable softmax = subtract max before exponentiating:

softmax(x)ᵢ = exp(xᵢ − m) / Σⱼ exp(xⱼ − m),  m = max(x)

This is mathematically equivalent to the original because both numerator and denominator are multiplied by exp(−m), which cancels. The operation costs one additional pass over x (to find the maximum) but is entirely safe.

Stable log-softmax builds on stable logsumexp:

log softmax(x)ᵢ = xᵢ − logsumexp(x) = xᵢ − m − log Σⱼ exp(xⱼ − m)

Note that this is just subtraction — no exp on the output side, so no overflow or underflow on the final values. The only exp calls are in computing Σⱼ exp(xⱼ − m), which is safe because all arguments are ≤ 0.

Cross-entropy loss = NLL(log_softmax(logits), targets). PyTorch's F.cross_entropy combines both steps in a single numerically stable fused operation.

```python
import torch
import torch.nn.functional as F
import numpy as np

# Stable log-softmax from scratch
def stable_log_softmax(x):
    """log(exp(xi) / sum(exp(xj))) = xi - logsumexp(x)."""
    m = x.max()
    log_sum = m + np.log(np.sum(np.exp(x - m)))
    return x - log_sum

# Demonstration with extreme logits
logits_np = np.array([1000.0, 1001.0, 1002.0], dtype=np.float32)
logits_t  = torch.tensor(logits_np)

print("=== Log-Softmax Comparison ===")
# Naive: log(softmax(x)) — two-step, unstable
naive_sm  = np.exp(logits_np) / np.sum(np.exp(logits_np))  # inf/inf = nan
print("naive softmax:", naive_sm)

# Stable from scratch
print("stable log_softmax:", stable_log_softmax(logits_np))

# PyTorch F.log_softmax (stable by design)
print("F.log_softmax:", F.log_softmax(logits_t, dim=0).numpy())

# Cross-entropy: always use F.cross_entropy, not manual softmax -> log -> NLL
print("\n=== Cross-Entropy Stability ===")
batch_logits = torch.tensor([[1000.0, 1001.0, 1002.0]])
target       = torch.tensor([2])  # class 2 is correct

# WRONG: manual softmax -> log -> NLL
probs = torch.softmax(batch_logits, dim=1)  # [0, 0, nan] or similar
loss_wrong = -torch.log(probs[0, target[0]])
print(f"Wrong (softmax->log->NLL): {loss_wrong.item()}")  # nan or inf

# CORRECT: F.cross_entropy (fused stable operation)
loss_correct = F.cross_entropy(batch_logits, target)
print(f"Correct (F.cross_entropy): {loss_correct.item():.6f}")  # ~0.4076

# Verify: same result with normal logits
normal_logits = torch.tensor([[1.0, 2.0, 3.0]])
print("\nNormal logits comparison:")
print(f"  Manual:         {-torch.log(torch.softmax(normal_logits, dim=1)[0, 2]).item():.6f}")
print(f"  F.cross_entropy:{F.cross_entropy(normal_logits, target).item():.6f}")
```

## Variants and Special Cases

Log-domain arithmetic is needed whenever multiplying many probabilities, since products underflow rapidly. For a sequence of T tokens each with probability ~0.1, the joint probability is 0.1^T which underflows to 0 for T > 45 in fp32. Log-domain: sum log-probabilities instead.

Temperature scaling softmax(x/T):
- T < 1 (sharpening): divides by T < 1, which multiplies logit magnitudes by 1/T — making overflow more likely. Always apply the max-shift trick.
- T > 1 (softening): reduces logit magnitudes, less overflow risk.

log-sum-exp with two terms: log(exp(a) + exp(b)) = max(a,b) + log(1 + exp(−|a−b|)). This is the logaddexp function in numpy and log1p(exp(x)) for softplus. Both appear frequently in probabilistic models.

## Log-Domain HMM Forward Algorithm

The HMM forward algorithm computes the probability of an observed sequence by marginalizing over all hidden state sequences. The product of T emission and transition probabilities underflows to zero for long sequences. The log-domain forward algorithm maintains log α_t(s) = log P(x₁,...,xₜ, state_t = s) and performs all summations using logsumexp:

log α_t(s') = log P(xₜ | s') + logsumexp_s[log α_{t-1}(s) + log A(s→s')]

This is O(T × S²) in time (same as standard forward algorithm) but stable for sequences of any length.

```python
import numpy as np

def log_forward_hmm(log_emission, log_transition, log_init):
    """
    Log-domain HMM forward algorithm (numerically stable).
    log_emission:   (T, S) log P(x_t | state_s)
    log_transition: (S, S) log P(state_s' | state_s)
    log_init:       (S,)   log P(state_s at t=0)
    Returns: log P(observation sequence)
    """
    T, S = log_emission.shape
    log_alpha = log_init + log_emission[0]  # (S,) — init at t=0

    for t in range(1, T):
        # log_alpha[s'] = log sum_s exp(log_alpha[s] + log_A[s,s'])
        # Shape broadcast: log_alpha (S,1) + log_transition (S,S) -> (S,S)
        log_trans_contrib = log_alpha[:, None] + log_transition  # (S, S)
        log_alpha = np.logaddexp.reduce(log_trans_contrib, axis=0) + log_emission[t]

    # Total log probability: sum over final states
    return np.logaddexp.reduce(log_alpha)

# Demo: 3-state HMM, 50-step sequence
np.random.seed(42)
S, T = 3, 50
log_A = np.log(np.array([[0.7, 0.2, 0.1],
                           [0.1, 0.6, 0.3],
                           [0.2, 0.3, 0.5]]))
log_B = np.random.randn(T, S) - np.log(S)  # random emission log-probs
log_pi = np.log(np.ones(S) / S)

log_prob = log_forward_hmm(log_B, log_A, log_pi)
print(f"Log P(sequence): {log_prob:.4f}")
print(f"P(sequence) = exp({log_prob:.4f}) = {np.exp(log_prob):.4e}")
# Without log-domain, P would underflow to 0 for T=50 steps
```

## Pitfalls

Common mistakes with overflow/underflow:

1. **Manual softmax before log**: computing log(softmax(x)) in two steps instead of using log_softmax. The intermediate softmax may produce NaN that log then propagates.

2. **Forgetting max-shift when scaling**: dividing logits by temperature < 1 before softmax inflates magnitudes. Always apply temperature first, then use stable softmax.

3. **Using fp16 for attention without max-shift**: attention scores Q@K^T/√d can easily exceed 11 in fp16, causing overflow. Use bf16 or ensure FlashAttention's tiled softmax is active.

4. **Accumulating probabilities across tokens**: multiplying per-token probabilities instead of adding log-probabilities causes rapid underflow for sequences longer than ~50 tokens in fp32.

## Practical Guidance

Rules for numerically safe computation:

- **Always use F.cross_entropy** in PyTorch, never manual softmax → log → NLL.
- **Use torch.logsumexp** rather than implementing logsumexp manually.
- **In custom normalizing-flow implementations**, compute log-determinants as sums of log|diag(J)|, not products of |diag(J)|.
- **For beam search**, maintain log-probabilities and add per-step log-probs; only convert to probability for final output.
- **Validate with small test cases**: verify that naive and stable implementations agree on normal logits before testing on extreme inputs.

> **WARNING: Temperature < 1 Amplifies Overflow Risk**
>
> Temperature scaling computes softmax(x/T). For T < 1 (sharpening), logits are multiplied by 1/T, increasing their magnitude. With logits already near the fp32 overflow threshold (~88), dividing by T = 0.1 gives logits near 880 — certain overflow. Always apply the max-shift trick explicitly when using temperatures other than 1.0, or use F.softmax(logits / T) which does so internally.

> **TIP: Log-Domain Arithmetic for Long Sequences**
>
> When computing probability of a sequence (product of conditionals), always work in log-domain: add log-probabilities instead of multiplying probabilities. For N tokens each with probability ~0.1, joint probability 0.1^N underflows for N > 45 in fp32. In log-domain, N × log(0.1) ≈ −N × 2.303 remains perfectly representable for any N.

| Computation | Naive Failure | Stable Solution |
| --- | --- | --- |
| logsumexp(x) | exp overflow | m + log Σ exp(x-m), m=max(x) |
| softmax(x) | exp overflow → NaN | softmax(x - max(x)) |
| log_softmax(x) | log(0) when denominator underflows | x - logsumexp(x) |
| cross_entropy | chain of instabilities | F.cross_entropy (fused) |
| sequence probability | product underflows | sum of log-probs |
| HMM forward | α_t → 0 for long T | log-domain with logaddexp |

---

## Key Takeaways

- exp(x) overflows in fp32 for x > 88.72 and underflows to 0 for x < −87.34; fp16 thresholds are much tighter (±11).
- The log-sum-exp trick log Σ exp(xᵢ) = m + log Σ exp(xᵢ−m) with m = max(x) is mathematically identical but numerically safe.
- Stable softmax subtracts max before exponentiating; stable log-softmax computes xᵢ − logsumexp(x).
- Always use F.cross_entropy (PyTorch) — it fuses log_softmax + NLL in one stable operation.
- Temperature T < 1 amplifies logit magnitudes by 1/T, increasing overflow risk — always use the max-shift trick.
- For long sequences, maintain and accumulate log-probabilities instead of multiplying probabilities (which underflow past ~45 tokens in fp32).
- The log-domain forward algorithm (using logaddexp reductions) enables stable HMM inference over arbitrarily long sequences.
