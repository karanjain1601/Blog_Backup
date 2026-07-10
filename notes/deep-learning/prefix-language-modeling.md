---
title: "Prefix Language Modeling — T5 Span Corruption and Mixed Training Objectives"
slug: "prefix-language-modeling"
description: "Prefix LM combines bidirectional attention over a prefix with causal autoregressive generation for the continuation; T5 implements this via span corruption with sentinel tokens and a unified text-to-text format that casts every NLP task as sequence-to-sequence generation."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Prefix Language Modeling sits between CLM and MLM: a prefix (input prompt) is processed with full bidirectional attention so every prefix token can attend to every other prefix token, then the continuation is generated autoregressively with causal attention. This architecture naturally suits conditional generation — the encoder-like prefix understanding enables rich conditioning, while the decoder-like continuation enables generative flexibility. T5 (Raffel et al., 2020) operationalises this with span corruption: replace random 15% text spans with sentinel tokens (\u003cextra_id_0\u003e, \u003cextra_id_1\u003e, …) and train the model to predict the dropped spans. All tasks — classification, summarisation, translation, QA — are cast as text-to-text pairs."},{"type":"heading","level":2,"content":"T5 Span Corruption Objective"},{"type":"text","content":"T5\u0027s pretraining objective corrupts the input by removing contiguous spans of tokens and replacing each span with a unique sentinel token. The target sequence consists of those sentinels each followed by the original tokens of the corresponding span, terminated by a final sentinel and EOS. Span lengths are sampled from a geometric distribution with a mean of 3 tokens, giving a mix of short (1–2 token) and occasionally long (5–10 token) spans. Because spans typically contain 3 tokens but are replaced by a single sentinel, the input sequence is ~10% shorter than the original and the target is ~3–4× shorter than the original dropped tokens — making both encoder and decoder passes computationally cheap."},{"type":"code","language":"python","content":"import torch\nimport random\nimport math\nfrom transformers import T5Tokenizer\n\ndef t5_span_corruption(tokens, tokenizer, noise_density=0.15, mean_span=3.0):\n    \"\"\"T5 span corruption: replace random spans with \u003cextra_id_N\u003e sentinel tokens.\"\"\"\n    n         = len(tokens)\n    num_noise = max(1, int(n * noise_density))\n    spans, total = [], 0\n    while total \u003c num_noise:\n        length = max(1, min(int(-mean_span * math.log(max(random.random(), 1e-9))), n // 4))\n        spans.append(length)\n        total += length\n    max_start = max(1, n - max(spans))\n    starts    = sorted(random.sample(range(max_start), min(len(spans), max_start)))\n    sentinel_base = tokenizer.convert_tokens_to_ids(\"\u003cextra_id_0\u003e\")\n    inp, tgt, pos = [], [], 0\n    for idx, (start, length) in enumerate(zip(starts, spans)):\n        end = min(start + length, n)\n        inp.extend(tokens[pos:start])          # keep non-corrupted tokens\n        inp.append(sentinel_base - idx)        # \u003cextra_id_idx\u003e replaces span\n        tgt.append(sentinel_base - idx)        # target: sentinel then original tokens\n        tgt.extend(tokens[start:end])\n        pos = end\n    inp.extend(tokens[pos:])\n    tgt.append(tokenizer.eos_token_id)\n    return torch.tensor(inp, dtype=torch.long), torch.tensor(tgt, dtype=torch.long)\n\ntokenizer = T5Tokenizer.from_pretrained(\"t5-small\")\ntext   = \"Pretraining objectives determine how well a language model generalizes to new tasks\"\ntokens = tokenizer.encode(text)[:-1]\ninp, tgt = t5_span_corruption(tokens, tokenizer)\nprint(f\"Original: {len(tokens)} | Input: {len(inp)} | Target: {len(tgt)}\")\nprint(\"Input :\", tokenizer.decode(inp))\nprint(\"Target:\", tokenizer.decode(tgt))"},{"type":"heading","level":2,"content":"Prefix LM Attention Mask"},{"type":"text","content":"The prefix LM attention pattern is a hybrid: prefix tokens form a fully connected (bidirectional) block — every prefix token can attend to every other prefix token in both directions. Continuation tokens form a causal block — each continuation token can attend to all prefix tokens and all prior continuation tokens but not future ones. In an encoder-decoder model like T5 this is implemented naturally by the cross-attention mechanism: the encoder computes fully bidirectional representations of the corrupted input (the prefix), and the decoder attends to those representations via cross-attention while applying a causal self-attention mask over the generated tokens so far."},{"type":"code","language":"python","content":"import torch\nimport math\n\ndef build_prefix_lm_mask(seq_len, prefix_len, device=\"cpu\"):\n    \"\"\"Prefix LM mask: prefix bidirectional, continuation causal.\n    Returns (seq_len, seq_len) bool tensor; True = allowed to attend.\"\"\"\n    mask = torch.zeros(seq_len, seq_len, dtype=torch.bool, device=device)\n    mask[:prefix_len, :prefix_len] = True   # prefix attends to all prefix\n    for i in range(prefix_len, seq_len):\n        mask[i, :i + 1] = True             # continuation: causal window\n    return mask\n\ndef scaled_dot_product_prefix_lm(Q, K, V, prefix_len):\n    \"\"\"Attention with prefix LM mask applied in a single call.\"\"\"\n    seq_len = Q.size(-2)\n    d_k     = Q.size(-1)\n    scores  = torch.matmul(Q, K.transpose(-2, -1)) / math.sqrt(d_k)\n    mask    = build_prefix_lm_mask(seq_len, prefix_len, Q.device)\n    scores  = scores.masked_fill(~mask, float(\"-inf\"))\n    weights = torch.softmax(scores, dim=-1)\n    return torch.matmul(weights, V), weights\n\nseq_len, prefix_len, d_k = 12, 5, 64\nQ = torch.randn(1, seq_len, d_k)\nK = torch.randn(1, seq_len, d_k)\nV = torch.randn(1, seq_len, d_k)\nout, attn = scaled_dot_product_prefix_lm(Q, K, V, prefix_len)\nmask = build_prefix_lm_mask(seq_len, prefix_len)\nprint(f\"Prefix ({prefix_len} tokens): attend to {mask[:prefix_len,:prefix_len].sum(1).float().mean():.0f} tokens avg (full prefix)\")\nprint(f\"Continuation ({seq_len-prefix_len} tokens): causal — prefix + prior tokens only\")\nprint(f\"Output shape: {out.shape}\")"},{"type":"heading","level":2,"content":"Text-to-Text Task Formatting"},{"type":"text","content":"T5\u0027s most influential design decision is the text-to-text format: every NLP task is expressed as a mapping from an input text string to an output text string. Classification becomes string output (\u0027positive\u0027, \u0027negative\u0027, \u0027neutral\u0027); regression becomes a numeric string; translation is self-evident; QA maps \u0027question: ... context: ...\u0027 to an answer string. A task-specific prefix (e.g. \u0027sst2 sentence:\u0027, \u0027summarize:\u0027, \u0027translate English to German:\u0027) routes the model to the appropriate behaviour. This unification means a single model can handle dozens of tasks with no architecture changes, only prompt changes — the precursor to modern instruction-tuned models."},{"type":"code","language":"python","content":"from transformers import T5Tokenizer\n\nTASK_TEMPLATES = {\n    \"classification\": (\"sst2 sentence: {text}\", \"{label}\"),\n    \"summarization\":  (\"summarize: {text}\", \"{summary}\"),\n    \"translation\":    (\"translate English to German: {text}\", \"{translation}\"),\n    \"nli\":            (\"mnli hypothesis: {hypothesis} premise: {premise}\", \"{label}\"),\n    \"qa\":             (\"question: {question} context: {context}\", \"{answer}\"),\n}\n\ndef format_text_to_text(task, **kwargs):\n    tmpl_in, tmpl_out = TASK_TEMPLATES[task]\n    return tmpl_in.format(**kwargs), tmpl_out.format(**kwargs)\n\ntokenizer = T5Tokenizer.from_pretrained(\"t5-small\")\nexamples  = [\n    format_text_to_text(\"classification\", text=\"The film was breathtaking.\", label=\"positive\"),\n    format_text_to_text(\"translation\", text=\"Deep learning is powerful.\", translation=\"Deep Learning ist machtvoll.\"),\n    format_text_to_text(\"qa\", question=\"What is T5?\",\n                        context=\"T5 is a text-to-text transfer transformer.\",\n                        answer=\"text-to-text transfer transformer\"),\n    format_text_to_text(\"summarization\",\n                        text=\"T5 converts every NLP task into text-to-text format using an encoder-decoder.\",\n                        summary=\"T5 unifies NLP tasks as text-to-text.\"),\n]\nfor inp, tgt in examples:\n    enc_in  = tokenizer.encode(inp)\n    enc_tgt = tokenizer.encode(tgt)\n    print(f\"[{len(enc_in):3d} in | {len(enc_tgt):2d} tgt] {inp[:55]}...\")\n    print(f\"  Target: {tgt}\\n\")"},{"type":"callout","variant":"tip","title":"T5 Span Corruption vs Word-Level Masking","content":"T5\u0027s span corruption creates 3.4x shorter target sequences than SpanBERT\u0027s word-level masking for the same 15% masking rate — this significantly reduces decoder compute during pretraining while maintaining span-level context recovery. A mean span of 3 tokens means one sentinel replaces 3 tokens in the input, compressing the target to roughly 1/3 of the dropped-token count."},{"type":"heading","level":2,"content":"FLAN-T5 Zero-Shot Inference"},{"type":"text","content":"FLAN-T5 (Wei et al. 2022, Chung et al. 2022) fine-tunes T5 on a massive mixture of instruction-formatted tasks — over 1800 tasks phrased as natural language instructions across multiple benchmarks. This instruction tuning dramatically improves zero-shot and few-shot performance: the model learns to follow free-form instructions rather than only task-specific prefixes. FLAN-T5-XXL (11B parameters) matches or exceeds GPT-3 (175B) on many benchmarks, demonstrating that instruction diversity matters more than raw scale for zero-shot generalisation."},{"type":"code","language":"python","content":"import torch\nfrom transformers import T5ForConditionalGeneration, T5Tokenizer\n\ndevice    = \"cuda\" if torch.cuda.is_available() else \"cpu\"\nmodel     = T5ForConditionalGeneration.from_pretrained(\"google/flan-t5-base\").to(device)\ntokenizer = T5Tokenizer.from_pretrained(\"google/flan-t5-base\")\nmodel.eval()\n\ndef flan_t5_predict(prompt, max_new_tokens=64, num_beams=4):\n    \"\"\"Zero-shot FLAN-T5 inference for arbitrary instruction-formatted tasks.\"\"\"\n    inputs = tokenizer(prompt, return_tensors=\"pt\", truncation=True,\n                       max_length=512).to(device)\n    with torch.no_grad():\n        out = model.generate(**inputs, max_new_tokens=max_new_tokens,\n                             num_beams=num_beams, early_stopping=True)\n    return tokenizer.decode(out[0], skip_special_tokens=True)\n\nprompts = [\n    \"Classify sentiment (positive/negative): \u0027This lecture on transformers was outstanding!\u0027\",\n    \"Translate to French: \u0027The quick brown fox jumps over the lazy dog.\u0027\",\n    \"Answer: What pretraining objective does T5 use? Context: T5 uses span corruption.\",\n]\nfor prompt in prompts:\n    answer = flan_t5_predict(prompt)\n    print(f\"Q: {prompt[:60]}...\")\n    print(f\"A: {answer}\\n\")"},{"type":"heading","level":2,"content":"Comparison of Pretraining Objectives"},{"type":"text","content":"The three paradigms — CLM, MLM, and Prefix LM / Encoder-Decoder — represent fundamental trade-offs between generation capability, representation richness, and compute efficiency. CLM is the simplest and most sample-efficient, making it dominant for large-scale pretraining. MLM produces the richest token-level representations for understanding but cannot generate. Prefix LM / Encoder-Decoder is the most powerful for conditional generation tasks but requires paired input-output data for task formatting and is more expensive to train (two components)."},{"type":"table","headers":["Aspect","CLM","MLM","Prefix LM","Encoder-Decoder"],"rows":[["Attention type","Causal (left-to-right)","Bidirectional (full)","Bidir prefix + causal continuation","Encoder: full; Decoder: causal"],["Training target","All N tokens (shifted)","~15% masked tokens","Dropped span tokens + sentinels","Target sequence tokens"],["Generation","Native autoregressive","Not native — needs separate decoder","Native continuation of prefix","Native via cross-attention decoding"],["Sample efficiency","High — N targets/seq","Low — ~0.15N targets/seq","Medium — depends on span density","Depends on paired data quality"],["Key models","GPT, LLaMA, Mistral","BERT, RoBERTa, DeBERTa","PaLM (suffix prediction)","T5, FLAN-T5, BART, mT5"]]},{"type":"heading","level":2,"content":"UL2 — Mixture of Objectives"},{"type":"text","content":"UL2 (Tay et al. 2022) proposes training a single model with a mixture of denoising objectives, calling it Mixture-of-Denoisers (MoD). Three objective families are mixed: R-denoisers (CLM-like: predict a suffix), S-denoisers (span corruption like T5 with short spans), and X-denoisers (extreme span corruption with very long spans or high masking rates). A mode token ([R], [S], [X]) prepended to the input tells the model which denoising regime applies. UL2-20B outperforms GPT-3 175B on many benchmarks, showing that objective diversity during pretraining is a more efficient use of compute than scaling a single objective."},{"type":"list","ordered":false,"items":["R-denoiser: predict suffix from prefix — identical to CLM, encourages left-to-right generation.","S-denoiser: T5-style span corruption with short spans (mean 3 tokens, 15% rate) — standard seq2seq.","X-denoiser: extreme corruption — very long spans (mean 32 tokens) or high rate (50%) — forces full document reconstruction.","Mode token ([R], [S], [X]) prepended to input routes the model to the correct denoising behaviour.","UL2 unifies GPT-style generation and T5-style seq2seq in one model without architectural changes."]},{"type":"heading","level":2,"content":"Compute Efficiency of Prefix LM"},{"type":"text","content":"A practical advantage of the encoder-decoder architecture is that the encoder computes prefix representations only once per generation request. In CLM, re-processing the entire prompt is required for each new token (mitigated by KV cache), and the prefix tokens compete for context length with generated tokens. In encoder-decoder models, the prefix is processed by the encoder at full attention complexity once, then its key-value representations are passed to the decoder via cross-attention for all generation steps. This separation means the encoder can process very long contexts without burdening the decoder. T5 11B achieves strong performance across diverse tasks while remaining more interpretable than same-size CLM models due to this explicit input-output separation."},{"type":"heading","level":2,"content":"PaLM and Prefix Prediction"},{"type":"text","content":"PaLM (Chowdhery et al., 2022), a 540B parameter decoder-only model, also incorporates a prefix-style training variant called suffix prediction: a fraction of training examples are formatted so that a random suffix of the document is moved to the beginning, and the model learns to complete the document from a position in the middle. This exposes the CLM-only model to bidirectional context during pretraining without requiring an encoder. Combined with chain-of-thought prompting, PaLM achieves human-level performance on a wide range of multi-step reasoning tasks, suggesting that pretraining objective diversity — even within a decoder-only framework — significantly improves generalisation."}]"
---
# Prefix Language Modeling — T5 Span Corruption and Mixed Training Objectives

Prefix Language Modeling sits between CLM and MLM: a prefix (input prompt) is processed with full bidirectional attention so every prefix token can attend to every other prefix token, then the continuation is generated autoregressively with causal attention. This architecture naturally suits conditional generation — the encoder-like prefix understanding enables rich conditioning, while the decoder-like continuation enables generative flexibility. T5 (Raffel et al., 2020) operationalises this with span corruption: replace random 15% text spans with sentinel tokens (<extra_id_0>, <extra_id_1>, …) and train the model to predict the dropped spans. All tasks — classification, summarisation, translation, QA — are cast as text-to-text pairs.

## T5 Span Corruption Objective

T5's pretraining objective corrupts the input by removing contiguous spans of tokens and replacing each span with a unique sentinel token. The target sequence consists of those sentinels each followed by the original tokens of the corresponding span, terminated by a final sentinel and EOS. Span lengths are sampled from a geometric distribution with a mean of 3 tokens, giving a mix of short (1–2 token) and occasionally long (5–10 token) spans. Because spans typically contain 3 tokens but are replaced by a single sentinel, the input sequence is ~10% shorter than the original and the target is ~3–4× shorter than the original dropped tokens — making both encoder and decoder passes computationally cheap.

```python
import torch
import random
import math
from transformers import T5Tokenizer

def t5_span_corruption(tokens, tokenizer, noise_density=0.15, mean_span=3.0):
    """T5 span corruption: replace random spans with <extra_id_N> sentinel tokens."""
    n         = len(tokens)
    num_noise = max(1, int(n * noise_density))
    spans, total = [], 0
    while total < num_noise:
        length = max(1, min(int(-mean_span * math.log(max(random.random(), 1e-9))), n // 4))
        spans.append(length)
        total += length
    max_start = max(1, n - max(spans))
    starts    = sorted(random.sample(range(max_start), min(len(spans), max_start)))
    sentinel_base = tokenizer.convert_tokens_to_ids("<extra_id_0>")
    inp, tgt, pos = [], [], 0
    for idx, (start, length) in enumerate(zip(starts, spans)):
        end = min(start + length, n)
        inp.extend(tokens[pos:start])          # keep non-corrupted tokens
        inp.append(sentinel_base - idx)        # <extra_id_idx> replaces span
        tgt.append(sentinel_base - idx)        # target: sentinel then original tokens
        tgt.extend(tokens[start:end])
        pos = end
    inp.extend(tokens[pos:])
    tgt.append(tokenizer.eos_token_id)
    return torch.tensor(inp, dtype=torch.long), torch.tensor(tgt, dtype=torch.long)

tokenizer = T5Tokenizer.from_pretrained("t5-small")
text   = "Pretraining objectives determine how well a language model generalizes to new tasks"
tokens = tokenizer.encode(text)[:-1]
inp, tgt = t5_span_corruption(tokens, tokenizer)
print(f"Original: {len(tokens)} | Input: {len(inp)} | Target: {len(tgt)}")
print("Input :", tokenizer.decode(inp))
print("Target:", tokenizer.decode(tgt))
```

## Prefix LM Attention Mask

The prefix LM attention pattern is a hybrid: prefix tokens form a fully connected (bidirectional) block — every prefix token can attend to every other prefix token in both directions. Continuation tokens form a causal block — each continuation token can attend to all prefix tokens and all prior continuation tokens but not future ones. In an encoder-decoder model like T5 this is implemented naturally by the cross-attention mechanism: the encoder computes fully bidirectional representations of the corrupted input (the prefix), and the decoder attends to those representations via cross-attention while applying a causal self-attention mask over the generated tokens so far.

```python
import torch
import math

def build_prefix_lm_mask(seq_len, prefix_len, device="cpu"):
    """Prefix LM mask: prefix bidirectional, continuation causal.
    Returns (seq_len, seq_len) bool tensor; True = allowed to attend."""
    mask = torch.zeros(seq_len, seq_len, dtype=torch.bool, device=device)
    mask[:prefix_len, :prefix_len] = True   # prefix attends to all prefix
    for i in range(prefix_len, seq_len):
        mask[i, :i + 1] = True             # continuation: causal window
    return mask

def scaled_dot_product_prefix_lm(Q, K, V, prefix_len):
    """Attention with prefix LM mask applied in a single call."""
    seq_len = Q.size(-2)
    d_k     = Q.size(-1)
    scores  = torch.matmul(Q, K.transpose(-2, -1)) / math.sqrt(d_k)
    mask    = build_prefix_lm_mask(seq_len, prefix_len, Q.device)
    scores  = scores.masked_fill(~mask, float("-inf"))
    weights = torch.softmax(scores, dim=-1)
    return torch.matmul(weights, V), weights

seq_len, prefix_len, d_k = 12, 5, 64
Q = torch.randn(1, seq_len, d_k)
K = torch.randn(1, seq_len, d_k)
V = torch.randn(1, seq_len, d_k)
out, attn = scaled_dot_product_prefix_lm(Q, K, V, prefix_len)
mask = build_prefix_lm_mask(seq_len, prefix_len)
print(f"Prefix ({prefix_len} tokens): attend to {mask[:prefix_len,:prefix_len].sum(1).float().mean():.0f} tokens avg (full prefix)")
print(f"Continuation ({seq_len-prefix_len} tokens): causal — prefix + prior tokens only")
print(f"Output shape: {out.shape}")
```

## Text-to-Text Task Formatting

T5's most influential design decision is the text-to-text format: every NLP task is expressed as a mapping from an input text string to an output text string. Classification becomes string output ('positive', 'negative', 'neutral'); regression becomes a numeric string; translation is self-evident; QA maps 'question: ... context: ...' to an answer string. A task-specific prefix (e.g. 'sst2 sentence:', 'summarize:', 'translate English to German:') routes the model to the appropriate behaviour. This unification means a single model can handle dozens of tasks with no architecture changes, only prompt changes — the precursor to modern instruction-tuned models.

```python
from transformers import T5Tokenizer

TASK_TEMPLATES = {
    "classification": ("sst2 sentence: {text}", "{label}"),
    "summarization":  ("summarize: {text}", "{summary}"),
    "translation":    ("translate English to German: {text}", "{translation}"),
    "nli":            ("mnli hypothesis: {hypothesis} premise: {premise}", "{label}"),
    "qa":             ("question: {question} context: {context}", "{answer}"),
}

def format_text_to_text(task, **kwargs):
    tmpl_in, tmpl_out = TASK_TEMPLATES[task]
    return tmpl_in.format(**kwargs), tmpl_out.format(**kwargs)

tokenizer = T5Tokenizer.from_pretrained("t5-small")
examples  = [
    format_text_to_text("classification", text="The film was breathtaking.", label="positive"),
    format_text_to_text("translation", text="Deep learning is powerful.", translation="Deep Learning ist machtvoll."),
    format_text_to_text("qa", question="What is T5?",
                        context="T5 is a text-to-text transfer transformer.",
                        answer="text-to-text transfer transformer"),
    format_text_to_text("summarization",
                        text="T5 converts every NLP task into text-to-text format using an encoder-decoder.",
                        summary="T5 unifies NLP tasks as text-to-text."),
]
for inp, tgt in examples:
    enc_in  = tokenizer.encode(inp)
    enc_tgt = tokenizer.encode(tgt)
    print(f"[{len(enc_in):3d} in | {len(enc_tgt):2d} tgt] {inp[:55]}...")
    print(f"  Target: {tgt}\n")
```

> **T5 Span Corruption vs Word-Level Masking**: T5's span corruption creates 3.4x shorter target sequences than SpanBERT's word-level masking for the same 15% masking rate — this significantly reduces decoder compute during pretraining while maintaining span-level context recovery. A mean span of 3 tokens means one sentinel replaces 3 tokens in the input, compressing the target to roughly 1/3 of the dropped-token count.

## FLAN-T5 Zero-Shot Inference

FLAN-T5 (Wei et al. 2022, Chung et al. 2022) fine-tunes T5 on a massive mixture of instruction-formatted tasks — over 1800 tasks phrased as natural language instructions across multiple benchmarks. This instruction tuning dramatically improves zero-shot and few-shot performance: the model learns to follow free-form instructions rather than only task-specific prefixes. FLAN-T5-XXL (11B parameters) matches or exceeds GPT-3 (175B) on many benchmarks, demonstrating that instruction diversity matters more than raw scale for zero-shot generalisation.

```python
import torch
from transformers import T5ForConditionalGeneration, T5Tokenizer

device    = "cuda" if torch.cuda.is_available() else "cpu"
model     = T5ForConditionalGeneration.from_pretrained("google/flan-t5-base").to(device)
tokenizer = T5Tokenizer.from_pretrained("google/flan-t5-base")
model.eval()

def flan_t5_predict(prompt, max_new_tokens=64, num_beams=4):
    """Zero-shot FLAN-T5 inference for arbitrary instruction-formatted tasks."""
    inputs = tokenizer(prompt, return_tensors="pt", truncation=True,
                       max_length=512).to(device)
    with torch.no_grad():
        out = model.generate(**inputs, max_new_tokens=max_new_tokens,
                             num_beams=num_beams, early_stopping=True)
    return tokenizer.decode(out[0], skip_special_tokens=True)

prompts = [
    "Classify sentiment (positive/negative): 'This lecture on transformers was outstanding!'",
    "Translate to French: 'The quick brown fox jumps over the lazy dog.'",
    "Answer: What pretraining objective does T5 use? Context: T5 uses span corruption.",
]
for prompt in prompts:
    answer = flan_t5_predict(prompt)
    print(f"Q: {prompt[:60]}...")
    print(f"A: {answer}\n")
```

## Comparison of Pretraining Objectives

The three paradigms — CLM, MLM, and Prefix LM / Encoder-Decoder — represent fundamental trade-offs between generation capability, representation richness, and compute efficiency. CLM is the simplest and most sample-efficient, making it dominant for large-scale pretraining. MLM produces the richest token-level representations for understanding but cannot generate. Prefix LM / Encoder-Decoder is the most powerful for conditional generation tasks but requires paired input-output data for task formatting and is more expensive to train (two components).

| Aspect | CLM | MLM | Prefix LM | Encoder-Decoder |
| --- | --- | --- | --- | --- |
| Attention type | Causal (left-to-right) | Bidirectional (full) | Bidir prefix + causal continuation | Encoder: full; Decoder: causal |
| Training target | All N tokens (shifted) | ~15% masked tokens | Dropped span tokens + sentinels | Target sequence tokens |
| Generation | Native autoregressive | Not native — needs separate decoder | Native continuation of prefix | Native via cross-attention decoding |
| Sample efficiency | High — N targets/seq | Low — ~0.15N targets/seq | Medium — depends on span density | Depends on paired data quality |
| Key models | GPT, LLaMA, Mistral | BERT, RoBERTa, DeBERTa | PaLM (suffix prediction) | T5, FLAN-T5, BART, mT5 |

## UL2 — Mixture of Objectives

UL2 (Tay et al. 2022) proposes training a single model with a mixture of denoising objectives, calling it Mixture-of-Denoisers (MoD). Three objective families are mixed: R-denoisers (CLM-like: predict a suffix), S-denoisers (span corruption like T5 with short spans), and X-denoisers (extreme span corruption with very long spans or high masking rates). A mode token ([R], [S], [X]) prepended to the input tells the model which denoising regime applies. UL2-20B outperforms GPT-3 175B on many benchmarks, showing that objective diversity during pretraining is a more efficient use of compute than scaling a single objective.

- R-denoiser: predict suffix from prefix — identical to CLM, encourages left-to-right generation.
- S-denoiser: T5-style span corruption with short spans (mean 3 tokens, 15% rate) — standard seq2seq.
- X-denoiser: extreme corruption — very long spans (mean 32 tokens) or high rate (50%) — forces full document reconstruction.
- Mode token ([R], [S], [X]) prepended to input routes the model to the correct denoising behaviour.
- UL2 unifies GPT-style generation and T5-style seq2seq in one model without architectural changes.

## Compute Efficiency of Prefix LM

A practical advantage of the encoder-decoder architecture is that the encoder computes prefix representations only once per generation request. In CLM, re-processing the entire prompt is required for each new token (mitigated by KV cache), and the prefix tokens compete for context length with generated tokens. In encoder-decoder models, the prefix is processed by the encoder at full attention complexity once, then its key-value representations are passed to the decoder via cross-attention for all generation steps. This separation means the encoder can process very long contexts without burdening the decoder. T5 11B achieves strong performance across diverse tasks while remaining more interpretable than same-size CLM models due to this explicit input-output separation.

## PaLM and Prefix Prediction

PaLM (Chowdhery et al., 2022), a 540B parameter decoder-only model, also incorporates a prefix-style training variant called suffix prediction: a fraction of training examples are formatted so that a random suffix of the document is moved to the beginning, and the model learns to complete the document from a position in the middle. This exposes the CLM-only model to bidirectional context during pretraining without requiring an encoder. Combined with chain-of-thought prompting, PaLM achieves human-level performance on a wide range of multi-step reasoning tasks, suggesting that pretraining objective diversity — even within a decoder-only framework — significantly improves generalisation.

