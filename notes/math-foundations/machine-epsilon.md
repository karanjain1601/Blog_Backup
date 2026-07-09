---
title: "Machine Epsilon and Floating-Point Precision"
slug: "machine-epsilon"
description: "Machine epsilon definition, the relative error model, float equality pitfalls, Kahan compensated summation, and how floating-point precision constrains gradient computation in mixed-precision ML training."
tags: ["numerical-methods", "math", "foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type": "text", "content": "Machine epsilon is the fundamental precision limit of floating-point arithmetic. It determines the smallest relative difference that can be distinguished from zero, sets the floor for numerical differentiation step sizes, and quantifies the precision of gradient computations across every layer of a deep network. Understanding machine epsilon is essential for diagnosing numerical instabilities, choosing convergence tolerances, and reasoning about which operations can safely run in bf16 versus those that require fp32. Every practitioner building at scale will eventually hit a wall caused by insufficient numerical precision — understanding epsilon is the starting point for debugging such failures."}, {"type": "heading", "level": 2, "content": "Core Definition"}, {"type": "text", "content": "Machine epsilon (ε_mach) is the smallest positive floating-point number ε such that fl(1 + ε) > 1 — equivalently, the spacing between 1.0 and the next representable number. For a format with m mantissa bits:\n\nε_mach = 2^{−m}\n\nValues by format:\n- fp64 (double): ε = 2^{−52} ≈ 2.22×10⁻¹⁶  (53 significant bits)\n- fp32 (float):  ε = 2^{−23} ≈ 1.19×10⁻⁷  (24 significant bits)\n- fp16 (half):   ε = 2^{−10} ≈ 9.77×10⁻⁴  (11 significant bits)\n- bf16:          ε = 2^{−7}  ≈ 7.81×10⁻³  (8 significant bits)\n\nThe unit roundoff is ε_mach/2 — the maximum relative rounding error for any single IEEE 754 operation. Crucially, floating-point numbers are not uniformly spaced: they are denser near zero and sparser for large magnitudes. For a value x, the absolute spacing is approximately |x| × ε_mach, so precision is always measured in relative terms."}, {"type": "code", "language": "python", "content": "import numpy as np\nimport torch\n\n# Machine epsilon from numpy finfo\nprint(\"=== finfo values ===\")\nfor dtype in [np.float16, np.float32, np.float64]:\n    info = np.finfo(dtype)\n    print(f\"{dtype.__name__:10s}: eps={info.eps:.3e}  tiny={info.tiny:.3e}  max={info.max:.3e}\")\n\n# bfloat16 is torch-only\nprint()\nfor dtype in [torch.float16, torch.bfloat16, torch.float32, torch.float64]:\n    info = torch.finfo(dtype)\n    print(f\"{str(dtype):20s}: eps={info.eps:.3e}  bits={info.bits}\")\n\n# Empirically compute fp32 epsilon\nprint(\"\\n=== Empirical fp32 epsilon ===\")\neps = np.float32(1.0)\nwhile np.float32(1.0) + eps / np.float32(2.0) > np.float32(1.0):\n    eps = eps / np.float32(2.0)\nprint(f\"Empirical fp32 eps = {eps * 2:.6e}  (np.finfo = {np.finfo(np.float32).eps:.6e})\")\n\n# Non-uniform spacing: absolute precision depends on magnitude\nprint(\"\\n=== Spacing at Different Magnitudes (fp32) ===\")\nfor x_val in [0.5, 1.0, 16.0, 1024.0, 1e6]:\n    x = np.float32(x_val)\n    nxt = np.nextafter(x, np.float32(np.inf))\n    spacing = float(nxt - x)\n    print(f\"  x={x_val:>10g}: abs_spacing={spacing:.3e}  rel_spacing={spacing/x_val:.3e}\")\n# Observation: relative spacing ~constant (eps_mach), absolute spacing grows with x"}, {"type": "heading", "level": 2, "content": "The Relative Error Model"}, {"type": "text", "content": "The IEEE 754 standard guarantees that every correctly-rounded operation satisfies:\n\nfl(a ∘ b) = (a ∘ b)(1 + δ),  |δ| ≤ ε_mach/2\n\nThis holds for addition, subtraction, multiplication, division, and square root. It means every single floating-point operation introduces relative error at most ε_mach/2. For a computation involving N operations, accumulated error is at most N × ε_mach/2 in the worst case (all errors constructively reinforce), though in practice random cancellation reduces this to roughly √N × ε_mach/2.\n\nImplication for gradient computation: if gradient magnitudes are O(1), fp32 gradients are accurate to ~7 decimal places — more than sufficient. If gradients are very small (O(1e-6) or smaller), the relative error of fp16 can dominate. This is why fp32 master weights are maintained in mixed-precision training even when forward and backward passes run in bf16."}, {"type": "heading", "level": 2, "content": "Float Equality and Comparison"}, {"type": "text", "content": "Direct equality comparison (a == b) is almost never appropriate for floating-point values computed by different code paths. Because intermediate rounding errors accumulate differently, two mathematically identical computations can produce slightly different results. The classic example: 0.1 + 0.2 ≠ 0.3 in binary floating-point because none of these values are exactly representable.\n\nCorrect approach: check if |a − b| ≤ atol + rtol × |b| for appropriate tolerances. This is exactly what numpy.isclose and torch.isclose implement. For fp32 computations with ~100 operations, rtol=1e-4 and atol=1e-6 is a reasonable default. For bf16, rtol=1e-2 reflects the format's limited precision. For gradient checking (numerical vs analytical), use central differences with step h ≈ √ε_mach ≈ 1e-4 for fp32."}, {"type": "code", "language": "python", "content": "import numpy as np\nimport torch\n\n# Classic float equality failure\nprint(\"0.1 + 0.2 == 0.3:\", 0.1 + 0.2 == 0.3)   # False\nprint(f\"0.1 + 0.2 = {0.1 + 0.2:.17f}\")\nprint(f\"0.3       = {0.3:.17f}\")\n\n# Correct: tolerance-based comparison\nprint(\"np.isclose:\", np.isclose(0.1 + 0.2, 0.3))  # True\n# Formula: |a-b| <= atol + rtol * |b|\n\n# fp32 roundtrip through string vs computation\na = np.float32(1.0 / 3.0)\nb = np.float32(0.333333)\nprint(f\"\\n1/3 fp32={a:.8f}, 0.333333={b:.8f}, isclose={np.isclose(a, b, rtol=1e-4)}\")\n\n# torch.isclose for tensor comparison\nx = torch.tensor([1.0, 1.0 + 1e-7, 1000.0], dtype=torch.float32)\ny = torch.tensor([1.0, 1.0,         1000.0 + 1e-4], dtype=torch.float32)\nprint(\"torch.isclose (rtol=1e-4, atol=1e-6):\", torch.isclose(x, y, rtol=1e-4, atol=1e-6))\n\n# Optimal step for gradient checking: h = sqrt(eps_mach)\nfp32_eps = np.finfo(np.float32).eps\nh = np.sqrt(fp32_eps)\nprint(f\"\\nOptimal gradient-check step (fp32): h = sqrt({fp32_eps:.2e}) = {h:.4e}\")\n\ndef numerical_grad_central(f, x, h=1e-4):\n    return (f(x + h) - f(x - h)) / (2 * h)\n\nf = lambda x: x**3 - 2*x + 1\nprint(f\"Numerical grad of x^3-2x+1 at x=2: {numerical_grad_central(f, 2.0):.8f}\")\nprint(f\"Analytical (3x^2-2) at x=2:         {3*4 - 2:.8f}\")"}, {"type": "heading", "level": 2, "content": "Kahan Compensated Summation"}, {"type": "text", "content": "Naive sequential summation accumulates O(n × ε_mach) error: each addition introduces a small rounding error that grows with n. For n = 10 million fp32 additions, the worst-case accumulated error is ~1.19. The Kahan compensated summation algorithm reduces this to O(ε_mach) independent of n by tracking the low-order bits discarded in each addition.\n\nThe algorithm maintains a compensation variable c. At each step:\n- y = xᵢ − c   (adjust input by accumulated error)\n- t = total + y  (add adjusted value)\n- c = (t − total) − y  (capture bits lost when adding y to total)\n- total = t\n\nThe key insight: (t − total) recovers what was actually added to total (not exactly y due to rounding), so (t − total) − y captures the rounding error. NumPy's built-in sum uses pairwise summation, achieving O(log n × ε_mach) — better than naive but worse than Kahan."}, {"type": "code", "language": "python", "content": "import numpy as np\n\ndef naive_sum(arr):\n    \"\"\"Sequential summation — O(n * eps) accumulated error.\"\"\"\n    total = arr.dtype.type(0.0)\n    for x in arr:\n        total += x\n    return float(total)\n\ndef kahan_sum(arr):\n    \"\"\"Kahan compensated summation — O(eps) error independent of n.\"\"\"\n    total = arr.dtype.type(0.0)\n    comp  = arr.dtype.type(0.0)\n    for x in arr:\n        y     = x - comp        # corrected addend\n        t     = total + y       # provisional sum\n        comp  = (t - total) - y # new compensation (bits lost)\n        total = t\n    return float(total)\n\n# Compare on 10M fp32 values\nn = 10_000_000\nrng = np.random.default_rng(42)\nvals_f32 = rng.standard_normal(n).astype(np.float32)\ntrue_sum = float(np.sum(vals_f32.astype(np.float64)))  # fp64 ground truth\n\nnaive  = naive_sum(vals_f32)\nkahan  = kahan_sum(vals_f32)\nnp_sum = float(np.sum(vals_f32))   # pairwise summation\n\nprint(f\"True sum (fp64): {true_sum:.8f}\")\nprint(f\"Naive fp32:  error={abs(naive  - true_sum):.3e}\")\nprint(f\"Kahan fp32:  error={abs(kahan  - true_sum):.3e}\")\nprint(f\"np.sum fp32: error={abs(np_sum - true_sum):.3e}\")\n\n# Error scaling with n\nprint(\"\\n--- Error growth vs n (all-ones * 1e-7) ---\")\nfor n_t in [100, 10_000, 1_000_000]:\n    v = np.ones(n_t, dtype=np.float32) * np.float32(1e-7)\n    true_v = n_t * 1e-7\n    ne = abs(naive_sum(v) - true_v); ke = abs(kahan_sum(v) - true_v)\n    print(f\"  n={n_t:>9,}: naive_err={ne:.2e}  kahan_err={ke:.2e}\")"}, {"type": "heading", "level": 2, "content": "ML and AI Connections"}, {"type": "text", "content": "In deep learning, floating-point precision affects every computation stage differently. The forward pass is usually fine in bf16 because LayerNorm and residual connections keep activations in a healthy range. The backward pass is more sensitive: gradients must survive many matrix multiplications, and vanishing gradients compound precision loss. Loss scaling (used in AMP/FSDP training) multiplies the loss by a large factor (e.g., 2^15 = 32768) before backward, shifting small gradients into the representable fp16 range, then divides the recovered gradients before the optimizer step.\n\nAttention is particularly sensitive: Q@K^T values can become large for high model dimensions, causing overflow in fp16 (but not bf16, which has the same exponent range as fp32). FlashAttention addresses this by computing softmax in tiles with online normalization, keeping intermediate values in registers and avoiding materialization of the full attention matrix in lower-precision formats."}, {"type": "code", "language": "python", "content": "import numpy as np\nimport torch\n\n# Mixed precision dot product error analysis\nprint(\"=== Dot product precision analysis (n=1024) ===\")\nn = 1024\nrng = np.random.default_rng(42)\na = rng.standard_normal(n).astype(np.float32)\nb = rng.standard_normal(n).astype(np.float32)\ntrue_dot = float(np.dot(a.astype(np.float64), b.astype(np.float64)))\n\na_t, b_t = torch.tensor(a), torch.tensor(b)\nresults = {\n    \"fp32\": float(torch.dot(a_t, b_t)),\n    \"bf16 (fp32 acc)\": float(torch.dot(a_t.bfloat16().float(), b_t.bfloat16().float())),\n    \"fp16 (fp32 acc)\": float(torch.dot(a_t.half().float(), b_t.half().float())),\n    \"bf16 acc\": float(torch.dot(a_t.bfloat16(), b_t.bfloat16())),\n}\nfor name, val in results.items():\n    print(f\"  {name:20s}: {val:.6f}  rel_err={abs(val-true_dot)/abs(true_dot):.2e}\")\n\n# Loss scaling simulation (AMP)\nprint(\"\\n=== Loss Scaling (AMP) ===\")\ntiny_grad = torch.tensor(1e-6, dtype=torch.float16)\nscale = 2**15\nscaled = tiny_grad * scale\nprint(f\"Tiny grad fp16: {float(tiny_grad):.4e}\")\nprint(f\"Scaled by {scale}: {float(scaled):.4e}\")\nprint(f\"Unscaled: {float(scaled / scale):.4e}\")\n\n# Accumulation error in iterative algorithm\nprint(\"\\n=== Iterative accumulation error ===\")\nx_fp32 = np.float32(0.0)\nfor _ in range(10000): x_fp32 += np.float32(0.0001)\nx_fp64 = sum(0.0001 for _ in range(10000))\nprint(f\"fp64 reference: {x_fp64:.10f}\")\nprint(f\"fp32 result:    {float(x_fp32):.10f}  error={abs(float(x_fp32)-x_fp64):.3e}\")"}, {"type": "heading", "level": 2, "content": "Pitfalls"}, {"type": "text", "content": "The most common floating-point pitfalls in ML code:\n\n1. **Catastrophic cancellation**: subtracting nearly equal numbers destroys significant digits. Computing variance as E[X²] − E[X]² can lose all precision when the mean is large relative to the standard deviation.\n\n2. **Order-of-operations sensitivity**: (a + b) + c ≠ a + (b + c) in floating-point. GPU reduction kernels may produce different results depending on thread ordering — this is expected and usually benign.\n\n3. **Convergence checks with exact equality**: while loss != prev_loss can loop forever or terminate early. Always use tolerance-based convergence: |loss − prev| < tol.\n\n4. **Mixing magnitudes**: adding 1e8 and 1e-8 in fp32 loses the small term entirely — it falls within machine epsilon of the large term and gets absorbed as rounding noise."}, {"type": "heading", "level": 2, "content": "Practical Guidance"}, {"type": "text", "content": "Concrete rules for floating-point precision in ML systems:\n\n- **Gradient checking**: central differences (f(x+h) − f(x−h))/(2h) with h = √ε_mach ≈ 1e-4 for fp32. Expect rtol ≈ 1e-4 for agreement.\n- **Convergence tests**: use |loss − prev_loss| < rtol × |prev_loss| + atol, never exact equality.\n- **Mixed-precision training**: keep Adam m1/m2 and master weights in fp32; forward/backward in bf16; loss and attention accumulation in fp32.\n- **High-precision reductions**: prefer numpy's built-in sum (pairwise) over naive loops; use Kahan summation for very high accuracy requirements.\n- **Testing numerical correctness**: torch.testing.assert_close(a, b, rtol=1e-4, atol=1e-6) for fp32; rtol=1e-2 for bf16."}, {"type": "callout", "variant": "warning", "title": "Precision is Magnitude-Relative", "content": "Machine epsilon is a relative precision: the absolute precision at value x is |x| × ε_mach. At x = 10⁶ in fp32, absolute precision ≈ 0.119 — no decimal places at all. Operations that simultaneously involve very large and very small numbers are especially prone to catastrophic cancellation. Normalize inputs to a sensible range before performing sensitive operations."}, {"type": "table", "headers": ["Format", "Mantissa bits", "ε_mach", "Safe ML use"], "rows": [["fp64", "52", "2.22e-16", "Ground truth, numerical testing"], ["fp32", "23", "1.19e-7", "Optimizer state, master weights, loss"], ["fp16", "10", "9.77e-4", "Tensor Core compute (limited exponent range)"], ["bf16", "7", "7.81e-3", "Forward/backward pass (full fp32 exponent range)"]]}, {"type": "divider"}, {"type": "heading", "level": 2, "content": "Key Takeaways"}, {"type": "list", "ordered": false, "items": ["ε_mach = 2^{-m} for m mantissa bits; fp32 ε ≈ 1.19e-7, bf16 ε ≈ 7.81e-3.", "Every IEEE 754 operation introduces relative error ≤ ε_mach/2; N operations accumulate ≤ N × ε_mach/2 worst case.", "Floating-point numbers are not uniformly spaced — absolute spacing scales as |x| × ε_mach.", "Never use == for float comparison; use np.isclose or torch.isclose with explicit rtol and atol.", "Kahan compensated summation reduces error from O(n × ε) to O(ε) independent of n — critical for high-precision reductions.", "In mixed-precision training, bf16 is safe for forward/backward because mini-batch gradient noise dominates numerical precision error; fp32 is required for optimizer state and master weights.", "For gradient checking, use central differences with h ≈ √ε_mach; for stable variance, use Welford's online algorithm rather than E[X²] − E[X]²."]}]"
---
# Machine Epsilon and Floating-Point Precision

Machine epsilon is the fundamental precision limit of floating-point arithmetic. It determines the smallest relative difference that can be distinguished from zero, sets the floor for numerical differentiation step sizes, and quantifies the precision of gradient computations across every layer of a deep network. Understanding machine epsilon is essential for diagnosing numerical instabilities, choosing convergence tolerances, and reasoning about which operations can safely run in bf16 versus those that require fp32. Every practitioner building at scale will eventually hit a wall caused by insufficient numerical precision — understanding epsilon is the starting point for debugging such failures.

## Core Definition

Machine epsilon (ε_mach) is the smallest positive floating-point number ε such that fl(1 + ε) > 1 — equivalently, the spacing between 1.0 and the next representable number. For a format with m mantissa bits:

ε_mach = 2^{−m}

Values by format:
- fp64 (double): ε = 2^{−52} ≈ 2.22×10⁻¹⁶  (53 significant bits)
- fp32 (float):  ε = 2^{−23} ≈ 1.19×10⁻⁷  (24 significant bits)
- fp16 (half):   ε = 2^{−10} ≈ 9.77×10⁻⁴  (11 significant bits)
- bf16:          ε = 2^{−7}  ≈ 7.81×10⁻³  (8 significant bits)

The unit roundoff is ε_mach/2 — the maximum relative rounding error for any single IEEE 754 operation. Crucially, floating-point numbers are not uniformly spaced: they are denser near zero and sparser for large magnitudes. For a value x, the absolute spacing is approximately |x| × ε_mach, so precision is always measured in relative terms.

```python
import numpy as np
import torch

# Machine epsilon from numpy finfo
print("=== finfo values ===")
for dtype in [np.float16, np.float32, np.float64]:
    info = np.finfo(dtype)
    print(f"{dtype.__name__:10s}: eps={info.eps:.3e}  tiny={info.tiny:.3e}  max={info.max:.3e}")

# bfloat16 is torch-only
print()
for dtype in [torch.float16, torch.bfloat16, torch.float32, torch.float64]:
    info = torch.finfo(dtype)
    print(f"{str(dtype):20s}: eps={info.eps:.3e}  bits={info.bits}")

# Empirically compute fp32 epsilon
print("\n=== Empirical fp32 epsilon ===")
eps = np.float32(1.0)
while np.float32(1.0) + eps / np.float32(2.0) > np.float32(1.0):
    eps = eps / np.float32(2.0)
print(f"Empirical fp32 eps = {eps * 2:.6e}  (np.finfo = {np.finfo(np.float32).eps:.6e})")

# Non-uniform spacing: absolute precision depends on magnitude
print("\n=== Spacing at Different Magnitudes (fp32) ===")
for x_val in [0.5, 1.0, 16.0, 1024.0, 1e6]:
    x = np.float32(x_val)
    nxt = np.nextafter(x, np.float32(np.inf))
    spacing = float(nxt - x)
    print(f"  x={x_val:>10g}: abs_spacing={spacing:.3e}  rel_spacing={spacing/x_val:.3e}")
# Observation: relative spacing ~constant (eps_mach), absolute spacing grows with x
```

## The Relative Error Model

The IEEE 754 standard guarantees that every correctly-rounded operation satisfies:

fl(a ∘ b) = (a ∘ b)(1 + δ),  |δ| ≤ ε_mach/2

This holds for addition, subtraction, multiplication, division, and square root. It means every single floating-point operation introduces relative error at most ε_mach/2. For a computation involving N operations, accumulated error is at most N × ε_mach/2 in the worst case (all errors constructively reinforce), though in practice random cancellation reduces this to roughly √N × ε_mach/2.

Implication for gradient computation: if gradient magnitudes are O(1), fp32 gradients are accurate to ~7 decimal places — more than sufficient. If gradients are very small (O(1e-6) or smaller), the relative error of fp16 can dominate. This is why fp32 master weights are maintained in mixed-precision training even when forward and backward passes run in bf16.

## Float Equality and Comparison

Direct equality comparison (a == b) is almost never appropriate for floating-point values computed by different code paths. Because intermediate rounding errors accumulate differently, two mathematically identical computations can produce slightly different results. The classic example: 0.1 + 0.2 ≠ 0.3 in binary floating-point because none of these values are exactly representable.

Correct approach: check if |a − b| ≤ atol + rtol × |b| for appropriate tolerances. This is exactly what numpy.isclose and torch.isclose implement. For fp32 computations with ~100 operations, rtol=1e-4 and atol=1e-6 is a reasonable default. For bf16, rtol=1e-2 reflects the format's limited precision. For gradient checking (numerical vs analytical), use central differences with step h ≈ √ε_mach ≈ 1e-4 for fp32.

```python
import numpy as np
import torch

# Classic float equality failure
print("0.1 + 0.2 == 0.3:", 0.1 + 0.2 == 0.3)   # False
print(f"0.1 + 0.2 = {0.1 + 0.2:.17f}")
print(f"0.3       = {0.3:.17f}")

# Correct: tolerance-based comparison
print("np.isclose:", np.isclose(0.1 + 0.2, 0.3))  # True
# Formula: |a-b| <= atol + rtol * |b|

# fp32 roundtrip through string vs computation
a = np.float32(1.0 / 3.0)
b = np.float32(0.333333)
print(f"\n1/3 fp32={a:.8f}, 0.333333={b:.8f}, isclose={np.isclose(a, b, rtol=1e-4)}")

# torch.isclose for tensor comparison
x = torch.tensor([1.0, 1.0 + 1e-7, 1000.0], dtype=torch.float32)
y = torch.tensor([1.0, 1.0,         1000.0 + 1e-4], dtype=torch.float32)
print("torch.isclose (rtol=1e-4, atol=1e-6):", torch.isclose(x, y, rtol=1e-4, atol=1e-6))

# Optimal step for gradient checking: h = sqrt(eps_mach)
fp32_eps = np.finfo(np.float32).eps
h = np.sqrt(fp32_eps)
print(f"\nOptimal gradient-check step (fp32): h = sqrt({fp32_eps:.2e}) = {h:.4e}")

def numerical_grad_central(f, x, h=1e-4):
    return (f(x + h) - f(x - h)) / (2 * h)

f = lambda x: x**3 - 2*x + 1
print(f"Numerical grad of x^3-2x+1 at x=2: {numerical_grad_central(f, 2.0):.8f}")
print(f"Analytical (3x^2-2) at x=2:         {3*4 - 2:.8f}")
```

## Kahan Compensated Summation

Naive sequential summation accumulates O(n × ε_mach) error: each addition introduces a small rounding error that grows with n. For n = 10 million fp32 additions, the worst-case accumulated error is ~1.19. The Kahan compensated summation algorithm reduces this to O(ε_mach) independent of n by tracking the low-order bits discarded in each addition.

The algorithm maintains a compensation variable c. At each step:
- y = xᵢ − c   (adjust input by accumulated error)
- t = total + y  (add adjusted value)
- c = (t − total) − y  (capture bits lost when adding y to total)
- total = t

The key insight: (t − total) recovers what was actually added to total (not exactly y due to rounding), so (t − total) − y captures the rounding error. NumPy's built-in sum uses pairwise summation, achieving O(log n × ε_mach) — better than naive but worse than Kahan.

```python
import numpy as np

def naive_sum(arr):
    """Sequential summation — O(n * eps) accumulated error."""
    total = arr.dtype.type(0.0)
    for x in arr:
        total += x
    return float(total)

def kahan_sum(arr):
    """Kahan compensated summation — O(eps) error independent of n."""
    total = arr.dtype.type(0.0)
    comp  = arr.dtype.type(0.0)
    for x in arr:
        y     = x - comp        # corrected addend
        t     = total + y       # provisional sum
        comp  = (t - total) - y # new compensation (bits lost)
        total = t
    return float(total)

# Compare on 10M fp32 values
n = 10_000_000
rng = np.random.default_rng(42)
vals_f32 = rng.standard_normal(n).astype(np.float32)
true_sum = float(np.sum(vals_f32.astype(np.float64)))  # fp64 ground truth

naive  = naive_sum(vals_f32)
kahan  = kahan_sum(vals_f32)
np_sum = float(np.sum(vals_f32))   # pairwise summation

print(f"True sum (fp64): {true_sum:.8f}")
print(f"Naive fp32:  error={abs(naive  - true_sum):.3e}")
print(f"Kahan fp32:  error={abs(kahan  - true_sum):.3e}")
print(f"np.sum fp32: error={abs(np_sum - true_sum):.3e}")

# Error scaling with n
print("\n--- Error growth vs n (all-ones * 1e-7) ---")
for n_t in [100, 10_000, 1_000_000]:
    v = np.ones(n_t, dtype=np.float32) * np.float32(1e-7)
    true_v = n_t * 1e-7
    ne = abs(naive_sum(v) - true_v); ke = abs(kahan_sum(v) - true_v)
    print(f"  n={n_t:>9,}: naive_err={ne:.2e}  kahan_err={ke:.2e}")
```

## ML and AI Connections

In deep learning, floating-point precision affects every computation stage differently. The forward pass is usually fine in bf16 because LayerNorm and residual connections keep activations in a healthy range. The backward pass is more sensitive: gradients must survive many matrix multiplications, and vanishing gradients compound precision loss. Loss scaling (used in AMP/FSDP training) multiplies the loss by a large factor (e.g., 2^15 = 32768) before backward, shifting small gradients into the representable fp16 range, then divides the recovered gradients before the optimizer step.

Attention is particularly sensitive: Q@K^T values can become large for high model dimensions, causing overflow in fp16 (but not bf16, which has the same exponent range as fp32). FlashAttention addresses this by computing softmax in tiles with online normalization, keeping intermediate values in registers and avoiding materialization of the full attention matrix in lower-precision formats.

```python
import numpy as np
import torch

# Mixed precision dot product error analysis
print("=== Dot product precision analysis (n=1024) ===")
n = 1024
rng = np.random.default_rng(42)
a = rng.standard_normal(n).astype(np.float32)
b = rng.standard_normal(n).astype(np.float32)
true_dot = float(np.dot(a.astype(np.float64), b.astype(np.float64)))

a_t, b_t = torch.tensor(a), torch.tensor(b)
results = {
    "fp32": float(torch.dot(a_t, b_t)),
    "bf16 (fp32 acc)": float(torch.dot(a_t.bfloat16().float(), b_t.bfloat16().float())),
    "fp16 (fp32 acc)": float(torch.dot(a_t.half().float(), b_t.half().float())),
    "bf16 acc": float(torch.dot(a_t.bfloat16(), b_t.bfloat16())),
}
for name, val in results.items():
    print(f"  {name:20s}: {val:.6f}  rel_err={abs(val-true_dot)/abs(true_dot):.2e}")

# Loss scaling simulation (AMP)
print("\n=== Loss Scaling (AMP) ===")
tiny_grad = torch.tensor(1e-6, dtype=torch.float16)
scale = 2**15
scaled = tiny_grad * scale
print(f"Tiny grad fp16: {float(tiny_grad):.4e}")
print(f"Scaled by {scale}: {float(scaled):.4e}")
print(f"Unscaled: {float(scaled / scale):.4e}")

# Accumulation error in iterative algorithm
print("\n=== Iterative accumulation error ===")
x_fp32 = np.float32(0.0)
for _ in range(10000): x_fp32 += np.float32(0.0001)
x_fp64 = sum(0.0001 for _ in range(10000))
print(f"fp64 reference: {x_fp64:.10f}")
print(f"fp32 result:    {float(x_fp32):.10f}  error={abs(float(x_fp32)-x_fp64):.3e}")
```

## Pitfalls

The most common floating-point pitfalls in ML code:

1. **Catastrophic cancellation**: subtracting nearly equal numbers destroys significant digits. Computing variance as E[X²] − E[X]² can lose all precision when the mean is large relative to the standard deviation.

2. **Order-of-operations sensitivity**: (a + b) + c ≠ a + (b + c) in floating-point. GPU reduction kernels may produce different results depending on thread ordering — this is expected and usually benign.

3. **Convergence checks with exact equality**: while loss != prev_loss can loop forever or terminate early. Always use tolerance-based convergence: |loss − prev| < tol.

4. **Mixing magnitudes**: adding 1e8 and 1e-8 in fp32 loses the small term entirely — it falls within machine epsilon of the large term and gets absorbed as rounding noise.

## Practical Guidance

Concrete rules for floating-point precision in ML systems:

- **Gradient checking**: central differences (f(x+h) − f(x−h))/(2h) with h = √ε_mach ≈ 1e-4 for fp32. Expect rtol ≈ 1e-4 for agreement.
- **Convergence tests**: use |loss − prev_loss| < rtol × |prev_loss| + atol, never exact equality.
- **Mixed-precision training**: keep Adam m1/m2 and master weights in fp32; forward/backward in bf16; loss and attention accumulation in fp32.
- **High-precision reductions**: prefer numpy's built-in sum (pairwise) over naive loops; use Kahan summation for very high accuracy requirements.
- **Testing numerical correctness**: torch.testing.assert_close(a, b, rtol=1e-4, atol=1e-6) for fp32; rtol=1e-2 for bf16.

> **WARNING: Precision is Magnitude-Relative**
>
> Machine epsilon is a relative precision: the absolute precision at value x is |x| × ε_mach. At x = 10⁶ in fp32, absolute precision ≈ 0.119 — no decimal places at all. Operations that simultaneously involve very large and very small numbers are especially prone to catastrophic cancellation. Normalize inputs to a sensible range before performing sensitive operations.

| Format | Mantissa bits | ε_mach | Safe ML use |
| --- | --- | --- | --- |
| fp64 | 52 | 2.22e-16 | Ground truth, numerical testing |
| fp32 | 23 | 1.19e-7 | Optimizer state, master weights, loss |
| fp16 | 10 | 9.77e-4 | Tensor Core compute (limited exponent range) |
| bf16 | 7 | 7.81e-3 | Forward/backward pass (full fp32 exponent range) |

---

## Key Takeaways

- ε_mach = 2^{-m} for m mantissa bits; fp32 ε ≈ 1.19e-7, bf16 ε ≈ 7.81e-3.
- Every IEEE 754 operation introduces relative error ≤ ε_mach/2; N operations accumulate ≤ N × ε_mach/2 worst case.
- Floating-point numbers are not uniformly spaced — absolute spacing scales as |x| × ε_mach.
- Never use == for float comparison; use np.isclose or torch.isclose with explicit rtol and atol.
- Kahan compensated summation reduces error from O(n × ε) to O(ε) independent of n — critical for high-precision reductions.
- In mixed-precision training, bf16 is safe for forward/backward because mini-batch gradient noise dominates numerical precision error; fp32 is required for optimizer state and master weights.
- For gradient checking, use central differences with h ≈ √ε_mach; for stable variance, use Welford's online algorithm rather than E[X²] − E[X]².
