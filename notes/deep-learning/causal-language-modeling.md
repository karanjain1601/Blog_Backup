---
title: "Causal Language Modeling — Next-Token Prediction and Autoregressive Training"
slug: "causal-language-modeling"
description: "CLM trains decoder-only transformers (GPT, LLaMA, Mistral) to predict the next token from all prior tokens using cross-entropy loss over every sequence position simultaneously, making it the foundation of modern generative language models."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Causal Language Modeling (CLM) is the pretraining objective underlying the GPT family, LLaMA, Mistral, and virtually every modern large generative model. The objective is deceptively simple: given a sequence of tokens x₁, x₂, …, xₙ, learn the probability P(xₜ | x₁, …, xₜ₋₁) for every position t simultaneously. A single forward pass through the network computes predictions for all N positions at once — each position t sees only the tokens to its left, enforced by a lower-triangular causal attention mask. The cross-entropy loss is averaged over all N positions, making CLM roughly 6.7× more sample-efficient per forward pass than Masked Language Modeling, which only supervises ~15% of positions."},{"type":"heading","level":2,"content":"Next-Token Prediction Objective"},{"type":"text","content":"The training objective is to minimise the negative log-likelihood averaged over every token in the sequence: L = -(1/N) Σₜ log P(xₜ | x\u003cₜ). This is equivalent to minimising cross-entropy between the model\u0027s predicted distribution and the one-hot true token at each position. Targets are simply the inputs shifted by one: given input [x₁, …, xₙ], the target is [x₂, …, xₙ₊₁]. Teacher forcing means the true context is always fed during training, not the model\u0027s own predictions — this stabilises training but creates an exposure bias at inference time where errors can compound autoregressively."},{"type":"code","language":"python","content":"import torch\nfrom torch.utils.data import Dataset\nfrom torch.nn.utils.rnn import pad_sequence\nfrom transformers import GPT2Tokenizer\n\nclass CLMDataset(Dataset):\n    \"\"\"Dataset for CLM: tokenise text and create shifted input/target pairs.\"\"\"\n    def __init__(self, texts, tokenizer, max_length=512):\n        self.tokenizer = tokenizer\n        self.max_length = max_length\n        self.examples = []\n        for text in texts:\n            ids = tokenizer.encode(text, add_special_tokens=True)\n            for i in range(0, len(ids) - 1, max_length):\n                chunk = ids[i: i + max_length + 1]\n                if len(chunk) \u003e= 2:\n                    self.examples.append(chunk)\n\n    def __len__(self):\n        return len(self.examples)\n\n    def __getitem__(self, idx):\n        ids = self.examples[idx]\n        input_ids = torch.tensor(ids[:-1], dtype=torch.long)  # [x1, ..., xN]\n        labels    = torch.tensor(ids[1:],  dtype=torch.long)  # [x2, ..., xN+1]\n        return {\"input_ids\": input_ids, \"labels\": labels,\n                \"attention_mask\": torch.ones_like(input_ids)}\n\ndef clm_collate_fn(batch, pad_token_id=50256):\n    input_ids  = pad_sequence([b[\"input_ids\"]  for b in batch], batch_first=True, padding_value=pad_token_id)\n    labels     = pad_sequence([b[\"labels\"]     for b in batch], batch_first=True, padding_value=-100)\n    attn_masks = pad_sequence([b[\"attention_mask\"] for b in batch], batch_first=True, padding_value=0)\n    return {\"input_ids\": input_ids, \"labels\": labels, \"attention_mask\": attn_masks}"},{"type":"heading","level":2,"content":"Causal Attention Mask and Decoder-Only Architecture"},{"type":"text","content":"The causal (lower-triangular) attention mask is what makes CLM possible in a single forward pass. Position t may only attend to positions 1 … t. In PyTorch this is typically implemented as a boolean mask filled into the attention scores before softmax: positions that should be blocked receive -inf, collapsing to zero probability after softmax. Decoder-only transformers (GPT, LLaMA, Mistral) stack N such masked self-attention layers. There is no encoder — the model reads, reasons, and generates all in one stack, using the KV cache at inference time to avoid recomputing keys and values for the already-generated prefix."},{"type":"heading","level":2,"content":"Training with Teacher Forcing"},{"type":"text","content":"During training the model always receives the true token xₜ₋₁ as input to predict xₜ, regardless of whether it would have predicted something different. This is called teacher forcing. It keeps training stable and fast — the loss gradients flow through every position in every batch. The downside is exposure bias: at inference time the model autoregressively feeds its own predictions back as input, so a single error early in generation can corrupt the rest of the sequence. Scheduled sampling and RLHF fine-tuning partially address this."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom transformers import GPT2LMHeadModel, GPT2Config\n\ndef train_clm_epoch(model, dataloader, optimizer, scheduler, device, grad_clip=1.0):\n    \"\"\"One epoch of CLM training with teacher forcing and causal mask.\"\"\"\n    model.train()\n    total_loss, total_tokens = 0.0, 0\n    for batch in dataloader:\n        input_ids = batch[\"input_ids\"].to(device)\n        labels    = batch[\"labels\"].to(device)\n        attn_mask = batch[\"attention_mask\"].to(device)\n        # GPT2 applies causal mask internally; labels=-100 positions are ignored\n        outputs   = model(input_ids=input_ids, attention_mask=attn_mask, labels=labels)\n        loss      = outputs.loss\n        num_toks  = (labels != -100).sum().item()\n        optimizer.zero_grad()\n        loss.backward()\n        torch.nn.utils.clip_grad_norm_(model.parameters(), grad_clip)\n        optimizer.step()\n        scheduler.step()\n        total_loss   += loss.item() * num_toks\n        total_tokens += num_toks\n    return total_loss / max(total_tokens, 1)\n\nconfig = GPT2Config(vocab_size=50257, n_layer=12, n_head=12, n_embd=768)\nmodel  = GPT2LMHeadModel(config)\nprint(f\"GPT-2 small parameters: {sum(p.numel() for p in model.parameters()) / 1e6:.1f}M\")\nprint(\"CLM trains on every token position — N targets per sequence of length N.\")"},{"type":"heading","level":2,"content":"Perplexity and Evaluation"},{"type":"text","content":"Perplexity (PPL) is the standard CLM evaluation metric: PPL = exp(average NLL per token). A perplexity of 20 means the model is as surprised by each token as if it had to choose uniformly from 20 equally likely options. Lower perplexity indicates a better language model. For long documents, a sliding-window approach is used to avoid the model having no context at the beginning: a stride of half the context length ensures each token is eventually predicted with a full preceding context. GPT-2 achieves PPL ≈ 18.3 on WikiText-103; LLaMA-2 70B achieves PPL ≈ 3.3."},{"type":"code","language":"python","content":"import torch\nimport math\nfrom transformers import GPT2LMHeadModel, GPT2Tokenizer\n\ndef compute_perplexity(model, tokenizer, text, device, max_length=1024):\n    \"\"\"Sliding-window perplexity: exp(average NLL per token).\"\"\"\n    model.eval()\n    ids    = tokenizer.encode(text)\n    stride = max_length // 2\n    total_nll, total_tokens = 0.0, 0\n    for begin in range(0, len(ids), stride):\n        end   = min(begin + max_length, len(ids))\n        chunk = torch.tensor(ids[begin:end], dtype=torch.long).unsqueeze(0).to(device)\n        with torch.no_grad():\n            loss = model(chunk, labels=chunk).loss.item()\n        total_nll    += loss * chunk.size(1)\n        total_tokens += chunk.size(1)\n        if end == len(ids):\n            break\n    return math.exp(total_nll / total_tokens)\n\nmodel     = GPT2LMHeadModel.from_pretrained(\"gpt2\")\ntokenizer = GPT2Tokenizer.from_pretrained(\"gpt2\")\ndevice    = \"cuda\" if torch.cuda.is_available() else \"cpu\"\nmodel.to(device)\nsample    = \"Language models assign probability to sequences of tokens. \" * 10\nppl       = compute_perplexity(model, tokenizer, sample, device)\nprint(f\"Perplexity: {ppl:.2f}  (lower is better — exp(avg NLL per token))\")"},{"type":"callout","variant":"info","title":"CLM Sample Efficiency vs MLM","content":"CLM trains on every token position simultaneously (not just masked positions like MLM), making it ~6.7x more sample-efficient per forward pass — one document generates N training examples for a sequence of length N. MLM with 15% masking yields only 0.15N supervised predictions per forward pass."},{"type":"heading","level":2,"content":"Autoregressive Inference and KV Cache"},{"type":"text","content":"At inference time, generation is purely autoregressive: sample or argmax one token, append it to the context, and repeat. Greedy decoding picks the most probable token at each step; temperature sampling rescales logits before softmax; top-k and nucleus (top-p) sampling truncate the distribution to the most likely tokens. The KV cache stores key and value tensors from prior positions so that only the new token needs to be processed each step, reducing per-step compute from O(N²) to O(N) after the first forward pass."},{"type":"code","language":"python","content":"import torch\nfrom transformers import GPT2LMHeadModel, GPT2Tokenizer\n\ndef generate_autoregressive(model, tokenizer, prompt, max_new_tokens=80,\n                             temperature=1.0, top_k=50, device=\"cpu\"):\n    \"\"\"Autoregressive generation with top-k sampling and temperature scaling.\"\"\"\n    model.eval()\n    input_ids = tokenizer.encode(prompt, return_tensors=\"pt\").to(device)\n    with torch.no_grad():\n        for _ in range(max_new_tokens):\n            outputs = model(input_ids)\n            logits  = outputs.logits[:, -1, :] / temperature  # last position\n            if top_k \u003e 0:\n                values, _ = torch.topk(logits, top_k)\n                logits     = logits.masked_fill(logits \u003c values[:, -1:], float(\"-inf\"))\n            probs      = torch.softmax(logits, dim=-1)\n            next_token = torch.multinomial(probs, 1)\n            input_ids  = torch.cat([input_ids, next_token], dim=1)\n            if next_token.item() == tokenizer.eos_token_id:\n                break\n    prefix_len = len(tokenizer.encode(prompt))\n    return tokenizer.decode(input_ids[0, prefix_len:], skip_special_tokens=True)\n\nmodel     = GPT2LMHeadModel.from_pretrained(\"gpt2\")\ntokenizer = GPT2Tokenizer.from_pretrained(\"gpt2\")\noutput    = generate_autoregressive(model, tokenizer, \"Causal language models\", max_new_tokens=40)\nprint(\"Generated:\", output)"},{"type":"heading","level":2,"content":"CLM vs MLM vs Prefix LM"},{"type":"text","content":"The three major pretraining paradigms differ in how much context each position can attend to and what fraction of positions are supervised. CLM (decoder-only) predicts every token from left context only — maximally sample-efficient but limited to one-directional attention. MLM (encoder-only) uses bidirectional attention but only supervises ~15% of tokens per pass. Prefix LM (encoder-decoder) uses bidirectional attention over a prefix and causal attention over the continuation, giving a middle ground suitable for conditional generation tasks."},{"type":"table","headers":["Model Type","Directionality","Objective","Architecture","Sample Efficiency","Primary Use"],"rows":[["CLM","Left-to-right (causal)","Next-token prediction (all N positions)","Decoder-only (GPT, LLaMA, Mistral)","High — N targets per sequence","Text generation, in-context learning"],["MLM","Bidirectional (full)","Predict ~15% masked tokens","Encoder-only (BERT, RoBERTa)","Low — ~0.15N targets per sequence","Classification, NER, understanding"],["Prefix LM","Bidir prefix + causal cont.","Span prediction / text-to-text","Encoder-decoder (T5, FLAN-T5)","Medium — depends on mask rate","Seq2seq, conditional generation"]]},{"type":"heading","level":2,"content":"In-Context Learning and Multi-Task Formatting"},{"type":"text","content":"One of the most surprising properties of large CLMs is in-context learning (ICL): the model can solve new tasks at inference time simply by prepending a few examples to the prompt — no gradient update required. ICL emerges naturally from CLM pretraining because the model has learned to continue any prefix coherently, including task demonstrations. Multi-task learning is equally natural: any task can be expressed as a text sequence (sentiment classification → \u0027Review: ... Sentiment: positive\u0027), and a CLM trained on a mixture of such tasks generalises across all of them with no task-specific head."},{"type":"list","ordered":false,"items":["GPT-1 (117M, 2018): first CLM with transformer decoder, demonstrated transfer learning.","GPT-2 (1.5B, 2019): zero-shot task performance via prompt engineering — text completion as the universal interface.","GPT-3 (175B, 2020): few-shot in-context learning at scale; task examples in the prompt replace fine-tuning.","LLaMA (7B–65B, 2023): open-weights CLM trained longer on more data — matches GPT-3 at a fraction of the size.","Mistral 7B (2023): CLM with grouped-query attention and sliding-window attention — efficient long-context generation."]},{"type":"heading","level":2,"content":"GPT Family and the Road to LLaMA"},{"type":"text","content":"All models in the GPT lineage share the same CLM objective — the differences are scale, data quality, training duration, and architectural micro-choices. LLaMA introduced RMSNorm (instead of LayerNorm), rotary positional embeddings (RoPE, instead of learned absolute positions), SwiGLU activations (instead of GELU), and pre-norm order — all contributing to training stability at scale. Mistral added grouped-query attention (GQA) to reduce KV cache memory and sliding-window attention for efficient long contexts. Despite these changes, the loss function is identical: cross-entropy over every token position, every step."}]"
---
# Causal Language Modeling — Next-Token Prediction and Autoregressive Training

Causal Language Modeling (CLM) is the pretraining objective underlying the GPT family, LLaMA, Mistral, and virtually every modern large generative model. The objective is deceptively simple: given a sequence of tokens x₁, x₂, …, xₙ, learn the probability P(xₜ | x₁, …, xₜ₋₁) for every position t simultaneously. A single forward pass through the network computes predictions for all N positions at once — each position t sees only the tokens to its left, enforced by a lower-triangular causal attention mask. The cross-entropy loss is averaged over all N positions, making CLM roughly 6.7× more sample-efficient per forward pass than Masked Language Modeling, which only supervises ~15% of positions.

## Next-Token Prediction Objective

The training objective is to minimise the negative log-likelihood averaged over every token in the sequence: L = -(1/N) Σₜ log P(xₜ | x<ₜ). This is equivalent to minimising cross-entropy between the model's predicted distribution and the one-hot true token at each position. Targets are simply the inputs shifted by one: given input [x₁, …, xₙ], the target is [x₂, …, xₙ₊₁]. Teacher forcing means the true context is always fed during training, not the model's own predictions — this stabilises training but creates an exposure bias at inference time where errors can compound autoregressively.

```python
import torch
from torch.utils.data import Dataset
from torch.nn.utils.rnn import pad_sequence
from transformers import GPT2Tokenizer

class CLMDataset(Dataset):
    """Dataset for CLM: tokenise text and create shifted input/target pairs."""
    def __init__(self, texts, tokenizer, max_length=512):
        self.tokenizer = tokenizer
        self.max_length = max_length
        self.examples = []
        for text in texts:
            ids = tokenizer.encode(text, add_special_tokens=True)
            for i in range(0, len(ids) - 1, max_length):
                chunk = ids[i: i + max_length + 1]
                if len(chunk) >= 2:
                    self.examples.append(chunk)

    def __len__(self):
        return len(self.examples)

    def __getitem__(self, idx):
        ids = self.examples[idx]
        input_ids = torch.tensor(ids[:-1], dtype=torch.long)  # [x1, ..., xN]
        labels    = torch.tensor(ids[1:],  dtype=torch.long)  # [x2, ..., xN+1]
        return {"input_ids": input_ids, "labels": labels,
                "attention_mask": torch.ones_like(input_ids)}

def clm_collate_fn(batch, pad_token_id=50256):
    input_ids  = pad_sequence([b["input_ids"]  for b in batch], batch_first=True, padding_value=pad_token_id)
    labels     = pad_sequence([b["labels"]     for b in batch], batch_first=True, padding_value=-100)
    attn_masks = pad_sequence([b["attention_mask"] for b in batch], batch_first=True, padding_value=0)
    return {"input_ids": input_ids, "labels": labels, "attention_mask": attn_masks}
```

## Causal Attention Mask and Decoder-Only Architecture

The causal (lower-triangular) attention mask is what makes CLM possible in a single forward pass. Position t may only attend to positions 1 … t. In PyTorch this is typically implemented as a boolean mask filled into the attention scores before softmax: positions that should be blocked receive -inf, collapsing to zero probability after softmax. Decoder-only transformers (GPT, LLaMA, Mistral) stack N such masked self-attention layers. There is no encoder — the model reads, reasons, and generates all in one stack, using the KV cache at inference time to avoid recomputing keys and values for the already-generated prefix.

## Training with Teacher Forcing

During training the model always receives the true token xₜ₋₁ as input to predict xₜ, regardless of whether it would have predicted something different. This is called teacher forcing. It keeps training stable and fast — the loss gradients flow through every position in every batch. The downside is exposure bias: at inference time the model autoregressively feeds its own predictions back as input, so a single error early in generation can corrupt the rest of the sequence. Scheduled sampling and RLHF fine-tuning partially address this.

```python
import torch
import torch.nn as nn
from transformers import GPT2LMHeadModel, GPT2Config

def train_clm_epoch(model, dataloader, optimizer, scheduler, device, grad_clip=1.0):
    """One epoch of CLM training with teacher forcing and causal mask."""
    model.train()
    total_loss, total_tokens = 0.0, 0
    for batch in dataloader:
        input_ids = batch["input_ids"].to(device)
        labels    = batch["labels"].to(device)
        attn_mask = batch["attention_mask"].to(device)
        # GPT2 applies causal mask internally; labels=-100 positions are ignored
        outputs   = model(input_ids=input_ids, attention_mask=attn_mask, labels=labels)
        loss      = outputs.loss
        num_toks  = (labels != -100).sum().item()
        optimizer.zero_grad()
        loss.backward()
        torch.nn.utils.clip_grad_norm_(model.parameters(), grad_clip)
        optimizer.step()
        scheduler.step()
        total_loss   += loss.item() * num_toks
        total_tokens += num_toks
    return total_loss / max(total_tokens, 1)

config = GPT2Config(vocab_size=50257, n_layer=12, n_head=12, n_embd=768)
model  = GPT2LMHeadModel(config)
print(f"GPT-2 small parameters: {sum(p.numel() for p in model.parameters()) / 1e6:.1f}M")
print("CLM trains on every token position — N targets per sequence of length N.")
```

## Perplexity and Evaluation

Perplexity (PPL) is the standard CLM evaluation metric: PPL = exp(average NLL per token). A perplexity of 20 means the model is as surprised by each token as if it had to choose uniformly from 20 equally likely options. Lower perplexity indicates a better language model. For long documents, a sliding-window approach is used to avoid the model having no context at the beginning: a stride of half the context length ensures each token is eventually predicted with a full preceding context. GPT-2 achieves PPL ≈ 18.3 on WikiText-103; LLaMA-2 70B achieves PPL ≈ 3.3.

```python
import torch
import math
from transformers import GPT2LMHeadModel, GPT2Tokenizer

def compute_perplexity(model, tokenizer, text, device, max_length=1024):
    """Sliding-window perplexity: exp(average NLL per token)."""
    model.eval()
    ids    = tokenizer.encode(text)
    stride = max_length // 2
    total_nll, total_tokens = 0.0, 0
    for begin in range(0, len(ids), stride):
        end   = min(begin + max_length, len(ids))
        chunk = torch.tensor(ids[begin:end], dtype=torch.long).unsqueeze(0).to(device)
        with torch.no_grad():
            loss = model(chunk, labels=chunk).loss.item()
        total_nll    += loss * chunk.size(1)
        total_tokens += chunk.size(1)
        if end == len(ids):
            break
    return math.exp(total_nll / total_tokens)

model     = GPT2LMHeadModel.from_pretrained("gpt2")
tokenizer = GPT2Tokenizer.from_pretrained("gpt2")
device    = "cuda" if torch.cuda.is_available() else "cpu"
model.to(device)
sample    = "Language models assign probability to sequences of tokens. " * 10
ppl       = compute_perplexity(model, tokenizer, sample, device)
print(f"Perplexity: {ppl:.2f}  (lower is better — exp(avg NLL per token))")
```

> **CLM Sample Efficiency vs MLM**: CLM trains on every token position simultaneously (not just masked positions like MLM), making it ~6.7x more sample-efficient per forward pass — one document generates N training examples for a sequence of length N. MLM with 15% masking yields only 0.15N supervised predictions per forward pass.

## Autoregressive Inference and KV Cache

At inference time, generation is purely autoregressive: sample or argmax one token, append it to the context, and repeat. Greedy decoding picks the most probable token at each step; temperature sampling rescales logits before softmax; top-k and nucleus (top-p) sampling truncate the distribution to the most likely tokens. The KV cache stores key and value tensors from prior positions so that only the new token needs to be processed each step, reducing per-step compute from O(N²) to O(N) after the first forward pass.

```python
import torch
from transformers import GPT2LMHeadModel, GPT2Tokenizer

def generate_autoregressive(model, tokenizer, prompt, max_new_tokens=80,
                             temperature=1.0, top_k=50, device="cpu"):
    """Autoregressive generation with top-k sampling and temperature scaling."""
    model.eval()
    input_ids = tokenizer.encode(prompt, return_tensors="pt").to(device)
    with torch.no_grad():
        for _ in range(max_new_tokens):
            outputs = model(input_ids)
            logits  = outputs.logits[:, -1, :] / temperature  # last position
            if top_k > 0:
                values, _ = torch.topk(logits, top_k)
                logits     = logits.masked_fill(logits < values[:, -1:], float("-inf"))
            probs      = torch.softmax(logits, dim=-1)
            next_token = torch.multinomial(probs, 1)
            input_ids  = torch.cat([input_ids, next_token], dim=1)
            if next_token.item() == tokenizer.eos_token_id:
                break
    prefix_len = len(tokenizer.encode(prompt))
    return tokenizer.decode(input_ids[0, prefix_len:], skip_special_tokens=True)

model     = GPT2LMHeadModel.from_pretrained("gpt2")
tokenizer = GPT2Tokenizer.from_pretrained("gpt2")
output    = generate_autoregressive(model, tokenizer, "Causal language models", max_new_tokens=40)
print("Generated:", output)
```

## CLM vs MLM vs Prefix LM

The three major pretraining paradigms differ in how much context each position can attend to and what fraction of positions are supervised. CLM (decoder-only) predicts every token from left context only — maximally sample-efficient but limited to one-directional attention. MLM (encoder-only) uses bidirectional attention but only supervises ~15% of tokens per pass. Prefix LM (encoder-decoder) uses bidirectional attention over a prefix and causal attention over the continuation, giving a middle ground suitable for conditional generation tasks.

| Model Type | Directionality | Objective | Architecture | Sample Efficiency | Primary Use |
| --- | --- | --- | --- | --- | --- |
| CLM | Left-to-right (causal) | Next-token prediction (all N positions) | Decoder-only (GPT, LLaMA, Mistral) | High — N targets per sequence | Text generation, in-context learning |
| MLM | Bidirectional (full) | Predict ~15% masked tokens | Encoder-only (BERT, RoBERTa) | Low — ~0.15N targets per sequence | Classification, NER, understanding |
| Prefix LM | Bidir prefix + causal cont. | Span prediction / text-to-text | Encoder-decoder (T5, FLAN-T5) | Medium — depends on mask rate | Seq2seq, conditional generation |

## In-Context Learning and Multi-Task Formatting

One of the most surprising properties of large CLMs is in-context learning (ICL): the model can solve new tasks at inference time simply by prepending a few examples to the prompt — no gradient update required. ICL emerges naturally from CLM pretraining because the model has learned to continue any prefix coherently, including task demonstrations. Multi-task learning is equally natural: any task can be expressed as a text sequence (sentiment classification → 'Review: ... Sentiment: positive'), and a CLM trained on a mixture of such tasks generalises across all of them with no task-specific head.

- GPT-1 (117M, 2018): first CLM with transformer decoder, demonstrated transfer learning.
- GPT-2 (1.5B, 2019): zero-shot task performance via prompt engineering — text completion as the universal interface.
- GPT-3 (175B, 2020): few-shot in-context learning at scale; task examples in the prompt replace fine-tuning.
- LLaMA (7B–65B, 2023): open-weights CLM trained longer on more data — matches GPT-3 at a fraction of the size.
- Mistral 7B (2023): CLM with grouped-query attention and sliding-window attention — efficient long-context generation.

## GPT Family and the Road to LLaMA

All models in the GPT lineage share the same CLM objective — the differences are scale, data quality, training duration, and architectural micro-choices. LLaMA introduced RMSNorm (instead of LayerNorm), rotary positional embeddings (RoPE, instead of learned absolute positions), SwiGLU activations (instead of GELU), and pre-norm order — all contributing to training stability at scale. Mistral added grouped-query attention (GQA) to reduce KV cache memory and sliding-window attention for efficient long contexts. Despite these changes, the loss function is identical: cross-entropy over every token position, every step.

