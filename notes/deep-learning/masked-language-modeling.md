---
title: "Masked Language Modeling — BERT-Style Objective and Bidirectional Pretraining"
slug: "masked-language-modeling"
description: "MLM trains encoder-only transformers (BERT, RoBERTa, DeBERTa) to predict randomly masked tokens from full bidirectional context, using a 15% masking rate with an 80/10/10 replacement strategy, enabling rich contextual representations for downstream NLU tasks."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Masked Language Modeling (MLM), introduced in BERT (Devlin et al., 2018), learns bidirectional contextual representations by predicting randomly masked tokens from their full surrounding context. Unlike CLM which processes tokens left-to-right, MLM uses unrestricted attention — every token can attend to every other token in the sequence. This bidirectionality produces richer representations for understanding tasks: the representation of the word \u0027bank\u0027 in \u0027river bank\u0027 vs \u0027bank account\u0027 is disambiguated by context from both sides. The tradeoff is that MLM cannot generate text naturally, and it only supervises ~15% of token positions per forward pass, making it less compute-efficient for pretraining than CLM."},{"type":"heading","level":2,"content":"BERT Masking Strategy — The 80/10/10 Rule"},{"type":"text","content":"BERT randomly selects 15% of input tokens for masking, then applies a three-way strategy: 80% of selected tokens are replaced with the special [MASK] token; 10% are replaced with a random vocabulary token; 10% are kept unchanged. The 10% random replacement prevents the model from learning that only [MASK] positions need to be predicted — it must check every token. The 10% unchanged rate prevents a train/test mismatch where [MASK] tokens appear only during pretraining but never at fine-tuning time. The loss is computed only on the 15% masked positions, not on the full sequence."},{"type":"code","language":"python","content":"import torch\nfrom transformers import BertTokenizer\n\ndef mlm_mask_tokens(input_ids, tokenizer, mlm_prob=0.15):\n    \"\"\"BERT 80/10/10 masking: 80% [MASK], 10% random token, 10% unchanged.\"\"\"\n    labels = input_ids.clone()\n    prob_matrix = torch.full(labels.shape, mlm_prob)\n    special_ids = set(tokenizer.all_special_ids)\n    for i, row in enumerate(input_ids.tolist()):\n        for j, tok in enumerate(row):\n            if tok in special_ids:\n                prob_matrix[i, j] = 0.0  # never mask [CLS], [SEP], [PAD]\n    masked_indices = torch.bernoulli(prob_matrix).bool()\n    labels[~masked_indices] = -100          # loss only on masked positions\n    # 80%: replace with [MASK]\n    mask_80 = torch.bernoulli(torch.full(labels.shape, 0.8)).bool() \u0026 masked_indices\n    input_ids[mask_80] = tokenizer.mask_token_id\n    # 10%: replace with random token (half of remaining 20%)\n    rand_20  = (~mask_80) \u0026 masked_indices\n    mask_10  = torch.bernoulli(torch.full(labels.shape, 0.5)).bool() \u0026 rand_20\n    random_tokens = torch.randint(len(tokenizer), labels.shape, dtype=torch.long)\n    input_ids[mask_10] = random_tokens[mask_10]\n    # 10%: keep unchanged — the other half of rand_20, no action needed\n    return input_ids, labels\n\ntokenizer = BertTokenizer.from_pretrained(\"bert-base-uncased\")\ntext = \"The quick brown fox jumps over the lazy dog and runs away from the farmer\"\nids  = tokenizer(text, return_tensors=\"pt\", max_length=64, truncation=True)[\"input_ids\"]\nmasked_ids, labels = mlm_mask_tokens(ids.clone(), tokenizer)\nprint(f\"Sequence: {ids.size(1)} tokens | Masked: {(labels != -100).sum().item()} | [MASK]: {(masked_ids == tokenizer.mask_token_id).sum().item()}\")"},{"type":"heading","level":2,"content":"MLM Training Forward Pass"},{"type":"text","content":"The MLM training loop applies the masking collator on the fly (dynamic masking) so that each epoch sees different masked positions for the same text — this acts as implicit data augmentation. The model\u0027s loss is the cross-entropy between the predicted logit distribution and the true token ID, summed only over positions where labels ≠ -100. HuggingFace\u0027s BertForMaskedLM handles this automatically when labels are passed: it calls CrossEntropyLoss with ignore_index=-100 internally. Typical hyperparameters: learning rate 1e-4, warmup 10k steps, batch size 256, AdamW with weight decay 0.01."},{"type":"code","language":"python","content":"import torch\nfrom transformers import BertForMaskedLM, BertTokenizer\n\ndef train_mlm_step(model, batch, tokenizer, optimizer, device):\n    \"\"\"Single MLM training step: apply masking, forward pass, backprop.\"\"\"\n    input_ids  = batch[\"input_ids\"].clone().to(device)\n    attn_mask  = batch[\"attention_mask\"].to(device)\n    masked_ids, labels = mlm_mask_tokens(input_ids, tokenizer)\n    labels = labels.to(device)\n    outputs = model(\n        input_ids=masked_ids,\n        attention_mask=attn_mask,\n        labels=labels,            # BertForMaskedLM ignores label=-100 in loss\n    )\n    loss     = outputs.loss       # cross-entropy over masked positions only\n    n_masked = (labels != -100).sum().item()\n    optimizer.zero_grad()\n    loss.backward()\n    torch.nn.utils.clip_grad_norm_(model.parameters(), 1.0)\n    optimizer.step()\n    return loss.item(), n_masked\n\ndevice    = \"cuda\" if torch.cuda.is_available() else \"cpu\"\nmodel     = BertForMaskedLM.from_pretrained(\"bert-base-uncased\").to(device)\noptimizer = torch.optim.AdamW(model.parameters(), lr=1e-4, weight_decay=0.01)\nn_params  = sum(p.numel() for p in model.parameters()) / 1e6\nprint(f\"BERT-base parameters: {n_params:.0f}M\")\nprint(\"MLM loss is averaged only over ~15% masked positions, not all N tokens.\")"},{"type":"heading","level":2,"content":"Span Masking — SpanBERT Style"},{"type":"text","content":"Token-level masking (BERT) masks individual subword tokens independently, but span masking (SpanBERT, Joshi et al. 2020) masks contiguous spans of tokens drawn from a geometric distribution. Masking contiguous spans is harder because the model cannot use adjacent masked tokens as hints — it must rely on the full surrounding context. SpanBERT also introduces the Span Boundary Objective (SBO): predict each masked token using only the two boundary tokens on either side of the span, without seeing any tokens inside the span. Together, these changes produce significantly better performance on span-extraction tasks like SQuAD."},{"type":"code","language":"python","content":"import torch\nimport random\nimport math\nfrom transformers import BertTokenizer\n\ndef span_mask_tokens(input_ids, tokenizer, noise_density=0.15, mean_span=3.0):\n    \"\"\"SpanBERT-style geometric span masking on a 1D token sequence.\"\"\"\n    special_ids = set(tokenizer.all_special_ids)\n    seq = input_ids.tolist()\n    n   = len(seq)\n    target_n_masked = max(1, int(n * noise_density))\n    masked_positions = set()\n    while len(masked_positions) \u003c target_n_masked:\n        span_len = max(1, int(-mean_span * math.log(max(random.random(), 1e-10))))\n        start    = random.randint(0, n - 1)\n        for p in range(start, min(start + span_len, n)):\n            if seq[p] not in special_ids:\n                masked_positions.add(p)\n    result = input_ids.clone()\n    labels = input_ids.clone()\n    for p in range(n):\n        if p in masked_positions:\n            result[p] = tokenizer.mask_token_id\n        else:\n            labels[p] = -100\n    return result, labels\n\ntokenizer = BertTokenizer.from_pretrained(\"bert-base-uncased\")\nids = tokenizer.encode(\"Span masking selects contiguous token spans for masking\",\n                        return_tensors=\"pt\")[0]\nresult, labels = span_mask_tokens(ids, tokenizer)\nprint(f\"Tokens: {len(ids)} | Masked: {(labels != -100).sum().item()} spans masked\")"},{"type":"callout","variant":"warning","title":"MLM Compute Efficiency vs CLM","content":"MLM learns only 15% of positions per forward pass vs 100% for CLM — this means MLM requires significantly more data or epochs to see each token as a target, making it less compute-efficient per token for pretraining. RoBERTa addressed this with dynamic masking and much larger data (160GB vs BERT\u0027s 16GB), not a change to the objective itself."},{"type":"heading","level":2,"content":"BERT Fine-Tuning for Classification"},{"type":"text","content":"MLM pretraining learns general-purpose representations; task-specific adaptation is done by fine-tuning. For classification, a linear head is added on top of the [CLS] token representation (the first token, which aggregates sequence-level information through bidirectional attention). The full model (encoder + head) is then trained end-to-end on labelled data with a much smaller learning rate (2e-5 to 5e-5). Freezing the embedding layer while fine-tuning all transformer layers reduces the number of trainable parameters slightly and often improves stability on small datasets."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom transformers import BertModel, BertTokenizer\n\nclass BertClassifier(nn.Module):\n    \"\"\"BERT for sequence classification using [CLS] token representation.\"\"\"\n    def __init__(self, model_name=\"bert-base-uncased\", num_labels=2, freeze_emb=True):\n        super().__init__()\n        self.bert = BertModel.from_pretrained(model_name)\n        if freeze_emb:\n            for p in self.bert.embeddings.parameters():\n                p.requires_grad_(False)\n        hidden = self.bert.config.hidden_size   # 768 for BERT-base\n        self.classifier = nn.Sequential(nn.Dropout(0.1), nn.Linear(hidden, num_labels))\n\n    def forward(self, input_ids, attention_mask, token_type_ids=None):\n        out      = self.bert(input_ids=input_ids, attention_mask=attention_mask,\n                             token_type_ids=token_type_ids)\n        cls_repr = out.last_hidden_state[:, 0, :]   # [CLS] token at position 0\n        return self.classifier(cls_repr)\n\ndevice = \"cuda\" if torch.cuda.is_available() else \"cpu\"\nmodel  = BertClassifier(num_labels=2).to(device)\noptimizer = torch.optim.AdamW(\n    filter(lambda p: p.requires_grad, model.parameters()), lr=2e-5\n)\ntrainable = sum(p.numel() for p in model.parameters() if p.requires_grad)\nprint(f\"Trainable parameters: {trainable / 1e6:.1f}M (embeddings frozen)\")\nprint(\"Fine-tune [CLS] → linear head; no causal mask — full bidirectional attention.\")"},{"type":"heading","level":2,"content":"MLM Variants Compared"},{"type":"text","content":"The original BERT paper spawned a family of encoder-only models that refined the masking strategy, removed or replaced the Next Sentence Prediction (NSP) auxiliary task, and scaled data and compute. RoBERTa (Liu et al. 2019) was the first major ablation: dropping NSP, dynamic masking, and training 10× longer on 10× more data improved BERT\u0027s GLUE score substantially without any architectural change. DeBERTa introduced disentangled attention — separate embeddings for token content and relative position — setting new SOTA on many benchmarks."},{"type":"table","headers":["Model","Masking Strategy","NSP","Masking Ratio","Key Innovation"],"rows":[["BERT","Token-level 80/10/10","Yes","15%","Bidirectional pretraining with MLM + NSP"],["RoBERTa","Dynamic token masking","No","15%","More data, longer training, no NSP — strong baseline"],["DeBERTa","Token + position masking","No","15%","Disentangled attention: separate content and position"],["SpanBERT","Contiguous span masking","No","15%","SBO: predict spans using boundary token context only"],["ALBERT","Token-level (shared weights)","No (SOP)","15%","Cross-layer weight sharing + sentence order prediction"],["XLNet","Permutation language modeling","No","All positions","AR over random permutations — bidirectional without [MASK]"]]},{"type":"heading","level":2,"content":"Dynamic and Whole-Word Masking"},{"type":"text","content":"Static masking (original BERT) applies a fixed masking pattern to each training example once during preprocessing — the model sees the same masked version of each sentence every epoch. Dynamic masking (RoBERTa) re-applies the masking function at each training step, so the model sees different masked positions across epochs for the same text. Whole-word masking ensures that if a word is tokenised into multiple subword pieces, all pieces are masked or unmasked together — preventing the model from trivially predicting a masked subword from an adjacent visible subword of the same word."},{"type":"list","ordered":false,"items":["Static masking (BERT): masking applied once at data preprocessing — each epoch sees the same masks.","Dynamic masking (RoBERTa): masking resampled at each step — effective 10× more variation per training example.","Whole-word masking: mask all subwords of a word together — prevents subword leakage (e.g. \u0027##ing\u0027 visible when \u0027run\u0027 is masked).","Span masking (SpanBERT): mask contiguous spans from geometric distribution with mean 3.8 tokens.","Entity/phrase masking (ERNIE, Baidu): always mask complete named entities or phrases — better entity-level representations."]},{"type":"heading","level":2,"content":"NSP and Its Removal in RoBERTa"},{"type":"text","content":"BERT was pretrained with a second objective: Next Sentence Prediction (NSP). Given two sentence segments A and B, the model must predict whether B naturally follows A (50% positive, 50% negative where B is sampled from a random document). The idea was to learn inter-sentence coherence. However, RoBERTa\u0027s ablation studies showed NSP slightly hurts performance: the task is too easy (random negatives are distinguishable by topic alone), and it forces artificially short training documents. Removing NSP and training on full documents improved every downstream benchmark. Later models (ALBERT) replaced NSP with Sentence Order Prediction (SOP), which is harder — the negative is the same two sentences in reverse order."},{"type":"heading","level":2,"content":"Bidirectional Attention Architecture"},{"type":"text","content":"The key architectural difference between BERT (encoder) and GPT (decoder) is the attention mask. BERT uses full bidirectional attention: no mask is applied, so every token attends to every other token including future tokens. This is implemented identically to standard multi-head self-attention but without the lower-triangular mask. The consequence is that BERT cannot generate text autoregressively — computing P(xₜ | x\u003cₜ) is undefined under bidirectional attention. Instead, BERT\u0027s strength is producing a single contextualised representation for each input token, which serves as a feature for classification, named entity recognition, question answering, and other understanding tasks."}]"
---
# Masked Language Modeling — BERT-Style Objective and Bidirectional Pretraining

Masked Language Modeling (MLM), introduced in BERT (Devlin et al., 2018), learns bidirectional contextual representations by predicting randomly masked tokens from their full surrounding context. Unlike CLM which processes tokens left-to-right, MLM uses unrestricted attention — every token can attend to every other token in the sequence. This bidirectionality produces richer representations for understanding tasks: the representation of the word 'bank' in 'river bank' vs 'bank account' is disambiguated by context from both sides. The tradeoff is that MLM cannot generate text naturally, and it only supervises ~15% of token positions per forward pass, making it less compute-efficient for pretraining than CLM.

## BERT Masking Strategy — The 80/10/10 Rule

BERT randomly selects 15% of input tokens for masking, then applies a three-way strategy: 80% of selected tokens are replaced with the special [MASK] token; 10% are replaced with a random vocabulary token; 10% are kept unchanged. The 10% random replacement prevents the model from learning that only [MASK] positions need to be predicted — it must check every token. The 10% unchanged rate prevents a train/test mismatch where [MASK] tokens appear only during pretraining but never at fine-tuning time. The loss is computed only on the 15% masked positions, not on the full sequence.

```python
import torch
from transformers import BertTokenizer

def mlm_mask_tokens(input_ids, tokenizer, mlm_prob=0.15):
    """BERT 80/10/10 masking: 80% [MASK], 10% random token, 10% unchanged."""
    labels = input_ids.clone()
    prob_matrix = torch.full(labels.shape, mlm_prob)
    special_ids = set(tokenizer.all_special_ids)
    for i, row in enumerate(input_ids.tolist()):
        for j, tok in enumerate(row):
            if tok in special_ids:
                prob_matrix[i, j] = 0.0  # never mask [CLS], [SEP], [PAD]
    masked_indices = torch.bernoulli(prob_matrix).bool()
    labels[~masked_indices] = -100          # loss only on masked positions
    # 80%: replace with [MASK]
    mask_80 = torch.bernoulli(torch.full(labels.shape, 0.8)).bool() & masked_indices
    input_ids[mask_80] = tokenizer.mask_token_id
    # 10%: replace with random token (half of remaining 20%)
    rand_20  = (~mask_80) & masked_indices
    mask_10  = torch.bernoulli(torch.full(labels.shape, 0.5)).bool() & rand_20
    random_tokens = torch.randint(len(tokenizer), labels.shape, dtype=torch.long)
    input_ids[mask_10] = random_tokens[mask_10]
    # 10%: keep unchanged — the other half of rand_20, no action needed
    return input_ids, labels

tokenizer = BertTokenizer.from_pretrained("bert-base-uncased")
text = "The quick brown fox jumps over the lazy dog and runs away from the farmer"
ids  = tokenizer(text, return_tensors="pt", max_length=64, truncation=True)["input_ids"]
masked_ids, labels = mlm_mask_tokens(ids.clone(), tokenizer)
print(f"Sequence: {ids.size(1)} tokens | Masked: {(labels != -100).sum().item()} | [MASK]: {(masked_ids == tokenizer.mask_token_id).sum().item()}")
```

## MLM Training Forward Pass

The MLM training loop applies the masking collator on the fly (dynamic masking) so that each epoch sees different masked positions for the same text — this acts as implicit data augmentation. The model's loss is the cross-entropy between the predicted logit distribution and the true token ID, summed only over positions where labels ≠ -100. HuggingFace's BertForMaskedLM handles this automatically when labels are passed: it calls CrossEntropyLoss with ignore_index=-100 internally. Typical hyperparameters: learning rate 1e-4, warmup 10k steps, batch size 256, AdamW with weight decay 0.01.

```python
import torch
from transformers import BertForMaskedLM, BertTokenizer

def train_mlm_step(model, batch, tokenizer, optimizer, device):
    """Single MLM training step: apply masking, forward pass, backprop."""
    input_ids  = batch["input_ids"].clone().to(device)
    attn_mask  = batch["attention_mask"].to(device)
    masked_ids, labels = mlm_mask_tokens(input_ids, tokenizer)
    labels = labels.to(device)
    outputs = model(
        input_ids=masked_ids,
        attention_mask=attn_mask,
        labels=labels,            # BertForMaskedLM ignores label=-100 in loss
    )
    loss     = outputs.loss       # cross-entropy over masked positions only
    n_masked = (labels != -100).sum().item()
    optimizer.zero_grad()
    loss.backward()
    torch.nn.utils.clip_grad_norm_(model.parameters(), 1.0)
    optimizer.step()
    return loss.item(), n_masked

device    = "cuda" if torch.cuda.is_available() else "cpu"
model     = BertForMaskedLM.from_pretrained("bert-base-uncased").to(device)
optimizer = torch.optim.AdamW(model.parameters(), lr=1e-4, weight_decay=0.01)
n_params  = sum(p.numel() for p in model.parameters()) / 1e6
print(f"BERT-base parameters: {n_params:.0f}M")
print("MLM loss is averaged only over ~15% masked positions, not all N tokens.")
```

## Span Masking — SpanBERT Style

Token-level masking (BERT) masks individual subword tokens independently, but span masking (SpanBERT, Joshi et al. 2020) masks contiguous spans of tokens drawn from a geometric distribution. Masking contiguous spans is harder because the model cannot use adjacent masked tokens as hints — it must rely on the full surrounding context. SpanBERT also introduces the Span Boundary Objective (SBO): predict each masked token using only the two boundary tokens on either side of the span, without seeing any tokens inside the span. Together, these changes produce significantly better performance on span-extraction tasks like SQuAD.

```python
import torch
import random
import math
from transformers import BertTokenizer

def span_mask_tokens(input_ids, tokenizer, noise_density=0.15, mean_span=3.0):
    """SpanBERT-style geometric span masking on a 1D token sequence."""
    special_ids = set(tokenizer.all_special_ids)
    seq = input_ids.tolist()
    n   = len(seq)
    target_n_masked = max(1, int(n * noise_density))
    masked_positions = set()
    while len(masked_positions) < target_n_masked:
        span_len = max(1, int(-mean_span * math.log(max(random.random(), 1e-10))))
        start    = random.randint(0, n - 1)
        for p in range(start, min(start + span_len, n)):
            if seq[p] not in special_ids:
                masked_positions.add(p)
    result = input_ids.clone()
    labels = input_ids.clone()
    for p in range(n):
        if p in masked_positions:
            result[p] = tokenizer.mask_token_id
        else:
            labels[p] = -100
    return result, labels

tokenizer = BertTokenizer.from_pretrained("bert-base-uncased")
ids = tokenizer.encode("Span masking selects contiguous token spans for masking",
                        return_tensors="pt")[0]
result, labels = span_mask_tokens(ids, tokenizer)
print(f"Tokens: {len(ids)} | Masked: {(labels != -100).sum().item()} spans masked")
```

> **MLM Compute Efficiency vs CLM**: MLM learns only 15% of positions per forward pass vs 100% for CLM — this means MLM requires significantly more data or epochs to see each token as a target, making it less compute-efficient per token for pretraining. RoBERTa addressed this with dynamic masking and much larger data (160GB vs BERT's 16GB), not a change to the objective itself.

## BERT Fine-Tuning for Classification

MLM pretraining learns general-purpose representations; task-specific adaptation is done by fine-tuning. For classification, a linear head is added on top of the [CLS] token representation (the first token, which aggregates sequence-level information through bidirectional attention). The full model (encoder + head) is then trained end-to-end on labelled data with a much smaller learning rate (2e-5 to 5e-5). Freezing the embedding layer while fine-tuning all transformer layers reduces the number of trainable parameters slightly and often improves stability on small datasets.

```python
import torch
import torch.nn as nn
from transformers import BertModel, BertTokenizer

class BertClassifier(nn.Module):
    """BERT for sequence classification using [CLS] token representation."""
    def __init__(self, model_name="bert-base-uncased", num_labels=2, freeze_emb=True):
        super().__init__()
        self.bert = BertModel.from_pretrained(model_name)
        if freeze_emb:
            for p in self.bert.embeddings.parameters():
                p.requires_grad_(False)
        hidden = self.bert.config.hidden_size   # 768 for BERT-base
        self.classifier = nn.Sequential(nn.Dropout(0.1), nn.Linear(hidden, num_labels))

    def forward(self, input_ids, attention_mask, token_type_ids=None):
        out      = self.bert(input_ids=input_ids, attention_mask=attention_mask,
                             token_type_ids=token_type_ids)
        cls_repr = out.last_hidden_state[:, 0, :]   # [CLS] token at position 0
        return self.classifier(cls_repr)

device = "cuda" if torch.cuda.is_available() else "cpu"
model  = BertClassifier(num_labels=2).to(device)
optimizer = torch.optim.AdamW(
    filter(lambda p: p.requires_grad, model.parameters()), lr=2e-5
)
trainable = sum(p.numel() for p in model.parameters() if p.requires_grad)
print(f"Trainable parameters: {trainable / 1e6:.1f}M (embeddings frozen)")
print("Fine-tune [CLS] → linear head; no causal mask — full bidirectional attention.")
```

## MLM Variants Compared

The original BERT paper spawned a family of encoder-only models that refined the masking strategy, removed or replaced the Next Sentence Prediction (NSP) auxiliary task, and scaled data and compute. RoBERTa (Liu et al. 2019) was the first major ablation: dropping NSP, dynamic masking, and training 10× longer on 10× more data improved BERT's GLUE score substantially without any architectural change. DeBERTa introduced disentangled attention — separate embeddings for token content and relative position — setting new SOTA on many benchmarks.

| Model | Masking Strategy | NSP | Masking Ratio | Key Innovation |
| --- | --- | --- | --- | --- |
| BERT | Token-level 80/10/10 | Yes | 15% | Bidirectional pretraining with MLM + NSP |
| RoBERTa | Dynamic token masking | No | 15% | More data, longer training, no NSP — strong baseline |
| DeBERTa | Token + position masking | No | 15% | Disentangled attention: separate content and position |
| SpanBERT | Contiguous span masking | No | 15% | SBO: predict spans using boundary token context only |
| ALBERT | Token-level (shared weights) | No (SOP) | 15% | Cross-layer weight sharing + sentence order prediction |
| XLNet | Permutation language modeling | No | All positions | AR over random permutations — bidirectional without [MASK] |

## Dynamic and Whole-Word Masking

Static masking (original BERT) applies a fixed masking pattern to each training example once during preprocessing — the model sees the same masked version of each sentence every epoch. Dynamic masking (RoBERTa) re-applies the masking function at each training step, so the model sees different masked positions across epochs for the same text. Whole-word masking ensures that if a word is tokenised into multiple subword pieces, all pieces are masked or unmasked together — preventing the model from trivially predicting a masked subword from an adjacent visible subword of the same word.

- Static masking (BERT): masking applied once at data preprocessing — each epoch sees the same masks.
- Dynamic masking (RoBERTa): masking resampled at each step — effective 10× more variation per training example.
- Whole-word masking: mask all subwords of a word together — prevents subword leakage (e.g. '##ing' visible when 'run' is masked).
- Span masking (SpanBERT): mask contiguous spans from geometric distribution with mean 3.8 tokens.
- Entity/phrase masking (ERNIE, Baidu): always mask complete named entities or phrases — better entity-level representations.

## NSP and Its Removal in RoBERTa

BERT was pretrained with a second objective: Next Sentence Prediction (NSP). Given two sentence segments A and B, the model must predict whether B naturally follows A (50% positive, 50% negative where B is sampled from a random document). The idea was to learn inter-sentence coherence. However, RoBERTa's ablation studies showed NSP slightly hurts performance: the task is too easy (random negatives are distinguishable by topic alone), and it forces artificially short training documents. Removing NSP and training on full documents improved every downstream benchmark. Later models (ALBERT) replaced NSP with Sentence Order Prediction (SOP), which is harder — the negative is the same two sentences in reverse order.

## Bidirectional Attention Architecture

The key architectural difference between BERT (encoder) and GPT (decoder) is the attention mask. BERT uses full bidirectional attention: no mask is applied, so every token attends to every other token including future tokens. This is implemented identically to standard multi-head self-attention but without the lower-triangular mask. The consequence is that BERT cannot generate text autoregressively — computing P(xₜ | x<ₜ) is undefined under bidirectional attention. Instead, BERT's strength is producing a single contextualised representation for each input token, which serves as a feature for classification, named entity recognition, question answering, and other understanding tasks.

