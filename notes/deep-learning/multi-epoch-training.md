---
title: "Multi-Epoch Training for LLMs — Data Repetition Effects and Degradation"
slug: "multi-epoch-training"
description: "How training language models on repeated data degrades quality — DeepMind findings on loss increases at 4x and 32x repetition, double descent in multi-epoch regimes, domain-specific repetition thresholds, model memorization measurement, and mitigation via data augmentation and synthetic data mixing."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Modern large language models are trained on trillions of tokens — LLaMA-3.1-8B on 15 trillion, for example — yet the total unique web data available falls well short of that threshold. The result is inevitable: some documents are seen multiple times during training. Understanding how repetition affects model quality, memorization, and downstream performance is essential for anyone designing a pretraining data pipeline. The Chinchilla paper established that for a compute-optimal model, training on roughly 1 epoch is ideal; but inference-optimized models intentionally overtrain past that point, surfacing the multi-epoch problem at scale."},{"type":"heading","level":2,"content":"Chinchilla Scaling and the Single-Epoch Assumption"},{"type":"text","content":"Hoffmann et al. (2022) showed that compute-optimal training balances model parameters N and training tokens D as D ≈ 20N: a 70B model trained on 1.4T tokens, roughly one pass over a large Common Crawl snapshot. The implicit assumption is a single pass over the data. Inference-optimized models — LLaMA-3.1, Mistral, Gemma — deliberately violate this by overtraining on 15–30T tokens with smaller parameter counts, producing cheaper-to-serve models that still perform well. The tradeoff is data repetition: any 1T-token source in a 15T-token run appears roughly 15 times if not diversified with fresh crawl data."},{"type":"heading","level":2,"content":"Data Repetition Effects — DeepMind Research"},{"type":"text","content":"DeepMind\u0027s research into multi-epoch training (Hernandez et al. 2022, Muennighoff et al. 2023) produced quantitative baselines: repeating the training corpus 4 times causes approximately 5% validation loss increase versus a single-epoch baseline; 32 repetitions causes approximately 20% loss increase. The degradation is non-linear — the first repetition adds almost no cost, the fourth adds a noticeable amount, and each subsequent doubling adds proportionally more. Muennighoff et al. also observed a double descent analog: after enough repetition, loss initially worsens, briefly improves as the model memorizes, then worsens again as memorization dominates generalization."},{"type":"code","language":"python","content":"import random\nfrom typing import List, Iterator\nfrom torch.utils.data import IterableDataset\n\nclass MultiEpochDataset(IterableDataset):\n    \"\"\"Shuffle documents across epochs; track per-document repetition count.\"\"\"\n    def __init__(self, documents: List, max_epochs: int = 4, seed: int = 42):\n        self.documents = documents\n        self.max_epochs = max_epochs\n        self.rng = random.Random(seed)\n        self.epoch_counts = [0] * len(documents)\n\n    def __iter__(self) -\u003e Iterator:\n        for epoch in range(self.max_epochs):\n            indices = list(range(len(self.documents)))\n            self.rng.shuffle(indices)          # different order each epoch\n            for idx in indices:\n                self.epoch_counts[idx] += 1\n                yield {\"tokens\": self.documents[idx], \"epoch\": epoch,\n                       \"doc_id\": idx, \"repetition_count\": self.epoch_counts[idx]}\n\n# 1,000 documents x 4 epochs -- no document exceeds 4x repetition\ndocs = [list(range(512)) for _ in range(1_000)]\ndataset = MultiEpochDataset(docs, max_epochs=4)\ntotal = sum(1 for _ in dataset)\nprint(f\"Total samples: {total}, max repetitions: {max(dataset.epoch_counts)}\")\nassert max(dataset.epoch_counts) == 4, \"Repetition limit violated\"\nprint(\"All documents stay within the 4x repetition limit\")"},{"type":"heading","level":2,"content":"Measuring Degradation Empirically"},{"type":"text","content":"Degradation from data repetition is measured by training identical model architectures on 1x, 2x, 4x, and 8x repetitions of the same fixed dataset, then evaluating on a held-out set that was never repeated. The key is ensuring held-out data comes from the same distribution but is completely disjoint from training — otherwise the measurement conflates distribution shift with repetition effects. The metric is absolute validation loss and the percentage increase relative to the 1x baseline. Perplexity is less useful here because it grows exponentially with loss, amplifying small absolute changes."},{"type":"code","language":"python","content":"import random\nimport torch\nimport torch.nn as nn\nfrom torch.utils.data import DataLoader, TensorDataset\n\ndef measure_repetition_degradation(token_corpus, rep_counts, seq_len=64, steps=300):\n    \"\"\"Train a tiny LM on corpus repeated N times; return eval loss per rep count.\"\"\"\n    vocab_size = max(token_corpus) + 1\n    results = {}\n    for reps in rep_counts:\n        tokens = token_corpus * reps\n        random.shuffle(tokens)\n        seqs = [tokens[i:i+seq_len+1] for i in range(0, len(tokens)-seq_len, seq_len)]\n        xs   = torch.tensor([s[:-1] for s in seqs])\n        ys   = torch.tensor([s[1:]  for s in seqs])\n        loader = DataLoader(TensorDataset(xs, ys), batch_size=64, shuffle=True)\n        model  = nn.Sequential(nn.Embedding(vocab_size, 64), nn.Linear(64, vocab_size))\n        opt    = torch.optim.Adam(model.parameters(), lr=3e-4)\n        for step, (x, y) in zip(range(steps), loader):\n            emb  = model[0](x).mean(1)\n            loss = nn.functional.cross_entropy(model[1](emb), y[:, seq_len // 2])\n            opt.zero_grad(); loss.backward(); opt.step()\n        results[reps] = loss.item()\n    return results\n\ncorpus = list(range(500)) * 200    # 100K token corpus\nlosses = measure_repetition_degradation(corpus, rep_counts=[1, 2, 4, 8])\nbase   = losses[1]\nfor r, l in losses.items():\n    print(f\"  {r}x: loss={l:.4f}  (+{(l - base) / base * 100:.1f}% vs 1x)\")"},{"type":"heading","level":2,"content":"Domain-Specific Repetition Strategies"},{"type":"text","content":"Not all data domains degrade equally with repetition. Repeated code data shows less loss degradation than repeated web text, possibly because code has more structured, learnable patterns with lower entropy. Books tolerate moderate repetition (3–4x) because signal density is high and redundancy is low. Web crawl text — the largest and noisiest source — should be kept at 1x wherever possible. The practical solution is a domain-weighted mixing schedule: assign per-domain epoch budgets that reflect each domain\u0027s repetition tolerance rather than repeating the entire corpus uniformly."},{"type":"code","language":"python","content":"import random\nfrom typing import Dict, List\n\ndef build_mixed_dataset(domain_corpora: Dict[str, List], domain_epochs: Dict[str, int],\n                        seed: int = 42) -\u003e List:\n    \"\"\"Mix domain corpora with different repetition counts into one training set.\"\"\"\n    rng = random.Random(seed)\n    mixed = []\n    for domain, corpus in domain_corpora.items():\n        epochs = domain_epochs.get(domain, 1)\n        repeated = corpus * epochs\n        rng.shuffle(repeated)\n        mixed.extend(repeated)\n        print(f\"  {domain:10s}: {len(corpus):\u003e8,} docs x {epochs}ep = {len(repeated):\u003e8,} samples\")\n    rng.shuffle(mixed)    # global shuffle across all domains\n    return mixed\n\n# LLaMA-3.1-style domain mixing: high-quality sources get more repetitions\nDOMAIN_CORPORA = {\n    \"books\":  [f\"book_doc_{i}\"  for i in range(50_000)],\n    \"code\":   [f\"code_doc_{i}\"  for i in range(80_000)],\n    \"web\":    [f\"web_doc_{i}\"   for i in range(500_000)],\n}\nDOMAIN_EPOCHS = {\"books\": 4, \"code\": 2, \"web\": 1}  # stay below 4x for books\nmixed = build_mixed_dataset(DOMAIN_CORPORA, DOMAIN_EPOCHS)\nprint(f\"Total training samples: {len(mixed):,}\")"},{"type":"heading","level":2,"content":"Model Memorization and Privacy Risk"},{"type":"text","content":"Carlini et al. (2021, 2023) demonstrated that LLMs memorize training data verbatim in measurable ways, and that memorization rate scales with repetition count. A document appearing once is rarely extractable via prefix completion; a document appearing 100 times is often recoverable with a short prefix. Beyond quality degradation, memorization carries privacy and legal risk: PII in repeated documents, copyright text, or proprietary code can be extracted by adversaries. Measuring extraction rate — the fraction of training documents recoverable via greedy decoding given a 50-token prefix — is the standard empirical proxy for memorization."},{"type":"code","language":"python","content":"import torch\nfrom typing import List\n\ndef compute_extraction_rate(model, tokenizer, train_docs: List[str],\n                            prefix_len: int = 50, gen_len: int = 50,\n                            match_threshold: float = 0.7) -\u003e float:\n    \"\"\"Estimate fraction of training docs recoverable via greedy prefix completion.\"\"\"\n    extracted = 0\n    for doc in train_docs:\n        ids = tokenizer(doc, return_tensors=\"pt\", truncation=True, max_length=200).input_ids\n        prefix = ids[:, :prefix_len]\n        suffix = ids[:, prefix_len:prefix_len + gen_len]\n        with torch.no_grad():\n            gen = model.generate(prefix, max_new_tokens=gen_len, do_sample=False)\n        gen_suffix = gen[:, prefix_len:]\n        min_len = min(gen_suffix.shape[1], suffix.shape[1])\n        match = (gen_suffix[:, :min_len] == suffix[:, :min_len]).float().mean().item()\n        extracted += int(match \u003e= match_threshold)\n    return extracted / len(train_docs)\n\n# Synthetic proxy: memorization rate grows with repetition count\nprint(\"Repetition | Extraction Rate | Memorization Risk\")\nprint(\"-\" * 48)\nfor reps, rate in [(1, 0.02), (2, 0.06), (4, 0.15), (8, 0.31), (16, 0.52)]:\n    risk = \"Low\" if rate \u003c 0.1 else (\"Medium\" if rate \u003c 0.3 else \"High\")\n    print(f\"   {reps:\u003e2}x    |     {rate:.0%}          | {risk}\")"},{"type":"heading","level":2,"content":"Mitigation Strategies"},{"type":"text","content":"When the data budget is exhausted and additional repetition becomes necessary, several strategies reduce quality degradation. Data augmentation — back-translation, paraphrase models, sentence reordering — creates semantically similar but token-distinct variants that provide fresh signal. Mixing fresh web crawl snapshots with high-quality repeated sources dilutes the effective repetition rate. Curriculum learning, presenting less-repeated data later in training when the model is more capable, can help, though evidence for language models specifically is mixed. Deduplication is the complementary defense: aggressive MinHash or exact-match deduplication before training removes implicit repetition from near-duplicate web pages."},{"type":"list","ordered":false,"items":["Back-translation: translate documents to a second language and back to produce near-duplicate but token-distinct training examples.","Paraphrase augmentation: use a separately trained paraphrase model to rewrite documents before each repetition epoch.","Crawl diversification: mix fresh CommonCrawl snapshots from different months rather than repeating the same snapshot.","Synthetic data insertion: use the model itself or a smaller teacher to generate text on training topics, injecting it as pseudo-fresh data.","Domain epoch budgeting: assign per-source repetition limits rather than repeating the entire corpus uniformly.","Pre-training deduplication: apply MinHash LSH or exact-match deduplication to remove near-duplicate web pages before any repetition counting."]},{"type":"heading","level":2,"content":"Synthetic Data and RLHF Considerations"},{"type":"text","content":"Model-generated synthetic data serves as pseudo-fresh training signal: it has never appeared in the training set exactly as written, so it does not count as a repetition of existing documents. The risk is mode collapse — if synthetic data dominates, the model converges on its own outputs. Practical recipes (Phi-3, LLaMA-3.1) mix 5–20% synthetic data with fresh web crawls. RLHF preference data is always trained for a single epoch: human annotation is expensive, the dataset is small relative to pretraining corpora, and repeated passes cause severe overfitting on the reward signal rather than generalizable human preference."},{"type":"table","headers":["Repetitions","Loss Increase vs 1x","Memorization Rate","Recommended Limit","Notes"],"rows":[["1x","0% (baseline)","~2%","Always safe","Chinchilla-optimal regime"],["2x","~1–2%","~5–8%","All source types","Negligible quality impact"],["4x","~5%","~15%","Books and code only","DeepMind threshold; avoid for web text"],["8x","~10–12%","~30%","Code only","Significant memorization; avoid for books and web"],["16x","~18%","~50%","Not recommended","Strong memorization artifacts, visible quality drop"],["32x","~20%+","\u003e60%","Never","DeepMind upper bound; severe degradation"]]},{"type":"callout","variant":"warning","title":"The 4x Repetition Threshold","content":"Beyond 4x repetition of the same documents, LLMs show significant memorization artifacts and downstream quality degradation — if you exhaust your data budget, invest in new data collection rather than additional repetition epochs."},{"type":"divider"}]"
---
# Multi-Epoch Training for LLMs — Data Repetition Effects and Degradation

Modern large language models are trained on trillions of tokens — LLaMA-3.1-8B on 15 trillion, for example — yet the total unique web data available falls well short of that threshold. The result is inevitable: some documents are seen multiple times during training. Understanding how repetition affects model quality, memorization, and downstream performance is essential for anyone designing a pretraining data pipeline. The Chinchilla paper established that for a compute-optimal model, training on roughly 1 epoch is ideal; but inference-optimized models intentionally overtrain past that point, surfacing the multi-epoch problem at scale.

## Chinchilla Scaling and the Single-Epoch Assumption

Hoffmann et al. (2022) showed that compute-optimal training balances model parameters N and training tokens D as D ≈ 20N: a 70B model trained on 1.4T tokens, roughly one pass over a large Common Crawl snapshot. The implicit assumption is a single pass over the data. Inference-optimized models — LLaMA-3.1, Mistral, Gemma — deliberately violate this by overtraining on 15–30T tokens with smaller parameter counts, producing cheaper-to-serve models that still perform well. The tradeoff is data repetition: any 1T-token source in a 15T-token run appears roughly 15 times if not diversified with fresh crawl data.

## Data Repetition Effects — DeepMind Research

DeepMind's research into multi-epoch training (Hernandez et al. 2022, Muennighoff et al. 2023) produced quantitative baselines: repeating the training corpus 4 times causes approximately 5% validation loss increase versus a single-epoch baseline; 32 repetitions causes approximately 20% loss increase. The degradation is non-linear — the first repetition adds almost no cost, the fourth adds a noticeable amount, and each subsequent doubling adds proportionally more. Muennighoff et al. also observed a double descent analog: after enough repetition, loss initially worsens, briefly improves as the model memorizes, then worsens again as memorization dominates generalization.

```python
import random
from typing import List, Iterator
from torch.utils.data import IterableDataset

class MultiEpochDataset(IterableDataset):
    """Shuffle documents across epochs; track per-document repetition count."""
    def __init__(self, documents: List, max_epochs: int = 4, seed: int = 42):
        self.documents = documents
        self.max_epochs = max_epochs
        self.rng = random.Random(seed)
        self.epoch_counts = [0] * len(documents)

    def __iter__(self) -> Iterator:
        for epoch in range(self.max_epochs):
            indices = list(range(len(self.documents)))
            self.rng.shuffle(indices)          # different order each epoch
            for idx in indices:
                self.epoch_counts[idx] += 1
                yield {"tokens": self.documents[idx], "epoch": epoch,
                       "doc_id": idx, "repetition_count": self.epoch_counts[idx]}

# 1,000 documents x 4 epochs -- no document exceeds 4x repetition
docs = [list(range(512)) for _ in range(1_000)]
dataset = MultiEpochDataset(docs, max_epochs=4)
total = sum(1 for _ in dataset)
print(f"Total samples: {total}, max repetitions: {max(dataset.epoch_counts)}")
assert max(dataset.epoch_counts) == 4, "Repetition limit violated"
print("All documents stay within the 4x repetition limit")
```

## Measuring Degradation Empirically

Degradation from data repetition is measured by training identical model architectures on 1x, 2x, 4x, and 8x repetitions of the same fixed dataset, then evaluating on a held-out set that was never repeated. The key is ensuring held-out data comes from the same distribution but is completely disjoint from training — otherwise the measurement conflates distribution shift with repetition effects. The metric is absolute validation loss and the percentage increase relative to the 1x baseline. Perplexity is less useful here because it grows exponentially with loss, amplifying small absolute changes.

```python
import random
import torch
import torch.nn as nn
from torch.utils.data import DataLoader, TensorDataset

def measure_repetition_degradation(token_corpus, rep_counts, seq_len=64, steps=300):
    """Train a tiny LM on corpus repeated N times; return eval loss per rep count."""
    vocab_size = max(token_corpus) + 1
    results = {}
    for reps in rep_counts:
        tokens = token_corpus * reps
        random.shuffle(tokens)
        seqs = [tokens[i:i+seq_len+1] for i in range(0, len(tokens)-seq_len, seq_len)]
        xs   = torch.tensor([s[:-1] for s in seqs])
        ys   = torch.tensor([s[1:]  for s in seqs])
        loader = DataLoader(TensorDataset(xs, ys), batch_size=64, shuffle=True)
        model  = nn.Sequential(nn.Embedding(vocab_size, 64), nn.Linear(64, vocab_size))
        opt    = torch.optim.Adam(model.parameters(), lr=3e-4)
        for step, (x, y) in zip(range(steps), loader):
            emb  = model[0](x).mean(1)
            loss = nn.functional.cross_entropy(model[1](emb), y[:, seq_len // 2])
            opt.zero_grad(); loss.backward(); opt.step()
        results[reps] = loss.item()
    return results

corpus = list(range(500)) * 200    # 100K token corpus
losses = measure_repetition_degradation(corpus, rep_counts=[1, 2, 4, 8])
base   = losses[1]
for r, l in losses.items():
    print(f"  {r}x: loss={l:.4f}  (+{(l - base) / base * 100:.1f}% vs 1x)")
```

## Domain-Specific Repetition Strategies

Not all data domains degrade equally with repetition. Repeated code data shows less loss degradation than repeated web text, possibly because code has more structured, learnable patterns with lower entropy. Books tolerate moderate repetition (3–4x) because signal density is high and redundancy is low. Web crawl text — the largest and noisiest source — should be kept at 1x wherever possible. The practical solution is a domain-weighted mixing schedule: assign per-domain epoch budgets that reflect each domain's repetition tolerance rather than repeating the entire corpus uniformly.

```python
import random
from typing import Dict, List

def build_mixed_dataset(domain_corpora: Dict[str, List], domain_epochs: Dict[str, int],
                        seed: int = 42) -> List:
    """Mix domain corpora with different repetition counts into one training set."""
    rng = random.Random(seed)
    mixed = []
    for domain, corpus in domain_corpora.items():
        epochs = domain_epochs.get(domain, 1)
        repeated = corpus * epochs
        rng.shuffle(repeated)
        mixed.extend(repeated)
        print(f"  {domain:10s}: {len(corpus):>8,} docs x {epochs}ep = {len(repeated):>8,} samples")
    rng.shuffle(mixed)    # global shuffle across all domains
    return mixed

# LLaMA-3.1-style domain mixing: high-quality sources get more repetitions
DOMAIN_CORPORA = {
    "books":  [f"book_doc_{i}"  for i in range(50_000)],
    "code":   [f"code_doc_{i}"  for i in range(80_000)],
    "web":    [f"web_doc_{i}"   for i in range(500_000)],
}
DOMAIN_EPOCHS = {"books": 4, "code": 2, "web": 1}  # stay below 4x for books
mixed = build_mixed_dataset(DOMAIN_CORPORA, DOMAIN_EPOCHS)
print(f"Total training samples: {len(mixed):,}")
```

## Model Memorization and Privacy Risk

Carlini et al. (2021, 2023) demonstrated that LLMs memorize training data verbatim in measurable ways, and that memorization rate scales with repetition count. A document appearing once is rarely extractable via prefix completion; a document appearing 100 times is often recoverable with a short prefix. Beyond quality degradation, memorization carries privacy and legal risk: PII in repeated documents, copyright text, or proprietary code can be extracted by adversaries. Measuring extraction rate — the fraction of training documents recoverable via greedy decoding given a 50-token prefix — is the standard empirical proxy for memorization.

```python
import torch
from typing import List

def compute_extraction_rate(model, tokenizer, train_docs: List[str],
                            prefix_len: int = 50, gen_len: int = 50,
                            match_threshold: float = 0.7) -> float:
    """Estimate fraction of training docs recoverable via greedy prefix completion."""
    extracted = 0
    for doc in train_docs:
        ids = tokenizer(doc, return_tensors="pt", truncation=True, max_length=200).input_ids
        prefix = ids[:, :prefix_len]
        suffix = ids[:, prefix_len:prefix_len + gen_len]
        with torch.no_grad():
            gen = model.generate(prefix, max_new_tokens=gen_len, do_sample=False)
        gen_suffix = gen[:, prefix_len:]
        min_len = min(gen_suffix.shape[1], suffix.shape[1])
        match = (gen_suffix[:, :min_len] == suffix[:, :min_len]).float().mean().item()
        extracted += int(match >= match_threshold)
    return extracted / len(train_docs)

# Synthetic proxy: memorization rate grows with repetition count
print("Repetition | Extraction Rate | Memorization Risk")
print("-" * 48)
for reps, rate in [(1, 0.02), (2, 0.06), (4, 0.15), (8, 0.31), (16, 0.52)]:
    risk = "Low" if rate < 0.1 else ("Medium" if rate < 0.3 else "High")
    print(f"   {reps:>2}x    |     {rate:.0%}          | {risk}")
```

## Mitigation Strategies

When the data budget is exhausted and additional repetition becomes necessary, several strategies reduce quality degradation. Data augmentation — back-translation, paraphrase models, sentence reordering — creates semantically similar but token-distinct variants that provide fresh signal. Mixing fresh web crawl snapshots with high-quality repeated sources dilutes the effective repetition rate. Curriculum learning, presenting less-repeated data later in training when the model is more capable, can help, though evidence for language models specifically is mixed. Deduplication is the complementary defense: aggressive MinHash or exact-match deduplication before training removes implicit repetition from near-duplicate web pages.

- Back-translation: translate documents to a second language and back to produce near-duplicate but token-distinct training examples.
- Paraphrase augmentation: use a separately trained paraphrase model to rewrite documents before each repetition epoch.
- Crawl diversification: mix fresh CommonCrawl snapshots from different months rather than repeating the same snapshot.
- Synthetic data insertion: use the model itself or a smaller teacher to generate text on training topics, injecting it as pseudo-fresh data.
- Domain epoch budgeting: assign per-source repetition limits rather than repeating the entire corpus uniformly.
- Pre-training deduplication: apply MinHash LSH or exact-match deduplication to remove near-duplicate web pages before any repetition counting.

## Synthetic Data and RLHF Considerations

Model-generated synthetic data serves as pseudo-fresh training signal: it has never appeared in the training set exactly as written, so it does not count as a repetition of existing documents. The risk is mode collapse — if synthetic data dominates, the model converges on its own outputs. Practical recipes (Phi-3, LLaMA-3.1) mix 5–20% synthetic data with fresh web crawls. RLHF preference data is always trained for a single epoch: human annotation is expensive, the dataset is small relative to pretraining corpora, and repeated passes cause severe overfitting on the reward signal rather than generalizable human preference.

| Repetitions | Loss Increase vs 1x | Memorization Rate | Recommended Limit | Notes |
| --- | --- | --- | --- | --- |
| 1x | 0% (baseline) | ~2% | Always safe | Chinchilla-optimal regime |
| 2x | ~1–2% | ~5–8% | All source types | Negligible quality impact |
| 4x | ~5% | ~15% | Books and code only | DeepMind threshold; avoid for web text |
| 8x | ~10–12% | ~30% | Code only | Significant memorization; avoid for books and web |
| 16x | ~18% | ~50% | Not recommended | Strong memorization artifacts, visible quality drop |
| 32x | ~20%+ | >60% | Never | DeepMind upper bound; severe degradation |

> **The 4x Repetition Threshold**: Beyond 4x repetition of the same documents, LLMs show significant memorization artifacts and downstream quality degradation — if you exhaust your data budget, invest in new data collection rather than additional repetition epochs.

---

