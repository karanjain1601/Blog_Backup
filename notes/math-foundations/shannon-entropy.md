---
title: "Shannon Entropy"
slug: "shannon-entropy"
description: "Entropy definition, units, bounds, and its role as the information-theoretic foundation of compression and ML loss functions."
tags: ["information-theory","math","foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[
  {"type":"text","content":"Shannon entropy, introduced by Claude Shannon in 1948, is the foundational measure of uncertainty in information theory. It quantifies the average number of bits required to encode outcomes of a random variable and sets the theoretical floor for lossless compression. Every cross-entropy loss, perplexity metric, and mutual information calculation in ML traces directly back to H(X) = -sum p(x) log p(x). Understanding entropy means understanding why training loss floors exist, why label smoothing works, and what perplexity actually measures."},
  {"type":"heading","level":2,"content":"Core Definition"},
  {"type":"text","content":"For a discrete random variable X with PMF p(x) over alphabet X, Shannon entropy is H(X) = -sum_{x} p(x) log p(x) = E[-log p(X)]. The term -log p(x) is the self-information of event x: rare events carry large self-information, certain events carry zero. Entropy is therefore the expected surprise of the distribution. Convention: 0 * log 0 = 0 (justified by continuity). Log base determines units: base-2 gives bits, natural log gives nats (PyTorch default), base-10 gives hartleys. Conversion: 1 nat = log2(e) approximately 1.4427 bits."},
  {"type":"code","language":"python","content":"import numpy as np\nfrom scipy.stats import entropy as scipy_entropy\n\ndef entropy_bits(probs):\n    # Shannon entropy in bits; 0*log(0)=0 by convention\n    p = np.asarray(probs, dtype=np.float64)\n    mask = p > 0\n    return float(-np.sum(p[mask] * np.log2(p[mask])))\n\ndef softmax_entropy_bits(logits):\n    # Entropy of softmax distribution (in bits)\n    logits = np.array(logits, dtype=float)\n    logits -= logits.max()  # numeric stability\n    probs = np.exp(logits) / np.exp(logits).sum()\n    return entropy_bits(probs)\n\nprint(entropy_bits([0.25, 0.25, 0.25, 0.25]))   # 2.000  uniform 4-class\nprint(entropy_bits([1.0, 0.0, 0.0, 0.0]))        # 0.000  deterministic\nprint(entropy_bits([0.9, 0.1]))                   # 0.469  Bernoulli(0.9)\nprint(scipy_entropy([0.25]*4) / np.log(2))        # 2.000  scipy nats to bits\nprint(softmax_entropy_bits([10.0, 0.0, 0.0]))     # ~0.005 confident\nprint(softmax_entropy_bits([0.1, 0.0, -0.1]))     # ~1.585 uncertain"},
  {"type":"heading","level":2,"content":"Mathematical Properties"},
  {"type":"text","content":"Non-negativity: H(X) >= 0; equality iff X is deterministic (one outcome has p=1). Maximum entropy: H(X) <= log|X|, achieved uniquely by the uniform distribution. Concavity: H is concave in the probability vector, so mixing distributions increases entropy. Binary entropy H_b(p) = -p log p - (1-p) log(1-p) is concave and symmetric, peaks at 1 bit for p=0.5, vanishes at p in {0,1}. Shannon axiomatic derivation (1948): entropy is the unique function satisfying continuity in all p_i, symmetry under outcome permutation, maximality at uniform, and the chain rule H(X,Y)=H(X)+H(Y|X). Subadditivity: H(X,Y) <= H(X)+H(Y) with equality iff X and Y are independent."},
  {"type":"code","language":"python","content":"import numpy as np\n\ndef binary_entropy(p):\n    # H_b(p) in bits for Bernoulli(p)\n    p = np.clip(p, 1e-15, 1 - 1e-15)\n    return -(p * np.log2(p) + (1-p) * np.log2(1-p))\n\ndef entropy_bits(probs):\n    p = np.asarray(probs, dtype=float)\n    mask = p > 0\n    return float(-np.sum(p[mask] * np.log2(p[mask])))\n\n# Binary entropy function properties\nps = np.linspace(0.001, 0.999, 1000)\nhbs = binary_entropy(ps)\nprint(f'Max H_b = {hbs.max():.4f} bits at p = {ps[hbs.argmax()]:.4f}')\nprint(f'H_b(0.1) = {binary_entropy(0.1):.4f} bits')\nprint(f'H_b(0.5) = {binary_entropy(0.5):.4f} bits')\n\n# Uniform maximizes entropy: compare uniform vs skewed distributions\nfor k in [2, 4, 8, 16]:\n    p_uni  = np.ones(k) / k\n    p_skew = np.array([0.9] + [0.1/(k-1)]*(k-1))\n    h_uni  = entropy_bits(p_uni)\n    h_skew = entropy_bits(p_skew)\n    print(f'k={k:2d}: H(uniform)={h_uni:.3f}  H(skewed)={h_skew:.3f}')"},
  {"type":"heading","level":2,"content":"Variants and Special Cases"},
  {"type":"text","content":"Differential entropy h(X) = -integral f(x) log f(x) dx extends entropy to continuous distributions but can be negative: h(Uniform[0, eps]) = log(eps) goes to -inf as eps approaches 0. It is not reparametrization-invariant: h(aX) = h(X) + log|a|. Only differences like mutual information carry absolute meaning. Gaussian N(mu, sigma^2) maximizes h for fixed variance: h = 0.5 * log(2*pi*e*sigma^2). Entropy rate h = lim H(X1,...,Xn)/n characterizes stationary processes; empirically English text runs at about 1.0-1.5 bits per character versus a theoretical maximum of log2(27) ~= 4.75 bits per character."},
  {"type":"heading","level":2,"content":"ML and AI Connections"},
  {"type":"text","content":"Shannon source coding theorem: no lossless code averages fewer than H(X) bits per symbol; Huffman codes achieve L < H(X)+1. The cross-entropy decomposition H(p,q) = H(p) + KL(p||q) splits training loss into an irreducible floor set by data noise and a reducible KL term. For noisy labels the floor is positive regardless of model capacity. Perplexity PPL = exp(H(p,q)) estimates the effective branching factor; typical LLMs achieve PPL 5-20. Predictive entropy serves as an uncertainty signal for active learning and OOD detection: high entropy predictions flag model uncertainty. Entropy also drives decision tree information gain and variational autoencoder KL regularization."},
  {"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nimport numpy as np\n\ndef predictive_entropy_nats(logits):\n    # Predictive entropy in nats from logit tensor (B, K)\n    probs  = F.softmax(logits, dim=-1)\n    log_p  = F.log_softmax(logits, dim=-1)\n    return -(probs * log_p).sum(dim=-1)  # (B,)\n\ndef cross_entropy_decomposition(true_probs, model_log_probs):\n    # H(p,q) = H(p) + KL(p||q)\n    p     = torch.tensor(true_probs, dtype=torch.float64)\n    log_q = torch.tensor(model_log_probs, dtype=torch.float64)\n    H_p   = -(p * torch.log(p + 1e-10)).sum().item()\n    KL    = (p * (torch.log(p + 1e-10) - log_q)).sum().item()\n    return H_p, KL, H_p + KL\n\n# Varying confidence: confident, uniform, mild\nlogits = torch.tensor([[10.0, 0.1, 0.1], [1.0, 1.0, 1.0], [3.0, 2.5, 2.0]])\nH = predictive_entropy_nats(logits)\nfor i, h in enumerate(H):\n    print(f'Sample {i}: H = {h.item():.4f} nats')\n\n# Noisy-label floor: 80% class 0, 20% class 1\nH_p, KL, H_pq = cross_entropy_decomposition([0.8, 0.2], [-0.22, -1.61])\nprint(f'Irreducible loss floor H(p) = {H_p:.4f} nats')"},
  {"type":"heading","level":2,"content":"Implementation Pitfalls"},
  {"type":"text","content":"Handle 0*log(0)=0 explicitly: masking zero-probability entries before computing p*log(p) avoids -inf. Never compute softmax then log separately — the combination loses precision for large logits; use F.log_softmax or F.cross_entropy which apply the log-sum-exp trick internally. Log base confusion: scipy.stats.entropy uses nats by default; divide by np.log(2) to convert to bits. Empirical entropy from small samples is biased upward because rare events are underrepresented — apply the Miller-Madow correction H_hat + (m-1)/(2N) where m is the number of observed bins and N is total sample count."},
  {"type":"heading","level":2,"content":"Practical Guidance"},
  {"type":"text","content":"Use predictive entropy to flag uncertain samples during inference: threshold at 0.5 * log2(K) bits to catch near-uniform predictions. Track training cross-entropy minus the theoretical H(p) floor to measure actual learning progress rather than absolute loss values. For class-imbalanced datasets, compute per-class entropy to verify whether the model has learned minority classes or collapsed to the majority. Always validate entropy implementations by checking that entropy_bits([1/K]*K) returns log2(K) before using in production code."},
  {"type":"code","language":"python","content":"import numpy as np\n\ndef entropy_bits_safe(probs, base=2):\n    # Production-safe: validates inputs, handles zero probabilities\n    p = np.asarray(probs, dtype=np.float64)\n    if not np.allclose(p.sum(), 1.0, atol=1e-6):\n        raise ValueError(f'Probs sum to {p.sum():.6f}, expected 1.0')\n    if np.any(p < 0):\n        raise ValueError('Negative probabilities detected')\n    mask = p > 0\n    raw = -np.sum(p[mask] * np.log(p[mask]))\n    return float(raw / np.log(base))\n\ndef ood_flag(logits, k_classes, threshold=0.5):\n    # Flag OOD if predictive entropy > threshold * max_entropy\n    logits = np.asarray(logits, dtype=float)\n    logits -= logits.max()\n    probs = np.exp(logits) / np.exp(logits).sum()\n    h = entropy_bits_safe(probs)\n    max_h = np.log2(k_classes)\n    return h > threshold * max_h, round(h, 4)\n\nprint(ood_flag([8.0, 0.0, 0.0], k_classes=3))   # (False, low entropy)\nprint(ood_flag([1.1, 1.0, 0.9], k_classes=3))   # (True,  high entropy)"},
  {"type":"callout","variant":"warning","title":"Entropy Floor Is Irreducible","content":"H(p,q) = H(p) + KL(p||q). The H(p) term is fixed by the data distribution and cannot be reduced by any model regardless of size or training duration. For datasets with label noise or inherent class ambiguity, training loss will plateau above zero. Before attributing a training plateau to underfitting, compute H(p_empirical) from your label distribution to determine whether the floor is irreducible noise or a genuine capacity problem."},
  {"type":"table","headers":["Distribution","H (bits)","Interpretation"],"rows":[["Deterministic","0.00","Perfect certainty, no surprise"],["Bernoulli(0.9)","0.47","Imbalanced binary outcome"],["Fair coin","1.00","Maximum 1-bit uncertainty"],["Uniform 8-class","3.00","8-class classification ceiling"],["Uniform 50k vocab","~15.6","LLM token upper bound"],["English characters (empirical)","~1.2","Shannon 1951 estimate"]]},
  {"type":"divider"},
  {"type":"heading","level":2,"content":"Key Takeaways"},
  {"type":"list","ordered":false,"items":["H(X) = E[-log p(X)] — entropy is average surprise; base-2 log gives bits, natural log gives nats","Uniform distribution uniquely maximizes entropy for a fixed alphabet size; deterministic distributions give H=0","Shannon source coding theorem: H(X) is the tight lower bound on average code length for any lossless compression scheme","Cross-entropy H(p,q) = H(p) + KL(p||q): training only reduces KL; H(p) is the irreducible floor set by data","Differential entropy can be negative and is not reparametrization-invariant — only differences like mutual information are meaningful","Predictive entropy is a principled uncertainty signal for OOD detection, active learning, and calibration monitoring","Always check log base before comparing entropy values across libraries or papers — nats and bits differ by factor log2(e)"]}
]
"
---
# Shannon Entropy

Shannon entropy, introduced by Claude Shannon in 1948, is the foundational measure of uncertainty in information theory. It quantifies the average number of bits required to encode outcomes of a random variable and sets the theoretical floor for lossless compression. Every cross-entropy loss, perplexity metric, and mutual information calculation in ML traces directly back to H(X) = -sum p(x) log p(x). Understanding entropy means understanding why training loss floors exist, why label smoothing works, and what perplexity actually measures.

## Core Definition

For a discrete random variable X with PMF p(x) over alphabet X, Shannon entropy is H(X) = -sum_{x} p(x) log p(x) = E[-log p(X)]. The term -log p(x) is the self-information of event x: rare events carry large self-information, certain events carry zero. Entropy is therefore the expected surprise of the distribution. Convention: 0 * log 0 = 0 (justified by continuity). Log base determines units: base-2 gives bits, natural log gives nats (PyTorch default), base-10 gives hartleys. Conversion: 1 nat = log2(e) approximately 1.4427 bits.

```python
import numpy as np
from scipy.stats import entropy as scipy_entropy

def entropy_bits(probs):
    # Shannon entropy in bits; 0*log(0)=0 by convention
    p = np.asarray(probs, dtype=np.float64)
    mask = p > 0
    return float(-np.sum(p[mask] * np.log2(p[mask])))

def softmax_entropy_bits(logits):
    # Entropy of softmax distribution (in bits)
    logits = np.array(logits, dtype=float)
    logits -= logits.max()  # numeric stability
    probs = np.exp(logits) / np.exp(logits).sum()
    return entropy_bits(probs)

print(entropy_bits([0.25, 0.25, 0.25, 0.25]))   # 2.000  uniform 4-class
print(entropy_bits([1.0, 0.0, 0.0, 0.0]))        # 0.000  deterministic
print(entropy_bits([0.9, 0.1]))                   # 0.469  Bernoulli(0.9)
print(scipy_entropy([0.25]*4) / np.log(2))        # 2.000  scipy nats to bits
print(softmax_entropy_bits([10.0, 0.0, 0.0]))     # ~0.005 confident
print(softmax_entropy_bits([0.1, 0.0, -0.1]))     # ~1.585 uncertain
```

## Mathematical Properties

Non-negativity: H(X) >= 0; equality iff X is deterministic (one outcome has p=1). Maximum entropy: H(X) <= log|X|, achieved uniquely by the uniform distribution. Concavity: H is concave in the probability vector, so mixing distributions increases entropy. Binary entropy H_b(p) = -p log p - (1-p) log(1-p) is concave and symmetric, peaks at 1 bit for p=0.5, vanishes at p in {0,1}. Shannon axiomatic derivation (1948): entropy is the unique function satisfying continuity in all p_i, symmetry under outcome permutation, maximality at uniform, and the chain rule H(X,Y)=H(X)+H(Y|X). Subadditivity: H(X,Y) <= H(X)+H(Y) with equality iff X and Y are independent.

```python
import numpy as np

def binary_entropy(p):
    # H_b(p) in bits for Bernoulli(p)
    p = np.clip(p, 1e-15, 1 - 1e-15)
    return -(p * np.log2(p) + (1-p) * np.log2(1-p))

def entropy_bits(probs):
    p = np.asarray(probs, dtype=float)
    mask = p > 0
    return float(-np.sum(p[mask] * np.log2(p[mask])))

# Binary entropy function properties
ps = np.linspace(0.001, 0.999, 1000)
hbs = binary_entropy(ps)
print(f'Max H_b = {hbs.max():.4f} bits at p = {ps[hbs.argmax()]:.4f}')
print(f'H_b(0.1) = {binary_entropy(0.1):.4f} bits')
print(f'H_b(0.5) = {binary_entropy(0.5):.4f} bits')

# Uniform maximizes entropy: compare uniform vs skewed distributions
for k in [2, 4, 8, 16]:
    p_uni  = np.ones(k) / k
    p_skew = np.array([0.9] + [0.1/(k-1)]*(k-1))
    h_uni  = entropy_bits(p_uni)
    h_skew = entropy_bits(p_skew)
    print(f'k={k:2d}: H(uniform)={h_uni:.3f}  H(skewed)={h_skew:.3f}')
```

## Variants and Special Cases

Differential entropy h(X) = -integral f(x) log f(x) dx extends entropy to continuous distributions but can be negative: h(Uniform[0, eps]) = log(eps) goes to -inf as eps approaches 0. It is not reparametrization-invariant: h(aX) = h(X) + log|a|. Only differences like mutual information carry absolute meaning. Gaussian N(mu, sigma^2) maximizes h for fixed variance: h = 0.5 * log(2*pi*e*sigma^2). Entropy rate h = lim H(X1,...,Xn)/n characterizes stationary processes; empirically English text runs at about 1.0-1.5 bits per character versus a theoretical maximum of log2(27) ~= 4.75 bits per character.

## ML and AI Connections

Shannon source coding theorem: no lossless code averages fewer than H(X) bits per symbol; Huffman codes achieve L < H(X)+1. The cross-entropy decomposition H(p,q) = H(p) + KL(p||q) splits training loss into an irreducible floor set by data noise and a reducible KL term. For noisy labels the floor is positive regardless of model capacity. Perplexity PPL = exp(H(p,q)) estimates the effective branching factor; typical LLMs achieve PPL 5-20. Predictive entropy serves as an uncertainty signal for active learning and OOD detection: high entropy predictions flag model uncertainty. Entropy also drives decision tree information gain and variational autoencoder KL regularization.

```python
import torch
import torch.nn.functional as F
import numpy as np

def predictive_entropy_nats(logits):
    # Predictive entropy in nats from logit tensor (B, K)
    probs  = F.softmax(logits, dim=-1)
    log_p  = F.log_softmax(logits, dim=-1)
    return -(probs * log_p).sum(dim=-1)  # (B,)

def cross_entropy_decomposition(true_probs, model_log_probs):
    # H(p,q) = H(p) + KL(p||q)
    p     = torch.tensor(true_probs, dtype=torch.float64)
    log_q = torch.tensor(model_log_probs, dtype=torch.float64)
    H_p   = -(p * torch.log(p + 1e-10)).sum().item()
    KL    = (p * (torch.log(p + 1e-10) - log_q)).sum().item()
    return H_p, KL, H_p + KL

# Varying confidence: confident, uniform, mild
logits = torch.tensor([[10.0, 0.1, 0.1], [1.0, 1.0, 1.0], [3.0, 2.5, 2.0]])
H = predictive_entropy_nats(logits)
for i, h in enumerate(H):
    print(f'Sample {i}: H = {h.item():.4f} nats')

# Noisy-label floor: 80% class 0, 20% class 1
H_p, KL, H_pq = cross_entropy_decomposition([0.8, 0.2], [-0.22, -1.61])
print(f'Irreducible loss floor H(p) = {H_p:.4f} nats')
```

## Implementation Pitfalls

Handle 0*log(0)=0 explicitly: masking zero-probability entries before computing p*log(p) avoids -inf. Never compute softmax then log separately — the combination loses precision for large logits; use F.log_softmax or F.cross_entropy which apply the log-sum-exp trick internally. Log base confusion: scipy.stats.entropy uses nats by default; divide by np.log(2) to convert to bits. Empirical entropy from small samples is biased upward because rare events are underrepresented — apply the Miller-Madow correction H_hat + (m-1)/(2N) where m is the number of observed bins and N is total sample count.

## Practical Guidance

Use predictive entropy to flag uncertain samples during inference: threshold at 0.5 * log2(K) bits to catch near-uniform predictions. Track training cross-entropy minus the theoretical H(p) floor to measure actual learning progress rather than absolute loss values. For class-imbalanced datasets, compute per-class entropy to verify whether the model has learned minority classes or collapsed to the majority. Always validate entropy implementations by checking that entropy_bits([1/K]*K) returns log2(K) before using in production code.

```python
import numpy as np

def entropy_bits_safe(probs, base=2):
    # Production-safe: validates inputs, handles zero probabilities
    p = np.asarray(probs, dtype=np.float64)
    if not np.allclose(p.sum(), 1.0, atol=1e-6):
        raise ValueError(f'Probs sum to {p.sum():.6f}, expected 1.0')
    if np.any(p < 0):
        raise ValueError('Negative probabilities detected')
    mask = p > 0
    raw = -np.sum(p[mask] * np.log(p[mask]))
    return float(raw / np.log(base))

def ood_flag(logits, k_classes, threshold=0.5):
    # Flag OOD if predictive entropy > threshold * max_entropy
    logits = np.asarray(logits, dtype=float)
    logits -= logits.max()
    probs = np.exp(logits) / np.exp(logits).sum()
    h = entropy_bits_safe(probs)
    max_h = np.log2(k_classes)
    return h > threshold * max_h, round(h, 4)

print(ood_flag([8.0, 0.0, 0.0], k_classes=3))   # (False, low entropy)
print(ood_flag([1.1, 1.0, 0.9], k_classes=3))   # (True,  high entropy)
```

> **WARNING: Entropy Floor Is Irreducible**
> H(p,q) = H(p) + KL(p||q). The H(p) term is fixed by the data distribution and cannot be reduced by any model regardless of size or training duration. For datasets with label noise or inherent class ambiguity, training loss will plateau above zero. Before attributing a training plateau to underfitting, compute H(p_empirical) from your label distribution to determine whether the floor is irreducible noise or a genuine capacity problem.

| Distribution | H (bits) | Interpretation |
|---|---|---|
| Deterministic | 0.00 | Perfect certainty, no surprise |
| Bernoulli(0.9) | 0.47 | Imbalanced binary outcome |
| Fair coin | 1.00 | Maximum 1-bit uncertainty |
| Uniform 8-class | 3.00 | 8-class classification ceiling |
| Uniform 50k vocab | ~15.6 | LLM token upper bound |
| English characters (empirical) | ~1.2 | Shannon 1951 estimate |

---

## Key Takeaways

- H(X) = E[-log p(X)] — entropy is average surprise; base-2 log gives bits, natural log gives nats
- Uniform distribution uniquely maximizes entropy for a fixed alphabet size; deterministic distributions give H=0
- Shannon source coding theorem: H(X) is the tight lower bound on average code length for any lossless compression scheme
- Cross-entropy H(p,q) = H(p) + KL(p||q): training only reduces KL; H(p) is the irreducible floor set by data
- Differential entropy can be negative and is not reparametrization-invariant — only differences like mutual information are meaningful
- Predictive entropy is a principled uncertainty signal for OOD detection, active learning, and calibration monitoring
- Always check log base before comparing entropy values across libraries or papers — nats and bits differ by factor log2(e)