---
title: "Data Contamination — Benchmark Leakage and Decontamination in LLM Pretraining"
slug: "data-contamination-llm"
description: "How benchmark test data leaks into LLM pretraining corpora, contamination detection via n-gram overlap and MinHash, decontamination pipelines, and strategies for unbiased evaluation."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Data contamination occurs when test examples from evaluation benchmarks appear in the pretraining corpus, causing inflated benchmark scores that do not reflect genuine generalization. As LLMs are trained on increasingly large web crawls (trillions of tokens), the probability that any given public benchmark has at least some overlap with the training data approaches 1. Contamination undermines the scientific value of benchmarks and makes it difficult to compare models trained at different times or on different data. GPT-3 was the first major LLM to publish a contamination analysis; subsequent models have adopted varying levels of transparency about contamination rates."},{"type":"heading","level":2,"content":"Types of Benchmark Contamination"},{"type":"text","content":"Contamination exists on a spectrum from verbatim reproduction to subtle thematic overlap. Exact contamination — where the test question and answer appear verbatim in training data — is the most severe and easiest to detect. Partial contamination covers cases where only the question or only the answer appears separately in training data. Near-contamination involves paraphrases within small edit distance that a model trained on them would still have an unfair advantage. Indirect contamination is the hardest to handle: training examples that are not from the benchmark but are so semantically similar that they provide the answer, such as the original source documents for multiple-choice questions."},{"type":"list","ordered":false,"items":["Exact: verbatim question + answer appear together in training data — maximum advantage","Partial: question or answer alone in training data — moderate advantage, hard to prove impact","Near: paraphrased version within small edit distance (Levenshtein \u003c20) — detectable via MinHash","Indirect: original source material (e.g., Wikipedia articles underlying MMLU questions) — nearly undetectable","Temporal: benchmark released before data cutoff, crawled later — common for newer benchmarks"]},{"type":"heading","level":2,"content":"N-gram Overlap Detection — The GPT-3 Approach"},{"type":"text","content":"GPT-3 introduced a simple but effective contamination detection method: build a set of all 13-grams (contiguous sequences of 13 tokens) from every test example, then scan the training corpus for documents containing more than a threshold number of matching 13-grams. A document is flagged if it has 5 or more overlapping 13-grams with any benchmark example. 13 tokens is chosen because it is long enough to be a meaningful phrase that uniquely identifies a benchmark example, yet short enough to catch near-exact copies. The threshold of 5 reduces false positives from commonly occurring phrases."},{"type":"code","language":"python","content":"import re\nfrom collections import defaultdict\n\ndef build_ngrams(text, n=13):\n    \"\"\"Build a set of n-gram tuples from whitespace-tokenized text.\"\"\"\n    tokens = re.sub(r\u0027[^\\w\\s]\u0027, \u0027 \u0027, text.lower()).split()\n    return set(tuple(tokens[i:i+n]) for i in range(len(tokens) - n + 1))\n\ndef scan_corpus_contamination(benchmark_examples, corpus_docs, n=13, threshold=5):\n    \"\"\"Flag training documents with \u003e= threshold overlapping n-grams with any benchmark example.\"\"\"\n    bench_ngrams = set()\n    for ex in benchmark_examples:\n        text = ex.get(\u0027question\u0027, \u0027\u0027) + \u0027 \u0027 + ex.get(\u0027answer\u0027, \u0027\u0027)\n        bench_ngrams.update(build_ngrams(text, n))\n\n    contaminated = []\n    for doc_id, doc_text in enumerate(corpus_docs):\n        doc_ngrams = build_ngrams(doc_text, n)\n        overlap    = len(doc_ngrams \u0026 bench_ngrams)\n        if overlap \u003e= threshold:\n            contaminated.append({\u0027doc_id\u0027: doc_id, \u0027overlap_count\u0027: overlap,\n                                 \u0027preview\u0027: doc_text[:100]})\n    return contaminated\n\n# Minimal reproducible example\nbenchmark = [\n    {\u0027question\u0027: \u0027What neurotransmitter is primarily associated with reward pathways in the brain\u0027,\n     \u0027answer\u0027: \u0027dopamine is associated with reward motivation and pleasure\u0027},\n    {\u0027question\u0027: \u0027Solve the recurrence relation T of n equals two T of n over two plus n\u0027,\n     \u0027answer\u0027: \u0027By master theorem T of n is theta n log n\u0027},\n]\ncorpus = [\n    \u0027dopamine is associated with reward motivation and pleasure in the ventral tegmental area nucleus accumbens\u0027,\n    \u0027transformers use self-attention to process all tokens in parallel without sequential computation\u0027,\n    \u0027By master theorem T of n is theta n log n for divide and conquer recurrences with balanced splits\u0027,\n]\nflagged = scan_corpus_contamination(benchmark, corpus, n=5, threshold=3)\nprint(f\"Contaminated docs: {len(flagged)}/{len(corpus)}\")\nfor r in flagged:\n    print(f\"  Doc {r[\u0027doc_id\u0027]}: {r[\u0027overlap_count\u0027]} overlapping n-grams — {r[\u0027preview\u0027]!r:.60}\")"},{"type":"heading","level":2,"content":"MinHash Near-Duplicate Decontamination"},{"type":"text","content":"N-gram exact matching misses paraphrased contamination. MinHash provides approximate Jaccard similarity between documents without comparing all n-gram pairs. A MinHash signature of a document is a fixed-length vector of minimum hash values; the fraction of signature positions where two documents agree is an unbiased estimator of Jaccard similarity. Using 128 hash functions gives an estimation variance of ~0.01. Documents with estimated Jaccard similarity above 0.5 with any benchmark example are flagged as near-contaminated. In practice, locality-sensitive hashing (LSH) allows sub-linear lookup — essential when the training corpus has billions of documents."},{"type":"code","language":"python","content":"import re\nimport random\nfrom typing import List\n\ndef shingle_set(text, k=5):\n    \"\"\"Build word k-shingle (k-gram) set from text for Jaccard estimation.\"\"\"\n    tokens = re.sub(r\u0027[^\\w\\s]\u0027, \u0027 \u0027, text.lower()).split()\n    return set(tuple(tokens[i:i+k]) for i in range(len(tokens)-k+1))\n\ndef minhash_signature(shingles, num_hashes=128, seed=0):\n    \"\"\"Compute MinHash signature: vector of min hash values over shingles.\"\"\"\n    rng = random.Random(seed)\n    params = [(rng.randint(1, 2**31-1), rng.randint(0, 2**31-1)) for _ in range(num_hashes)]\n    sig = []\n    for a, b in params:\n        min_val = min(((a * hash(s) + b) % (2**31 - 1)) for s in shingles) if shingles else 0\n        sig.append(min_val)\n    return sig\n\ndef jaccard_from_sigs(sig1, sig2):\n    return sum(a == b for a, b in zip(sig1, sig2)) / len(sig1)\n\ndef minhash_decontaminate(benchmark_examples, train_docs, threshold=0.4, num_hashes=128, k=5):\n    test_sigs = [minhash_signature(shingle_set(ex.get(\u0027question\u0027,\u0027\u0027) + \u0027 \u0027 + ex.get(\u0027answer\u0027,\u0027\u0027), k), num_hashes)\n                 for ex in benchmark_examples]\n    flagged = []\n    for i, doc in enumerate(train_docs):\n        doc_sig = minhash_signature(shingle_set(doc, k), num_hashes)\n        max_sim  = max(jaccard_from_sigs(doc_sig, ts) for ts in test_sigs)\n        if max_sim \u003e= threshold:\n            flagged.append({\u0027train_idx\u0027: i, \u0027max_jaccard\u0027: round(max_sim, 3)})\n    return flagged\n\ntest_set = [{\u0027question\u0027: \u0027What is the boiling point of water at standard pressure\u0027, \u0027answer\u0027: \u0027100 degrees Celsius at one atmosphere\u0027}]\ntrain    = [\n    \u0027The boiling point of water at standard pressure one atmosphere is 100 degrees Celsius or 212 Fahrenheit\u0027,\n    \u0027Neural networks learn data representations through gradient descent and backpropagation\u0027,\n    \u0027Water boils at 100 degrees Celsius at one atmosphere pressure standard conditions sea level\u0027,\n]\nresults = minhash_decontaminate(test_set, train, threshold=0.3)\nprint(f\"Flagged: {len(results)}/{len(train)} training docs\")\nfor r in results:\n    print(f\"  Train[{r[\u0027train_idx\u0027]}]: Jaccard={r[\u0027max_jaccard\u0027]}\")"},{"type":"heading","level":2,"content":"Contamination Rate Reporting"},{"type":"text","content":"Responsible contamination reporting requires running detection on every benchmark used in evaluation, reporting per-benchmark contamination rates, and showing that contaminated examples do not significantly change aggregate scores. The GPT-4 technical report ran contamination analysis across all major benchmarks and reported that contamination rates were low and did not substantially inflate scores. However, contamination analysis methodology varies widely — different n values, thresholds, and tokenization choices produce very different contamination rates for the same corpus and benchmark combination."},{"type":"code","language":"python","content":"import re\n\ndef ngrams_set(text, n):\n    tokens = re.sub(r\u0027[^\\w\\s]\u0027, \u0027 \u0027, text.lower()).split()\n    return set(tuple(tokens[i:i+n]) for i in range(len(tokens)-n+1))\n\ndef contamination_rate(benchmark_examples, train_text, n=13, min_overlap=5):\n    \"\"\"Return fraction of benchmark examples with \u003e=min_overlap n-gram matches in train.\"\"\"\n    train_ngrams    = ngrams_set(train_text, n)\n    contaminated    = 0\n    details         = []\n    for ex in benchmark_examples:\n        text     = ex.get(\u0027question\u0027,\u0027\u0027) + \u0027 \u0027 + ex.get(\u0027answer\u0027,\u0027\u0027)\n        ex_ng    = ngrams_set(text, n)\n        overlap  = len(ex_ng \u0026 train_ngrams)\n        is_cont  = overlap \u003e= min_overlap\n        contaminated += int(is_cont)\n        details.append({\u0027contaminated\u0027: is_cont, \u0027overlap\u0027: overlap})\n    rate = contaminated / len(benchmark_examples) if benchmark_examples else 0.0\n    return {\u0027total\u0027: len(benchmark_examples), \u0027contaminated\u0027: contaminated,\n            \u0027rate\u0027: round(rate, 4), \u0027details\u0027: details}\n\n# Simulate for three benchmark subsets\ntrain_blob = (\u0027dopamine is associated with reward motivation in nucleus accumbens \u0027\n              \u0027solve quadratic by completing the square x squared plus five x plus six \u0027\n              \u0027water boils at 100 degrees Celsius standard conditions sea level pressure\u0027)\nbenchmarks = {\n    \u0027MMLU\u0027:  [{\u0027question\u0027: \u0027dopamine is associated with reward motivation in nucleus accumbens\u0027, \u0027answer\u0027: \u0027correct answer A\u0027}],\n    \u0027GSM8K\u0027: [{\u0027question\u0027: \u0027solve quadratic by completing the square method\u0027, \u0027answer\u0027: \u0027x equals root values\u0027}],\n    \u0027ARC\u0027:   [{\u0027question\u0027: \u0027what is the largest planet in the solar system\u0027, \u0027answer\u0027: \u0027Jupiter has largest mass\u0027}],\n}\nfor name, examples in benchmarks.items():\n    r = contamination_rate(examples, train_blob, n=4, min_overlap=2)\n    print(f\"{name}: {r[\u0027contaminated\u0027]}/{r[\u0027total\u0027]} contaminated ({r[\u0027rate\u0027]:.1%})\")"},{"type":"callout","variant":"info","title":"Info","content":"Contamination detection with 13-gram matching has high false positive rate for common phrases — always manually review flagged examples before removal to avoid decontaminating unrelated documents that happen to share common phrases with benchmarks."},{"type":"heading","level":2,"content":"Decontamination Pipeline"},{"type":"text","content":"A decontamination pipeline runs before the final data mix is frozen: collect all benchmark examples scheduled for evaluation, extract n-grams, scan the training corpus, remove flagged documents, and regenerate token count statistics. The order matters — decontamination should run after other filtering steps (quality filter, deduplication) but before training data tokenization. Re-running decontamination with the final benchmark set at the end of data preparation is essential because benchmark selection often changes during development."},{"type":"code","language":"python","content":"import re\nimport json\n\ndef ngrams_set(text, n):\n    tokens = re.sub(r\u0027[^\\w\\s]\u0027, \u0027 \u0027, text.lower()).split()\n    return set(tuple(tokens[i:i+n]) for i in range(len(tokens)-n+1))\n\ndef build_benchmark_ngrams(benchmark_files, n=13):\n    \"\"\"Load benchmark JSON files and build combined n-gram set from all examples.\"\"\"\n    all_ngrams = set()\n    for path in benchmark_files:\n        with open(path) as f:\n            examples = json.load(f)\n        for ex in examples:\n            text = ex.get(\u0027question\u0027,\u0027\u0027) + \u0027 \u0027 + ex.get(\u0027choices\u0027,\u0027\u0027) + \u0027 \u0027 + ex.get(\u0027answer\u0027,\u0027\u0027)\n            all_ngrams.update(ngrams_set(text, n))\n    return all_ngrams\n\ndef decontaminate_corpus(train_docs, bench_ngrams, n=13, overlap_threshold=5):\n    \"\"\"Remove training documents with \u003e= overlap_threshold overlapping n-grams.\"\"\"\n    clean_docs, removed = [], []\n    for idx, doc in enumerate(train_docs):\n        doc_ng  = ngrams_set(doc[\u0027text\u0027], n)\n        overlap = len(doc_ng \u0026 bench_ngrams)\n        if overlap \u003c overlap_threshold:\n            clean_docs.append(doc)\n        else:\n            removed.append({\u0027idx\u0027: idx, \u0027overlap\u0027: overlap, \u0027preview\u0027: doc[\u0027text\u0027][:80]})\n    return clean_docs, removed\n\n# Simulate with in-memory benchmark n-grams\nbench_ngrams = ngrams_set(\u0027dopamine reward motivation nucleus accumbens ventral tegmental\u0027, n=4)\ntrain_corpus = [\n    {\u0027id\u0027: 0, \u0027text\u0027: \u0027dopamine reward motivation nucleus accumbens ventral tegmental area basal ganglia\u0027},\n    {\u0027id\u0027: 1, \u0027text\u0027: \u0027transformer attention scales quadratically with sequence length in the worst case\u0027},\n    {\u0027id\u0027: 2, \u0027text\u0027: \u0027reward motivation nucleus accumbens is key to understanding addiction and behavior\u0027},\n]\nclean, removed = decontaminate_corpus(train_corpus, bench_ngrams, n=4, overlap_threshold=3)\nprint(f\"Original: {len(train_corpus)}  Removed: {len(removed)}  Clean: {len(clean)}\")\nfor r in removed:\n    print(f\"  Removed doc {r[\u0027idx\u0027]}: {r[\u0027overlap\u0027]} overlapping n-grams\")"},{"type":"heading","level":2,"content":"Benchmark Contamination Rates in Major LLMs"},{"type":"table","headers":["Model","MMLU %","HellaSwag %","GSM8K %","ARC %","Detection Method"],"rows":[["GPT-3 175B","~2.2%","~3.1%","N/A","~2.8%","13-gram overlap, threshold 5"],["GPT-4","\u003c1.0%","\u003c1.5%","~0.8%","\u003c1.0%","GPT-4 contamination analysis"],["LLaMA-2 70B","~2.4%","~1.8%","~3.2%","~2.1%","N-gram + manual review"],["Mistral 7B","~1.1%","~0.9%","~1.4%","~0.7%","Proprietary (undisclosed threshold)"],["DeepSeek-V2","\u003c0.5%","\u003c0.5%","~0.6%","\u003c0.5%","Substring match deduplication"]]},{"type":"heading","level":2,"content":"True Evaluation — Avoiding Contamination"},{"type":"text","content":"The cleanest solution to benchmark contamination is to evaluate on unpublished benchmarks that were never on the public internet. Several research groups maintain private evaluation sets released only after training data cutoff. Dynamic benchmarking — generating new problems at evaluation time via templates or LLM-generated variants — is another approach. BIG-Bench Hard, MATH, and GPQA were designed with harder problems that resist memorization even under contamination. At minimum, every evaluation report should include contamination rates per benchmark and ablation showing scores with contaminated examples removed."},{"type":"list","ordered":false,"items":["Maintain a private held-out evaluation suite never published to the web","Use live code execution benchmarks (HumanEval, LiveCodeBench) — answers change with new problems","Report delta between contaminated and decontaminated benchmark scores as an honesty metric","For MMLU: check against the original source articles — contamination may come from Wikipedia not from the test itself","Prefer few-shot evaluation with novel prompt templates to reduce surface-level memorization advantage"]},{"type":"heading","level":2,"content":"Contamination\u0027s Impact on Reported Scores"},{"type":"text","content":"Empirical studies (Golchin et al. 2023, Xu et al. 2024) show that contamination inflates benchmark scores by 2–15 percentage points depending on contamination rate, benchmark difficulty, and model size. Larger models benefit more from contamination because they have greater memorization capacity. Harder benchmarks (MATH, GPQA) are less affected because memorizing an isolated problem-answer pair does not transfer to related problems that require genuine reasoning. The practical implication: MMLU scores above 85% should be interpreted cautiously for models trained on large web crawls without rigorous decontamination."}]"
---
# Data Contamination — Benchmark Leakage and Decontamination in LLM Pretraining

Data contamination occurs when test examples from evaluation benchmarks appear in the pretraining corpus, causing inflated benchmark scores that do not reflect genuine generalization. As LLMs are trained on increasingly large web crawls (trillions of tokens), the probability that any given public benchmark has at least some overlap with the training data approaches 1. Contamination undermines the scientific value of benchmarks and makes it difficult to compare models trained at different times or on different data. GPT-3 was the first major LLM to publish a contamination analysis; subsequent models have adopted varying levels of transparency about contamination rates.

## Types of Benchmark Contamination

Contamination exists on a spectrum from verbatim reproduction to subtle thematic overlap. Exact contamination — where the test question and answer appear verbatim in training data — is the most severe and easiest to detect. Partial contamination covers cases where only the question or only the answer appears separately in training data. Near-contamination involves paraphrases within small edit distance that a model trained on them would still have an unfair advantage. Indirect contamination is the hardest to handle: training examples that are not from the benchmark but are so semantically similar that they provide the answer, such as the original source documents for multiple-choice questions.

- Exact: verbatim question + answer appear together in training data — maximum advantage
- Partial: question or answer alone in training data — moderate advantage, hard to prove impact
- Near: paraphrased version within small edit distance (Levenshtein <20) — detectable via MinHash
- Indirect: original source material (e.g., Wikipedia articles underlying MMLU questions) — nearly undetectable
- Temporal: benchmark released before data cutoff, crawled later — common for newer benchmarks

## N-gram Overlap Detection — The GPT-3 Approach

GPT-3 introduced a simple but effective contamination detection method: build a set of all 13-grams (contiguous sequences of 13 tokens) from every test example, then scan the training corpus for documents containing more than a threshold number of matching 13-grams. A document is flagged if it has 5 or more overlapping 13-grams with any benchmark example. 13 tokens is chosen because it is long enough to be a meaningful phrase that uniquely identifies a benchmark example, yet short enough to catch near-exact copies. The threshold of 5 reduces false positives from commonly occurring phrases.

```python
import re
from collections import defaultdict

def build_ngrams(text, n=13):
    """Build a set of n-gram tuples from whitespace-tokenized text."""
    tokens = re.sub(r'[^\w\s]', ' ', text.lower()).split()
    return set(tuple(tokens[i:i+n]) for i in range(len(tokens) - n + 1))

def scan_corpus_contamination(benchmark_examples, corpus_docs, n=13, threshold=5):
    """Flag training documents with >= threshold overlapping n-grams with any benchmark example."""
    bench_ngrams = set()
    for ex in benchmark_examples:
        text = ex.get('question', '') + ' ' + ex.get('answer', '')
        bench_ngrams.update(build_ngrams(text, n))

    contaminated = []
    for doc_id, doc_text in enumerate(corpus_docs):
        doc_ngrams = build_ngrams(doc_text, n)
        overlap    = len(doc_ngrams & bench_ngrams)
        if overlap >= threshold:
            contaminated.append({'doc_id': doc_id, 'overlap_count': overlap,
                                 'preview': doc_text[:100]})
    return contaminated

# Minimal reproducible example
benchmark = [
    {'question': 'What neurotransmitter is primarily associated with reward pathways in the brain',
     'answer': 'dopamine is associated with reward motivation and pleasure'},
    {'question': 'Solve the recurrence relation T of n equals two T of n over two plus n',
     'answer': 'By master theorem T of n is theta n log n'},
]
corpus = [
    'dopamine is associated with reward motivation and pleasure in the ventral tegmental area nucleus accumbens',
    'transformers use self-attention to process all tokens in parallel without sequential computation',
    'By master theorem T of n is theta n log n for divide and conquer recurrences with balanced splits',
]
flagged = scan_corpus_contamination(benchmark, corpus, n=5, threshold=3)
print(f"Contaminated docs: {len(flagged)}/{len(corpus)}")
for r in flagged:
    print(f"  Doc {r['doc_id']}: {r['overlap_count']} overlapping n-grams — {r['preview']!r:.60}")
```

## MinHash Near-Duplicate Decontamination

N-gram exact matching misses paraphrased contamination. MinHash provides approximate Jaccard similarity between documents without comparing all n-gram pairs. A MinHash signature of a document is a fixed-length vector of minimum hash values; the fraction of signature positions where two documents agree is an unbiased estimator of Jaccard similarity. Using 128 hash functions gives an estimation variance of ~0.01. Documents with estimated Jaccard similarity above 0.5 with any benchmark example are flagged as near-contaminated. In practice, locality-sensitive hashing (LSH) allows sub-linear lookup — essential when the training corpus has billions of documents.

```python
import re
import random
from typing import List

def shingle_set(text, k=5):
    """Build word k-shingle (k-gram) set from text for Jaccard estimation."""
    tokens = re.sub(r'[^\w\s]', ' ', text.lower()).split()
    return set(tuple(tokens[i:i+k]) for i in range(len(tokens)-k+1))

def minhash_signature(shingles, num_hashes=128, seed=0):
    """Compute MinHash signature: vector of min hash values over shingles."""
    rng = random.Random(seed)
    params = [(rng.randint(1, 2**31-1), rng.randint(0, 2**31-1)) for _ in range(num_hashes)]
    sig = []
    for a, b in params:
        min_val = min(((a * hash(s) + b) % (2**31 - 1)) for s in shingles) if shingles else 0
        sig.append(min_val)
    return sig

def jaccard_from_sigs(sig1, sig2):
    return sum(a == b for a, b in zip(sig1, sig2)) / len(sig1)

def minhash_decontaminate(benchmark_examples, train_docs, threshold=0.4, num_hashes=128, k=5):
    test_sigs = [minhash_signature(shingle_set(ex.get('question','') + ' ' + ex.get('answer',''), k), num_hashes)
                 for ex in benchmark_examples]
    flagged = []
    for i, doc in enumerate(train_docs):
        doc_sig = minhash_signature(shingle_set(doc, k), num_hashes)
        max_sim  = max(jaccard_from_sigs(doc_sig, ts) for ts in test_sigs)
        if max_sim >= threshold:
            flagged.append({'train_idx': i, 'max_jaccard': round(max_sim, 3)})
    return flagged

test_set = [{'question': 'What is the boiling point of water at standard pressure', 'answer': '100 degrees Celsius at one atmosphere'}]
train    = [
    'The boiling point of water at standard pressure one atmosphere is 100 degrees Celsius or 212 Fahrenheit',
    'Neural networks learn data representations through gradient descent and backpropagation',
    'Water boils at 100 degrees Celsius at one atmosphere pressure standard conditions sea level',
]
results = minhash_decontaminate(test_set, train, threshold=0.3)
print(f"Flagged: {len(results)}/{len(train)} training docs")
for r in results:
    print(f"  Train[{r['train_idx']}]: Jaccard={r['max_jaccard']}")
```

## Contamination Rate Reporting

Responsible contamination reporting requires running detection on every benchmark used in evaluation, reporting per-benchmark contamination rates, and showing that contaminated examples do not significantly change aggregate scores. The GPT-4 technical report ran contamination analysis across all major benchmarks and reported that contamination rates were low and did not substantially inflate scores. However, contamination analysis methodology varies widely — different n values, thresholds, and tokenization choices produce very different contamination rates for the same corpus and benchmark combination.

```python
import re

def ngrams_set(text, n):
    tokens = re.sub(r'[^\w\s]', ' ', text.lower()).split()
    return set(tuple(tokens[i:i+n]) for i in range(len(tokens)-n+1))

def contamination_rate(benchmark_examples, train_text, n=13, min_overlap=5):
    """Return fraction of benchmark examples with >=min_overlap n-gram matches in train."""
    train_ngrams    = ngrams_set(train_text, n)
    contaminated    = 0
    details         = []
    for ex in benchmark_examples:
        text     = ex.get('question','') + ' ' + ex.get('answer','')
        ex_ng    = ngrams_set(text, n)
        overlap  = len(ex_ng & train_ngrams)
        is_cont  = overlap >= min_overlap
        contaminated += int(is_cont)
        details.append({'contaminated': is_cont, 'overlap': overlap})
    rate = contaminated / len(benchmark_examples) if benchmark_examples else 0.0
    return {'total': len(benchmark_examples), 'contaminated': contaminated,
            'rate': round(rate, 4), 'details': details}

# Simulate for three benchmark subsets
train_blob = ('dopamine is associated with reward motivation in nucleus accumbens '
              'solve quadratic by completing the square x squared plus five x plus six '
              'water boils at 100 degrees Celsius standard conditions sea level pressure')
benchmarks = {
    'MMLU':  [{'question': 'dopamine is associated with reward motivation in nucleus accumbens', 'answer': 'correct answer A'}],
    'GSM8K': [{'question': 'solve quadratic by completing the square method', 'answer': 'x equals root values'}],
    'ARC':   [{'question': 'what is the largest planet in the solar system', 'answer': 'Jupiter has largest mass'}],
}
for name, examples in benchmarks.items():
    r = contamination_rate(examples, train_blob, n=4, min_overlap=2)
    print(f"{name}: {r['contaminated']}/{r['total']} contaminated ({r['rate']:.1%})")
```

> **Info**: Contamination detection with 13-gram matching has high false positive rate for common phrases — always manually review flagged examples before removal to avoid decontaminating unrelated documents that happen to share common phrases with benchmarks.

## Decontamination Pipeline

A decontamination pipeline runs before the final data mix is frozen: collect all benchmark examples scheduled for evaluation, extract n-grams, scan the training corpus, remove flagged documents, and regenerate token count statistics. The order matters — decontamination should run after other filtering steps (quality filter, deduplication) but before training data tokenization. Re-running decontamination with the final benchmark set at the end of data preparation is essential because benchmark selection often changes during development.

```python
import re
import json

def ngrams_set(text, n):
    tokens = re.sub(r'[^\w\s]', ' ', text.lower()).split()
    return set(tuple(tokens[i:i+n]) for i in range(len(tokens)-n+1))

def build_benchmark_ngrams(benchmark_files, n=13):
    """Load benchmark JSON files and build combined n-gram set from all examples."""
    all_ngrams = set()
    for path in benchmark_files:
        with open(path) as f:
            examples = json.load(f)
        for ex in examples:
            text = ex.get('question','') + ' ' + ex.get('choices','') + ' ' + ex.get('answer','')
            all_ngrams.update(ngrams_set(text, n))
    return all_ngrams

def decontaminate_corpus(train_docs, bench_ngrams, n=13, overlap_threshold=5):
    """Remove training documents with >= overlap_threshold overlapping n-grams."""
    clean_docs, removed = [], []
    for idx, doc in enumerate(train_docs):
        doc_ng  = ngrams_set(doc['text'], n)
        overlap = len(doc_ng & bench_ngrams)
        if overlap < overlap_threshold:
            clean_docs.append(doc)
        else:
            removed.append({'idx': idx, 'overlap': overlap, 'preview': doc['text'][:80]})
    return clean_docs, removed

# Simulate with in-memory benchmark n-grams
bench_ngrams = ngrams_set('dopamine reward motivation nucleus accumbens ventral tegmental', n=4)
train_corpus = [
    {'id': 0, 'text': 'dopamine reward motivation nucleus accumbens ventral tegmental area basal ganglia'},
    {'id': 1, 'text': 'transformer attention scales quadratically with sequence length in the worst case'},
    {'id': 2, 'text': 'reward motivation nucleus accumbens is key to understanding addiction and behavior'},
]
clean, removed = decontaminate_corpus(train_corpus, bench_ngrams, n=4, overlap_threshold=3)
print(f"Original: {len(train_corpus)}  Removed: {len(removed)}  Clean: {len(clean)}")
for r in removed:
    print(f"  Removed doc {r['idx']}: {r['overlap']} overlapping n-grams")
```

## Benchmark Contamination Rates in Major LLMs

| Model | MMLU % | HellaSwag % | GSM8K % | ARC % | Detection Method |
| --- | --- | --- | --- | --- | --- |
| GPT-3 175B | ~2.2% | ~3.1% | N/A | ~2.8% | 13-gram overlap, threshold 5 |
| GPT-4 | <1.0% | <1.5% | ~0.8% | <1.0% | GPT-4 contamination analysis |
| LLaMA-2 70B | ~2.4% | ~1.8% | ~3.2% | ~2.1% | N-gram + manual review |
| Mistral 7B | ~1.1% | ~0.9% | ~1.4% | ~0.7% | Proprietary (undisclosed threshold) |
| DeepSeek-V2 | <0.5% | <0.5% | ~0.6% | <0.5% | Substring match deduplication |

## True Evaluation — Avoiding Contamination

The cleanest solution to benchmark contamination is to evaluate on unpublished benchmarks that were never on the public internet. Several research groups maintain private evaluation sets released only after training data cutoff. Dynamic benchmarking — generating new problems at evaluation time via templates or LLM-generated variants — is another approach. BIG-Bench Hard, MATH, and GPQA were designed with harder problems that resist memorization even under contamination. At minimum, every evaluation report should include contamination rates per benchmark and ablation showing scores with contaminated examples removed.

- Maintain a private held-out evaluation suite never published to the web
- Use live code execution benchmarks (HumanEval, LiveCodeBench) — answers change with new problems
- Report delta between contaminated and decontaminated benchmark scores as an honesty metric
- For MMLU: check against the original source articles — contamination may come from Wikipedia not from the test itself
- Prefer few-shot evaluation with novel prompt templates to reduce surface-level memorization advantage

## Contamination's Impact on Reported Scores

Empirical studies (Golchin et al. 2023, Xu et al. 2024) show that contamination inflates benchmark scores by 2–15 percentage points depending on contamination rate, benchmark difficulty, and model size. Larger models benefit more from contamination because they have greater memorization capacity. Harder benchmarks (MATH, GPQA) are less affected because memorizing an isolated problem-answer pair does not transfer to related problems that require genuine reasoning. The practical implication: MMLU scores above 85% should be interpreted cautiously for models trained on large web crawls without rigorous decontamination.

