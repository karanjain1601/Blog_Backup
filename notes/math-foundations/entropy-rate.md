---
title: "Entropy Rate and Information in Sequences"
slug: "entropy-rate"
description: "Entropy rate characterizes the irreducible uncertainty per symbol in a stochastic process. Covers Markov chains, language model perplexity, bits-per-byte, and Lempel-Ziv complexity."
tags: ["information-theory", "math", "foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"A single random variable has entropy H(X). But real-world data — text, audio, time series — is a *sequence* of random variables with temporal structure. The entropy rate captures how much genuine uncertainty exists per symbol once we account for all the patterns and dependencies in the sequence."},{"type":"heading","level":2,"content":"Definition of Entropy Rate"},{"type":"text","content":"For a stochastic process {Xₙ}, the entropy rate is defined as the limit:\n\nh = lim_{n→∞} (1/n) H(X₁, X₂, ..., Xₙ)\n\nprovided the limit exists. For a *stationary* process, this limit always exists and equals the conditional entropy rate:\n\nh = lim_{n→∞} H(Xₙ | X_{n-1}, ..., X₁)\n\nThe conditional form says: as we observe more context, the per-symbol uncertainty decreases monotonically and converges to h."},{"type":"callout","variant":"info","title":"Why the Limit Exists for Stationary Processes","content":"For a stationary process, H(Xₙ|X_{n-1},...,X₁) is non-increasing in n (more context never increases entropy) and bounded below by 0. By the monotone convergence theorem the limit exists. This is a consequence of the chain rule and sub-additivity of entropy."},{"type":"heading","level":2,"content":"Special Cases and Examples"},{"type":"table","headers":["Process Type","Entropy Rate Formula","Example","Rate (bits/symbol)"],"rows":[["i.i.d. uniform binary","H(X₁) = log₂(2) = 1","Fair coin flips","1.0"],["i.i.d. biased binary","H(X₁) = −p log p − (1−p) log(1−p)","Biased coin (p=0.1)","≈ 0.47"],["i.i.d. uniform over alphabet A","log₂(|A|)","Uniform die rolls (6-sided)","≈ 2.58"],["First-order Markov chain","−Σᵢ πᵢ Σⱼ Pᵢⱼ log Pᵢⱼ","Weather model","\u003c H(X₁)"],["Natural English text","Shannon experiment estimate","Written English","≈ 1.0–1.3"],["Random (incompressible)","H(X₁) = max entropy","True random bits","= log₂(|A|)"]]},{"type":"heading","level":2,"content":"Entropy Rate of a Markov Chain"},{"type":"text","content":"For an ergodic, time-homogeneous Markov chain with transition matrix P and stationary distribution π, the entropy rate has a closed form:\n\nh = −Σᵢ πᵢ Σⱼ Pᵢⱼ log Pᵢⱼ = Σᵢ πᵢ H(Xₙ | Xₙ₋₁=i)\n\nThis is the stationary-distribution-weighted average of the conditional entropy at each state. A highly predictable chain (near-deterministic transitions) has h ≈ 0; a fully random chain has h = log|A|."},{"type":"code","language":"python","content":"import numpy as np\nfrom scipy.linalg import eig\n\ndef markov_entropy_rate(P: np.ndarray, base: float = 2.0) -\u003e float:\n    \"\"\"Compute entropy rate of a finite ergodic Markov chain.\n\n    Args:\n        P: Transition matrix, shape (n_states, n_states). Rows sum to 1.\n        base: Logarithm base (2 = bits, e = nats).\n    Returns:\n        Entropy rate h in specified units.\n    \"\"\"\n    n = P.shape[0]\n    assert np.allclose(P.sum(axis=1), 1.0), \"Rows must sum to 1\"\n\n    # Stationary distribution: left eigenvector for eigenvalue 1\n    # Equivalently, solve π P = π with Σ πᵢ = 1\n    eigenvalues, eigenvectors = eig(P.T)\n    stationary_idx = np.argmin(np.abs(eigenvalues - 1.0))\n    pi = np.real(eigenvectors[:, stationary_idx])\n    pi = pi / pi.sum()  # normalize\n\n    # Compute h = -Σᵢ πᵢ Σⱼ Pᵢⱼ log Pᵢⱼ\n    log_fn = np.log if base == np.e else (lambda x: np.log(x) / np.log(base))\n    row_entropies = np.array([\n        -np.sum(P[i, P[i] \u003e 0] * log_fn(P[i, P[i] \u003e 0]))\n        for i in range(n)\n    ])\n    h = np.dot(pi, row_entropies)\n\n    print(f\"Stationary distribution π: {pi}\")\n    print(f\"Per-state conditional entropies: {row_entropies}\")\n    print(f\"Entropy rate h = {h:.6f} {\u0027bits\u0027 if base==2 else \u0027nats\u0027}/symbol\")\n    return h\n\n# Example: 3-state weather Markov chain\n#   States: 0=sunny, 1=cloudy, 2=rainy\nP = np.array([\n    [0.7, 0.2, 0.1],\n    [0.3, 0.4, 0.3],\n    [0.2, 0.3, 0.5]\n])\nmarkov_entropy_rate(P, base=2)"},{"type":"heading","level":2,"content":"Empirical Entropy Rate of Text"},{"type":"text","content":"Shannon famously estimated English text has an entropy rate of about 1 bit/character through human prediction experiments. We can approximate this computationally by estimating conditional entropy H(Xₙ|Xₙ₋ₖ,...,Xₙ₋₁) using sliding windows of increasing context length k. As k grows, the estimate approaches the true entropy rate."},{"type":"code","language":"python","content":"import numpy as np\nfrom collections import Counter, defaultdict\nfrom math import log2\nfrom typing import Dict, Tuple\n\ndef empirical_conditional_entropy(text: str, context_len: int) -\u003e float:\n    \"\"\"Estimate H(Xₙ | context of length context_len) from text.\n\n    Uses maximum-likelihood (frequency) estimates of conditional probabilities.\n    Returns entropy in bits/character.\n    \"\"\"\n    if context_len == 0:\n        # Marginal entropy\n        counts = Counter(text)\n        total = len(text)\n        probs = np.array([v / total for v in counts.values()])\n        return -np.sum(probs * np.log2(probs))\n\n    # Count transitions: context → next_char\n    context_counts: Dict[str, int] = defaultdict(int)\n    transition_counts: Dict[Tuple[str, str], int] = defaultdict(int)\n\n    for i in range(len(text) - context_len):\n        ctx = text[i:i + context_len]\n        nxt = text[i + context_len]\n        context_counts[ctx] += 1\n        transition_counts[(ctx, nxt)] += 1\n\n    # H(X|context) = Σ_{ctx} P(ctx) H(X|ctx=c)\n    total = sum(context_counts.values())\n    h_cond = 0.0\n    for ctx, ctx_count in context_counts.items():\n        p_ctx = ctx_count / total\n        # Conditional distribution over next chars\n        next_chars = {nxt: transition_counts[(ctx, nxt)] for nxt in set(c for (c2, c) in transition_counts if c2 == ctx)}\n        n_ctx = sum(next_chars.values())\n        h_ctx = -sum((c / n_ctx) * log2(c / n_ctx) for c in next_chars.values() if c \u003e 0)\n        h_cond += p_ctx * h_ctx\n\n    return h_cond\n\n# Download a small sample of text\nsample = \"\"\"the entropy rate of english text is approximately one bit per character\nwhen conditioning on sufficient context this was estimated by claude shannon\nusing human prediction experiments in the 1950s the result shows that english\ntext has enormous redundancy compared to the theoretical maximum\"\"\"\n\nprint(\"Context length → Estimated H(X|context) [bits/char]\")\nfor k in [0, 1, 2, 3, 4]:\n    h = empirical_conditional_entropy(sample, k)\n    print(f\"  k={k}: {h:.4f} bits/char\")"},{"type":"heading","level":2,"content":"Language Model Perplexity and Entropy Rate"},{"type":"text","content":"A language model assigns probability p_model(x₁,...,xₙ) to sequences. The cross-entropy of the model on the true data distribution is:\n\nH(p_true, p_model) = -E_{x~p_true}[log p_model(x)]\n\nFor a *perfect* model (p_model = p_true), cross-entropy equals the true entropy rate. Perplexity is PPL = 2^{cross-entropy} — the geometric mean number of equally likely choices the model sees at each token. A model matching the true entropy rate of English (~1 bit/char ≈ ~2-3 bits/token) would have PPL ≈ 4-8 on character-level tasks."},{"type":"code","language":"python","content":"import numpy as np\nfrom transformers import AutoTokenizer, AutoModelForCausalLM\nimport torch\nfrom typing import List\n\ndef compute_entropy_rate_and_perplexity(\n    texts: List[str],\n    model_name: str = \"gpt2\",\n    stride: int = 512\n) -\u003e dict:\n    \"\"\"Compute perplexity and estimate entropy rate from an LLM.\n\n    Uses stride-based approach to handle long texts without boundary artifacts.\n    \"\"\"\n    tokenizer = AutoTokenizer.from_pretrained(model_name)\n    model = AutoModelForCausalLM.from_pretrained(model_name)\n    model.eval()\n\n    total_log_prob = 0.0\n    total_tokens = 0\n    total_chars = sum(len(t) for t in texts)\n\n    with torch.no_grad():\n        for text in texts:\n            encodings = tokenizer(text, return_tensors=\"pt\")\n            input_ids = encodings.input_ids  # shape (1, T)\n            T = input_ids.shape[1]\n            max_len = model.config.n_positions\n\n            for begin in range(0, T, stride):\n                end = min(begin + max_len, T)\n                tgt_begin = max(begin, begin + max_len - stride)  # only score new tokens\n                chunk = input_ids[:, begin:end]\n                target_len = end - tgt_begin\n\n                outputs = model(chunk, labels=chunk)\n                # outputs.loss is mean NLL over all tokens in chunk\n                # We need to weight by target tokens only — simplified here\n                log_prob = -outputs.loss.item() * (end - begin)\n                total_log_prob += log_prob * (target_len / (end - begin))\n                total_tokens += target_len\n\n    cross_entropy_bits = -total_log_prob / total_tokens / np.log(2)\n    ppl = 2 ** cross_entropy_bits\n    avg_chars_per_token = total_chars / total_tokens\n    bpb = cross_entropy_bits / avg_chars_per_token  # bits-per-byte\n\n    return {\n        \"cross_entropy_bits_per_token\": cross_entropy_bits,\n        \"perplexity\": ppl,\n        \"bits_per_byte\": bpb,\n        \"entropy_rate_estimate_bits_per_char\": bpb\n    }\n\n# Usage (requires transformers + a downloaded model)\n# results = compute_entropy_rate_and_perplexity([\"example text here\"])\n# print(results)"},{"type":"heading","level":2,"content":"Lempel-Ziv Complexity and Entropy Rate"},{"type":"text","content":"The Lempel-Ziv algorithm (LZ77/LZ78) is a universal data compressor: without knowing the source statistics, it converges to the entropy rate as sequence length increases. This makes compression ratio a model-free estimator of entropy rate. The LZ76 complexity c(x) of a string x grows as c(x) ~ n/(log n) · h, where h is the entropy rate."},{"type":"callout","variant":"tip","title":"Bits-per-Byte (BPB) as a Universal Metric","content":"BPB = log₂(PPL) / avg_chars_per_token makes perplexity comparable across models with different tokenizers. GPT-4 tokenizer produces ~4 chars/token while LLaMA SentencePiece produces ~3.5 chars/token — so raw PPL numbers are incomparable, but BPB values are directly comparable."},{"type":"code","language":"python","content":"import gzip\nimport zlib\nimport bz2\nimport lzma\nimport struct\nfrom typing import Dict\n\ndef compression_vs_entropy_bound(\n    text: str,\n    entropy_rate_bits_per_char: float\n) -\u003e Dict[str, dict]:\n    \"\"\"Compare actual compression ratios vs the entropy rate lower bound.\n\n    Shannon\u0027s source coding theorem says the best lossless compressor\n    achieves exactly h bits/char. We compare standard algorithms to this bound.\n\n    Args:\n        text: Input text to compress.\n        entropy_rate_bits_per_char: Estimated entropy rate (e.g., 1.0 for English).\n    Returns:\n        Dict with compression statistics per method.\n    \"\"\"\n    data = text.encode(\u0027utf-8\u0027)\n    original_bytes = len(data)\n    original_bits_per_char = 8.0  # UTF-8 baseline: 8 bits/char (ASCII chars)\n\n    methods = {\n        \u0027gzip-1 (fast)\u0027: gzip.compress(data, compresslevel=1),\n        \u0027gzip-9 (best)\u0027: gzip.compress(data, compresslevel=9),\n        \u0027zlib-6 (default)\u0027: zlib.compress(data, level=6),\n        \u0027bz2 (block)\u0027: bz2.compress(data),\n        \u0027lzma (xz)\u0027: lzma.compress(data),\n    }\n\n    entropy_bound_bytes = len(text) * entropy_rate_bits_per_char / 8.0\n    print(f\"Original text: {len(text)} chars, {original_bytes} bytes\")\n    print(f\"Entropy bound @ h={entropy_rate_bits_per_char} b/char: {entropy_bound_bytes:.1f} bytes\")\n    print(f\"\\n{\u0027Method\u0027:\u003c20} {\u0027Compressed\u0027:\u003e12} {\u0027Bits/char\u0027:\u003e10} {\u0027vs bound\u0027:\u003e10}\")\n    print(\"-\" * 55)\n\n    results = {}\n    for name, compressed in methods.items():\n        n_bytes = len(compressed)\n        bits_per_char = (n_bytes * 8) / len(text)\n        gap_pct = 100 * (bits_per_char - entropy_rate_bits_per_char) / entropy_rate_bits_per_char\n        print(f\"{name:\u003c20} {n_bytes:\u003e12} {bits_per_char:\u003e10.3f} {gap_pct:\u003e+9.1f}%\")\n        results[name] = {\u0027compressed_bytes\u0027: n_bytes, \u0027bits_per_char\u0027: bits_per_char}\n\n    return results\n\n# English text sample (entropy rate ≈ 1.0-1.3 bits/char empirically)\nsample = (\"the quick brown fox jumps over the lazy dog \" * 50 +\n          \"information theory and entropy rate of english \" * 30)\ncompression_vs_entropy_bound(sample, entropy_rate_bits_per_char=1.2)"},{"type":"heading","level":2,"content":"Source Coding Theorem Connection"},{"type":"text","content":"Shannon\u0027s source coding theorem states that for a stationary ergodic source with entropy rate h, the optimal lossless compression achieves exactly h bits/symbol — no more, no less. Any code achieving fewer than h bits/symbol must have non-zero error probability; any code using more than h bits/symbol is wasting capacity. This is why entropy rate is both a theoretical limit and a practical benchmark for compression algorithms and language models."},{"type":"divider"},{"type":"text","content":"Entropy rate is the fingerprint of a stochastic process: i.i.d. sources have maximum entropy rate (no exploitable patterns), while structured processes like natural language have rates far below the alphabet maximum. Language model perplexity is the empirical entropy rate of the model\u0027s distribution on a test corpus — minimizing it is equivalent to finding a model whose distribution matches the true data distribution as closely as possible."}]"
---
# Entropy Rate and Information in Sequences

A single random variable has entropy H(X). But real-world data — text, audio, time series — is a *sequence* of random variables with temporal structure. The entropy rate captures how much genuine uncertainty exists per symbol once we account for all the patterns and dependencies in the sequence.

## Definition of Entropy Rate

For a stochastic process {Xₙ}, the entropy rate is defined as the limit:

h = lim_{n→∞} (1/n) H(X₁, X₂, ..., Xₙ)

provided the limit exists. For a *stationary* process, this limit always exists and equals the conditional entropy rate:

h = lim_{n→∞} H(Xₙ | X_{n-1}, ..., X₁)

The conditional form says: as we observe more context, the per-symbol uncertainty decreases monotonically and converges to h.

> **Why the Limit Exists for Stationary Processes**: For a stationary process, H(Xₙ|X_{n-1},...,X₁) is non-increasing in n (more context never increases entropy) and bounded below by 0. By the monotone convergence theorem the limit exists. This is a consequence of the chain rule and sub-additivity of entropy.

## Special Cases and Examples

| Process Type | Entropy Rate Formula | Example | Rate (bits/symbol) |
| --- | --- | --- | --- |
| i.i.d. uniform binary | H(X₁) = log₂(2) = 1 | Fair coin flips | 1.0 |
| i.i.d. biased binary | H(X₁) = −p log p − (1−p) log(1−p) | Biased coin (p=0.1) | ≈ 0.47 |
| i.i.d. uniform over alphabet A | log₂(|A|) | Uniform die rolls (6-sided) | ≈ 2.58 |
| First-order Markov chain | −Σᵢ πᵢ Σⱼ Pᵢⱼ log Pᵢⱼ | Weather model | < H(X₁) |
| Natural English text | Shannon experiment estimate | Written English | ≈ 1.0–1.3 |
| Random (incompressible) | H(X₁) = max entropy | True random bits | = log₂(|A|) |

## Entropy Rate of a Markov Chain

For an ergodic, time-homogeneous Markov chain with transition matrix P and stationary distribution π, the entropy rate has a closed form:

h = −Σᵢ πᵢ Σⱼ Pᵢⱼ log Pᵢⱼ = Σᵢ πᵢ H(Xₙ | Xₙ₋₁=i)

This is the stationary-distribution-weighted average of the conditional entropy at each state. A highly predictable chain (near-deterministic transitions) has h ≈ 0; a fully random chain has h = log|A|.

```python
import numpy as np
from scipy.linalg import eig

def markov_entropy_rate(P: np.ndarray, base: float = 2.0) -> float:
    """Compute entropy rate of a finite ergodic Markov chain.

    Args:
        P: Transition matrix, shape (n_states, n_states). Rows sum to 1.
        base: Logarithm base (2 = bits, e = nats).
    Returns:
        Entropy rate h in specified units.
    """
    n = P.shape[0]
    assert np.allclose(P.sum(axis=1), 1.0), "Rows must sum to 1"

    # Stationary distribution: left eigenvector for eigenvalue 1
    # Equivalently, solve π P = π with Σ πᵢ = 1
    eigenvalues, eigenvectors = eig(P.T)
    stationary_idx = np.argmin(np.abs(eigenvalues - 1.0))
    pi = np.real(eigenvectors[:, stationary_idx])
    pi = pi / pi.sum()  # normalize

    # Compute h = -Σᵢ πᵢ Σⱼ Pᵢⱼ log Pᵢⱼ
    log_fn = np.log if base == np.e else (lambda x: np.log(x) / np.log(base))
    row_entropies = np.array([
        -np.sum(P[i, P[i] > 0] * log_fn(P[i, P[i] > 0]))
        for i in range(n)
    ])
    h = np.dot(pi, row_entropies)

    print(f"Stationary distribution π: {pi}")
    print(f"Per-state conditional entropies: {row_entropies}")
    print(f"Entropy rate h = {h:.6f} {'bits' if base==2 else 'nats'}/symbol")
    return h

# Example: 3-state weather Markov chain
#   States: 0=sunny, 1=cloudy, 2=rainy
P = np.array([
    [0.7, 0.2, 0.1],
    [0.3, 0.4, 0.3],
    [0.2, 0.3, 0.5]
])
markov_entropy_rate(P, base=2)
```

## Empirical Entropy Rate of Text

Shannon famously estimated English text has an entropy rate of about 1 bit/character through human prediction experiments. We can approximate this computationally by estimating conditional entropy H(Xₙ|Xₙ₋ₖ,...,Xₙ₋₁) using sliding windows of increasing context length k. As k grows, the estimate approaches the true entropy rate.

```python
import numpy as np
from collections import Counter, defaultdict
from math import log2
from typing import Dict, Tuple

def empirical_conditional_entropy(text: str, context_len: int) -> float:
    """Estimate H(Xₙ | context of length context_len) from text.

    Uses maximum-likelihood (frequency) estimates of conditional probabilities.
    Returns entropy in bits/character.
    """
    if context_len == 0:
        # Marginal entropy
        counts = Counter(text)
        total = len(text)
        probs = np.array([v / total for v in counts.values()])
        return -np.sum(probs * np.log2(probs))

    # Count transitions: context → next_char
    context_counts: Dict[str, int] = defaultdict(int)
    transition_counts: Dict[Tuple[str, str], int] = defaultdict(int)

    for i in range(len(text) - context_len):
        ctx = text[i:i + context_len]
        nxt = text[i + context_len]
        context_counts[ctx] += 1
        transition_counts[(ctx, nxt)] += 1

    # H(X|context) = Σ_{ctx} P(ctx) H(X|ctx=c)
    total = sum(context_counts.values())
    h_cond = 0.0
    for ctx, ctx_count in context_counts.items():
        p_ctx = ctx_count / total
        # Conditional distribution over next chars
        next_chars = {nxt: transition_counts[(ctx, nxt)] for nxt in set(c for (c2, c) in transition_counts if c2 == ctx)}
        n_ctx = sum(next_chars.values())
        h_ctx = -sum((c / n_ctx) * log2(c / n_ctx) for c in next_chars.values() if c > 0)
        h_cond += p_ctx * h_ctx

    return h_cond

# Download a small sample of text
sample = """the entropy rate of english text is approximately one bit per character
when conditioning on sufficient context this was estimated by claude shannon
using human prediction experiments in the 1950s the result shows that english
text has enormous redundancy compared to the theoretical maximum"""

print("Context length → Estimated H(X|context) [bits/char]")
for k in [0, 1, 2, 3, 4]:
    h = empirical_conditional_entropy(sample, k)
    print(f"  k={k}: {h:.4f} bits/char")
```

## Language Model Perplexity and Entropy Rate

A language model assigns probability p_model(x₁,...,xₙ) to sequences. The cross-entropy of the model on the true data distribution is:

H(p_true, p_model) = -E_{x~p_true}[log p_model(x)]

For a *perfect* model (p_model = p_true), cross-entropy equals the true entropy rate. Perplexity is PPL = 2^{cross-entropy} — the geometric mean number of equally likely choices the model sees at each token. A model matching the true entropy rate of English (~1 bit/char ≈ ~2-3 bits/token) would have PPL ≈ 4-8 on character-level tasks.

```python
import numpy as np
from transformers import AutoTokenizer, AutoModelForCausalLM
import torch
from typing import List

def compute_entropy_rate_and_perplexity(
    texts: List[str],
    model_name: str = "gpt2",
    stride: int = 512
) -> dict:
    """Compute perplexity and estimate entropy rate from an LLM.

    Uses stride-based approach to handle long texts without boundary artifacts.
    """
    tokenizer = AutoTokenizer.from_pretrained(model_name)
    model = AutoModelForCausalLM.from_pretrained(model_name)
    model.eval()

    total_log_prob = 0.0
    total_tokens = 0
    total_chars = sum(len(t) for t in texts)

    with torch.no_grad():
        for text in texts:
            encodings = tokenizer(text, return_tensors="pt")
            input_ids = encodings.input_ids  # shape (1, T)
            T = input_ids.shape[1]
            max_len = model.config.n_positions

            for begin in range(0, T, stride):
                end = min(begin + max_len, T)
                tgt_begin = max(begin, begin + max_len - stride)  # only score new tokens
                chunk = input_ids[:, begin:end]
                target_len = end - tgt_begin

                outputs = model(chunk, labels=chunk)
                # outputs.loss is mean NLL over all tokens in chunk
                # We need to weight by target tokens only — simplified here
                log_prob = -outputs.loss.item() * (end - begin)
                total_log_prob += log_prob * (target_len / (end - begin))
                total_tokens += target_len

    cross_entropy_bits = -total_log_prob / total_tokens / np.log(2)
    ppl = 2 ** cross_entropy_bits
    avg_chars_per_token = total_chars / total_tokens
    bpb = cross_entropy_bits / avg_chars_per_token  # bits-per-byte

    return {
        "cross_entropy_bits_per_token": cross_entropy_bits,
        "perplexity": ppl,
        "bits_per_byte": bpb,
        "entropy_rate_estimate_bits_per_char": bpb
    }

# Usage (requires transformers + a downloaded model)
# results = compute_entropy_rate_and_perplexity(["example text here"])
# print(results)
```

## Lempel-Ziv Complexity and Entropy Rate

The Lempel-Ziv algorithm (LZ77/LZ78) is a universal data compressor: without knowing the source statistics, it converges to the entropy rate as sequence length increases. This makes compression ratio a model-free estimator of entropy rate. The LZ76 complexity c(x) of a string x grows as c(x) ~ n/(log n) · h, where h is the entropy rate.

> **Bits-per-Byte (BPB) as a Universal Metric**: BPB = log₂(PPL) / avg_chars_per_token makes perplexity comparable across models with different tokenizers. GPT-4 tokenizer produces ~4 chars/token while LLaMA SentencePiece produces ~3.5 chars/token — so raw PPL numbers are incomparable, but BPB values are directly comparable.

```python
import gzip
import zlib
import bz2
import lzma
import struct
from typing import Dict

def compression_vs_entropy_bound(
    text: str,
    entropy_rate_bits_per_char: float
) -> Dict[str, dict]:
    """Compare actual compression ratios vs the entropy rate lower bound.

    Shannon's source coding theorem says the best lossless compressor
    achieves exactly h bits/char. We compare standard algorithms to this bound.

    Args:
        text: Input text to compress.
        entropy_rate_bits_per_char: Estimated entropy rate (e.g., 1.0 for English).
    Returns:
        Dict with compression statistics per method.
    """
    data = text.encode('utf-8')
    original_bytes = len(data)
    original_bits_per_char = 8.0  # UTF-8 baseline: 8 bits/char (ASCII chars)

    methods = {
        'gzip-1 (fast)': gzip.compress(data, compresslevel=1),
        'gzip-9 (best)': gzip.compress(data, compresslevel=9),
        'zlib-6 (default)': zlib.compress(data, level=6),
        'bz2 (block)': bz2.compress(data),
        'lzma (xz)': lzma.compress(data),
    }

    entropy_bound_bytes = len(text) * entropy_rate_bits_per_char / 8.0
    print(f"Original text: {len(text)} chars, {original_bytes} bytes")
    print(f"Entropy bound @ h={entropy_rate_bits_per_char} b/char: {entropy_bound_bytes:.1f} bytes")
    print(f"\n{'Method':<20} {'Compressed':>12} {'Bits/char':>10} {'vs bound':>10}")
    print("-" * 55)

    results = {}
    for name, compressed in methods.items():
        n_bytes = len(compressed)
        bits_per_char = (n_bytes * 8) / len(text)
        gap_pct = 100 * (bits_per_char - entropy_rate_bits_per_char) / entropy_rate_bits_per_char
        print(f"{name:<20} {n_bytes:>12} {bits_per_char:>10.3f} {gap_pct:>+9.1f}%")
        results[name] = {'compressed_bytes': n_bytes, 'bits_per_char': bits_per_char}

    return results

# English text sample (entropy rate ≈ 1.0-1.3 bits/char empirically)
sample = ("the quick brown fox jumps over the lazy dog " * 50 +
          "information theory and entropy rate of english " * 30)
compression_vs_entropy_bound(sample, entropy_rate_bits_per_char=1.2)
```

## Source Coding Theorem Connection

Shannon's source coding theorem states that for a stationary ergodic source with entropy rate h, the optimal lossless compression achieves exactly h bits/symbol — no more, no less. Any code achieving fewer than h bits/symbol must have non-zero error probability; any code using more than h bits/symbol is wasting capacity. This is why entropy rate is both a theoretical limit and a practical benchmark for compression algorithms and language models.

---

Entropy rate is the fingerprint of a stochastic process: i.i.d. sources have maximum entropy rate (no exploitable patterns), while structured processes like natural language have rates far below the alphabet maximum. Language model perplexity is the empirical entropy rate of the model's distribution on a test corpus — minimizing it is equivalent to finding a model whose distribution matches the true data distribution as closely as possible.

