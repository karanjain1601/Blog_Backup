---
title: "SentencePiece — Unigram Language Model Tokenizer and Byte Fallback"
slug: "sentencepiece-tokenizer"
description: "How SentencePiece processes raw Unicode without pre-tokenization, the Unigram LM algorithm with EM training and pruning, byte fallback for rare characters, and subword regularization."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"SentencePiece is a language-independent tokenizer used by LLaMA, Gemma, Mistral, T5, and ALBERT. Unlike BPE implementations that first split text on whitespace, SentencePiece treats the input as a raw Unicode byte stream—whitespace is just another character. Words are not assumed to be separated by spaces, making the tokenizer suitable for Chinese, Japanese, Thai, and other languages without space-delimited words. SentencePiece supports two algorithms: BPE mode (identical in principle to GPT-2 BPE) and Unigram Language Model mode. The Unigram LM mode is the default for most modern models; it produces a probabilistic vocabulary and supports subword regularization during training—sampling multiple valid tokenizations of the same text to improve model robustness."},{"type":"heading","level":2,"content":"Introduction"},{"type":"text","content":"SentencePiece\u0027s self-contained .model file encodes the full vocabulary, algorithm, and special token configuration, making tokenization deterministic and portable across frameworks and languages. The _ prefix (U+2581 LOWER ONE EIGHTH BLOCK) marks the beginning of a word in place of GPT-2\u0027s Ġ byte-level space encoding. A sequence like \u0027▁hello▁world\u0027 tokenized as [\u0027▁hello\u0027, \u0027▁world\u0027] preserves the leading-space information needed to reconstruct the original text. LLaMA-1 uses a 32K SentencePiece Unigram vocabulary; LLaMA-3 switched to tiktoken BPE at 128K tokens; Gemma retains SentencePiece with 256K vocabulary."},{"type":"heading","level":2,"content":"Raw Unicode Processing"},{"type":"text","content":"Because SentencePiece processes raw Unicode without pre-tokenization, a space at position i is treated identically to any other character. This means \u0027hello world\u0027 and \u0027helloworld\u0027 produce different token sequences, and the tokenizer can learn that \u0027▁\u0027 (space) is a meaningful boundary signal without being explicitly programmed to split on whitespace. SentencePiece normalises input using Unicode NFKC by default, which maps compatibility characters to their canonical forms (e.g., full-width digits to ASCII digits). This normalisation can be disabled with normalization_rule_name=\u0027identity\u0027 when the model must handle raw text exactly."},{"type":"code","language":"python","content":"import sentencepiece as spm\nimport os, tempfile\n\n# Build a small training corpus\nlines = [\n    \u0027The quick brown fox jumps over the lazy dog.\u0027,\n    \u0027Natural language processing enables machines to understand text.\u0027,\n    \u0027Subword tokenization balances vocabulary size and sequence length.\u0027,\n    \u0027Byte-pair encoding and unigram models are the two main algorithms.\u0027,\n    \u0027SentencePiece processes raw Unicode without whitespace pre-splitting.\u0027,\n] * 60  # repeat to produce enough training data\n\nwith tempfile.NamedTemporaryFile(mode=\u0027w\u0027, suffix=\u0027.txt\u0027, delete=False, encoding=\u0027utf-8\u0027) as f:\n    f.write(\u0027\\n\u0027.join(lines))\n    corpus_file = f.name\n\nmodel_prefix = tempfile.mktemp()\nspm.SentencePieceTrainer.train(\n    input=corpus_file,\n    model_prefix=model_prefix,\n    vocab_size=300,\n    model_type=\u0027unigram\u0027,\n    character_coverage=0.9995,\n    pad_id=0, unk_id=1, bos_id=2, eos_id=3,\n)\nsp = spm.SentencePieceProcessor(model_file=model_prefix + \u0027.model\u0027)\n\ntest = \u0027The quick brown fox\u0027\nprint(f\u0027Text   : {test}\u0027)\nprint(f\u0027Tokens : {sp.encode(test, out_type=str)}\u0027)\nprint(f\u0027IDs    : {sp.encode(test, out_type=int)}\u0027)\nprint(f\u0027Vocab size: {sp.get_piece_size()}\u0027)\nprint(\u0027\\nTop 15 vocabulary pieces:\u0027)\nfor i in range(15):\n    print(f\u0027  [{i:3d}] {sp.id_to_piece(i)!r:\u003c20} score={sp.get_score(i):.4f}\u0027)\nos.unlink(corpus_file)"},{"type":"heading","level":2,"content":"Unigram Language Model Algorithm"},{"type":"text","content":"The Unigram LM tokenizer assigns a log-probability score p(t) to each token t in the vocabulary. The probability of a segmentation (t₁, t₂, …, t_k) of a word is p(t₁) × p(t₂) × … × p(t_k). The corpus log-likelihood is the sum of log p(best segmentation) over all words. Training starts with a large initial vocabulary (∼3× the target size, built from frequent substrings), then iteratively prunes it. At each EM iteration: (1) E-step: use the Viterbi algorithm to find the best segmentation of each word given the current probabilities; (2) M-step: update token probabilities using the segmentation counts; (3) prune tokens whose removal decreases corpus log-likelihood least, typically removing 10–20% of tokens per round. Repeat until the vocabulary reaches the target size V."},{"type":"code","language":"python","content":"import math\n\ndef viterbi_segment(word, unigram_log_probs, max_piece_len=8):\n    \"\"\"Viterbi best-path segmentation given unigram log-probabilities.\"\"\"\n    n = len(word)\n    best = [-math.inf] * (n + 1)\n    back = [None] * (n + 1)\n    best[0] = 0.0\n    for i in range(1, n + 1):\n        for j in range(max(0, i - max_piece_len), i):\n            piece = word[j:i]\n            lp = unigram_log_probs.get(piece, -math.inf)\n            score = best[j] + lp\n            if score \u003e best[i]:\n                best[i] = score\n                back[i] = j\n    if best[n] == -math.inf:\n        return [word]  # fallback: unknown word\n    tokens, i = [], n\n    while i \u003e 0:\n        j = back[i]\n        tokens.append(word[j:i])\n        i = j\n    return list(reversed(tokens))\n\n# Small example unigram vocabulary with log-probabilities\nunigram_lp = {\n    \u0027low\u0027: math.log(0.10), \u0027er\u0027: math.log(0.08), \u0027est\u0027: math.log(0.07),\n    \u0027new\u0027: math.log(0.09), \u0027wide\u0027: math.log(0.06), \u0027run\u0027: math.log(0.08),\n    \u0027lo\u0027: math.log(0.03), \u0027w\u0027: math.log(0.02), \u0027r\u0027: math.log(0.04),\n    \u0027n\u0027: math.log(0.02), \u0027e\u0027: math.log(0.05), \u0027s\u0027: math.log(0.03),\n    \u0027t\u0027: math.log(0.03), \u0027i\u0027: math.log(0.02), \u0027d\u0027: math.log(0.02),\n}\nwords = [\u0027lower\u0027, \u0027newest\u0027, \u0027wider\u0027, \u0027runner\u0027, \u0027lowest\u0027]\nprint(f\u0027{\"Word\":\u003c12} {\"Viterbi Segmentation\"}\u0027)\nfor w in words:\n    segs = viterbi_segment(w, unigram_lp)\n    print(f\u0027{w:\u003c12} {segs}\u0027)"},{"type":"heading","level":2,"content":"EM Training and Pruning"},{"type":"text","content":"EM training alternates between computing the best (or expected) segmentation of the corpus (E-step) and re-estimating token log-probabilities from segmentation counts (M-step). To prune, each token t is removed from the vocabulary and the loss in corpus log-likelihood is computed: tokens with the smallest loss impact are pruned. A pruning rate of 10–20% per round means that from an initial vocabulary of 100K, reaching a target of 32K takes roughly 5–8 rounds of EM + pruning. Unlike BPE (which adds tokens one by one), the Unigram LM approach works top-down by removing tokens, giving it more global control over the final vocabulary distribution."},{"type":"heading","level":2,"content":"Byte Fallback"},{"type":"text","content":"SentencePiece\u0027s byte fallback feature handles characters not covered by the vocabulary: any character that cannot be tokenized is split into its UTF-8 bytes, each encoded as a special token in the form \u003c0xHH\u003e where HH is the hex byte value. This guarantees that even rare CJK characters, emoji, or unusual Unicode can be encoded without [UNK]. LLaMA-1\u0027s tokenizer has 256 reserved byte fallback tokens (\u003c0x00\u003e through \u003c0xFF\u003e). The byte fallback vocabulary slots cost only 256 entries but enable complete Unicode coverage. Byte tokens have very low probability scores and are pruned last during Unigram LM training."},{"type":"code","language":"python","content":"# Demonstrate byte fallback encoding for rare Unicode characters\n# (without requiring a trained model)\n\ndef utf8_byte_tokens(char):\n    \"\"\"Return SentencePiece-style byte fallback tokens for a character.\"\"\"\n    return [f\u0027\u003c0x{b:02X}\u003e\u0027 for b in char.encode(\u0027utf-8\u0027)]\n\nrare_chars = [\n    (\u0027\\U0001F600\u0027, \u0027emoji (U+1F600)\u0027),\n    (\u0027\\u4e2d\u0027,     \u0027CJK \\u4e2d (U+4E2D)\u0027),\n    (\u0027\\u03b1\u0027,     \u0027Greek \\u03b1 (U+03B1)\u0027),\n    (\u0027\\u2192\u0027,     \u0027Arrow \\u2192 (U+2192)\u0027),\n    (\u0027\\u00f1\u0027,     \u0027Latin \\u00f1 (U+00F1)\u0027),\n    (\u0027\\u0436\u0027,     \u0027Cyrillic \\u0436 (U+0436)\u0027),\n]\nprint(\u0027Byte fallback encoding for rare Unicode characters:\u0027)\nprint(f\u0027{\"Char\":\u003c8} {\"Unicode\":\u003c22} {\"UTF-8 bytes\":\u003c20} {\"Fallback tokens\"}\u0027)\nprint(\u0027-\u0027 * 75)\nfor char, label in rare_chars:\n    utf8 = list(char.encode(\u0027utf-8\u0027))\n    tokens = utf8_byte_tokens(char)\n    print(f\u0027{repr(char):\u003c8} {label:\u003c22} {str(utf8):\u003c20} {tokens}\u0027)\n\nprint(\u0027\\nByte fallback uses 256 reserved token slots \u003c0x00\u003e...\u003c0xFF\u003e.\u0027)\nprint(\u0027Any Unicode character decomposes into at most 4 byte tokens.\u0027)"},{"type":"heading","level":2,"content":"Subword Regularization"},{"type":"text","content":"During training, subword regularization samples from the distribution of valid tokenizations rather than always using the Viterbi-best segmentation. For a word with probability distribution over valid token sequences, the E-step can sample instead of taking the argmax, exposing the model to multiple valid tokenizations of the same text. At inference time, the best (Viterbi) tokenization is used. Subword regularization is controlled by two parameters: nbest_size (number of candidate tokenizations to sample from; -1 = full lattice) and alpha (flatness of the sampling distribution; 0 = uniform, 1 = proportional to probability). It acts as a data augmentation technique that improves robustness to tokenization artifacts."},{"type":"code","language":"python","content":"import sentencepiece as spm\n\n# Reuse model trained in the first code block\nsp = spm.SentencePieceProcessor(model_file=model_prefix + \u0027.model\u0027)\n\ntext = \u0027natural language processing\u0027\nprint(f\u0027Text: {repr(text)}\u0027)\nprint()\n\n# Deterministic best segmentation\nbest = sp.encode(text, out_type=str)\nprint(f\u0027Best (Viterbi): {best}\u0027)\nprint()\n\n# Sample multiple tokenizations (subword regularization)\nprint(\u0027Sampled tokenizations (nbest_size=-1, alpha=0.1):\u0027)\nseen = set()\nfor _ in range(50):\n    sampled = sp.sample_encode(text, -1, 0.1, out_type=str)\n    key = \u0027|\u0027.join(sampled)\n    if key not in seen:\n        seen.add(key)\n        print(f\u0027  {sampled}\u0027)\n    if len(seen) \u003e= 6:\n        break\n\nprint()\nprint(f\u0027Unique segmentations found: {len(seen)}\u0027)\nprint(\u0027Use sample_encode during training to expose model to tokenization variants.\u0027)\nprint(\u0027At inference always use encode (Viterbi-best) for deterministic output.\u0027)"},{"type":"callout","variant":"tip","title":"Subword Regularization for Training Robustness","content":"Unigram LM tokenizer supports subword regularization (sample_encode with nbest_size=-1) during training — this exposes the model to multiple valid tokenizations of the same text, improving robustness to tokenization artifacts at inference. In practice, use alpha=0.1–0.2 (low alpha = near-best segmentation; high alpha = uniform random). Always switch to deterministic Viterbi encoding (sp.encode) at inference time to ensure consistent token sequences."},{"type":"heading","level":2,"content":"Practical Usage"},{"type":"text","content":"Load a SentencePiece model in Python with sentencepiece.SentencePieceProcessor(model_file=\u0027path.model\u0027). The .model binary file is fully self-contained: no additional vocabulary files are needed. HuggingFace wraps SentencePiece behind the LlamaTokenizer and T5Tokenizer classes, which add special token handling and the HuggingFace tokenizer API. When working with LLaMA-2, the BOS token (ID 1) must be prepended manually if using the raw SentencePiece API, as the model expects it; HuggingFace\u0027s LlamaTokenizer adds it automatically via add_special_tokens=True."},{"type":"table","headers":["Property","BPE Mode","Unigram LM Mode"],"rows":[["Training direction","Bottom-up: merge characters","Top-down: prune from large vocab"],["Merge criterion","Highest frequency count","Lowest log-likelihood loss on removal"],["Segmentation","Deterministic (merge order)","Probabilistic (Viterbi-best or sampled)"],["Handles rare chars","Byte-level BPE only","Yes, via byte fallback tokens"],["Vocabulary control","Exact (one slot per merge)","Approximate (pruning rate)"],["Subword regularization","No native support","Yes: sample_encode API"],["Used by","GPT-2/3/4, RoBERTa","T5, mT5, LLaMA-1/2, Gemma, Mistral"]]},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"list","ordered":false,"items":["SentencePiece treats whitespace as a regular character (marked with ▁), enabling language-agnostic tokenization without pre-splitting.","Unigram LM training starts with a large vocabulary and prunes iteratively using EM; unlike BPE it operates top-down.","Viterbi decoding finds the segmentation that maximises the product of unigram token probabilities.","Byte fallback encodes any Unicode character via its UTF-8 bytes as \u003c0xHH\u003e tokens, guaranteeing zero OOV with only 256 extra slots.","Subword regularization (sample_encode) samples from the tokenization distribution during training, improving model robustness.","The .model file is self-contained; the .vocab file is optional metadata. Ship only the .model file for inference.","LLaMA-1/2 use a 32K SentencePiece vocabulary; Gemma uses 256K. Larger vocabulary reduces fertility but requires more embedding parameters."]},{"type":"divider"}]"
---
# SentencePiece — Unigram Language Model Tokenizer and Byte Fallback

SentencePiece is a language-independent tokenizer used by LLaMA, Gemma, Mistral, T5, and ALBERT. Unlike BPE implementations that first split text on whitespace, SentencePiece treats the input as a raw Unicode byte stream—whitespace is just another character. Words are not assumed to be separated by spaces, making the tokenizer suitable for Chinese, Japanese, Thai, and other languages without space-delimited words. SentencePiece supports two algorithms: BPE mode (identical in principle to GPT-2 BPE) and Unigram Language Model mode. The Unigram LM mode is the default for most modern models; it produces a probabilistic vocabulary and supports subword regularization during training—sampling multiple valid tokenizations of the same text to improve model robustness.

## Introduction

SentencePiece's self-contained .model file encodes the full vocabulary, algorithm, and special token configuration, making tokenization deterministic and portable across frameworks and languages. The _ prefix (U+2581 LOWER ONE EIGHTH BLOCK) marks the beginning of a word in place of GPT-2's Ġ byte-level space encoding. A sequence like '▁hello▁world' tokenized as ['▁hello', '▁world'] preserves the leading-space information needed to reconstruct the original text. LLaMA-1 uses a 32K SentencePiece Unigram vocabulary; LLaMA-3 switched to tiktoken BPE at 128K tokens; Gemma retains SentencePiece with 256K vocabulary.

## Raw Unicode Processing

Because SentencePiece processes raw Unicode without pre-tokenization, a space at position i is treated identically to any other character. This means 'hello world' and 'helloworld' produce different token sequences, and the tokenizer can learn that '▁' (space) is a meaningful boundary signal without being explicitly programmed to split on whitespace. SentencePiece normalises input using Unicode NFKC by default, which maps compatibility characters to their canonical forms (e.g., full-width digits to ASCII digits). This normalisation can be disabled with normalization_rule_name='identity' when the model must handle raw text exactly.

```python
import sentencepiece as spm
import os, tempfile

# Build a small training corpus
lines = [
    'The quick brown fox jumps over the lazy dog.',
    'Natural language processing enables machines to understand text.',
    'Subword tokenization balances vocabulary size and sequence length.',
    'Byte-pair encoding and unigram models are the two main algorithms.',
    'SentencePiece processes raw Unicode without whitespace pre-splitting.',
] * 60  # repeat to produce enough training data

with tempfile.NamedTemporaryFile(mode='w', suffix='.txt', delete=False, encoding='utf-8') as f:
    f.write('\n'.join(lines))
    corpus_file = f.name

model_prefix = tempfile.mktemp()
spm.SentencePieceTrainer.train(
    input=corpus_file,
    model_prefix=model_prefix,
    vocab_size=300,
    model_type='unigram',
    character_coverage=0.9995,
    pad_id=0, unk_id=1, bos_id=2, eos_id=3,
)
sp = spm.SentencePieceProcessor(model_file=model_prefix + '.model')

test = 'The quick brown fox'
print(f'Text   : {test}')
print(f'Tokens : {sp.encode(test, out_type=str)}')
print(f'IDs    : {sp.encode(test, out_type=int)}')
print(f'Vocab size: {sp.get_piece_size()}')
print('\nTop 15 vocabulary pieces:')
for i in range(15):
    print(f'  [{i:3d}] {sp.id_to_piece(i)!r:<20} score={sp.get_score(i):.4f}')
os.unlink(corpus_file)
```

## Unigram Language Model Algorithm

The Unigram LM tokenizer assigns a log-probability score p(t) to each token t in the vocabulary. The probability of a segmentation (t₁, t₂, …, t_k) of a word is p(t₁) × p(t₂) × … × p(t_k). The corpus log-likelihood is the sum of log p(best segmentation) over all words. Training starts with a large initial vocabulary (∼3× the target size, built from frequent substrings), then iteratively prunes it. At each EM iteration: (1) E-step: use the Viterbi algorithm to find the best segmentation of each word given the current probabilities; (2) M-step: update token probabilities using the segmentation counts; (3) prune tokens whose removal decreases corpus log-likelihood least, typically removing 10–20% of tokens per round. Repeat until the vocabulary reaches the target size V.

```python
import math

def viterbi_segment(word, unigram_log_probs, max_piece_len=8):
    """Viterbi best-path segmentation given unigram log-probabilities."""
    n = len(word)
    best = [-math.inf] * (n + 1)
    back = [None] * (n + 1)
    best[0] = 0.0
    for i in range(1, n + 1):
        for j in range(max(0, i - max_piece_len), i):
            piece = word[j:i]
            lp = unigram_log_probs.get(piece, -math.inf)
            score = best[j] + lp
            if score > best[i]:
                best[i] = score
                back[i] = j
    if best[n] == -math.inf:
        return [word]  # fallback: unknown word
    tokens, i = [], n
    while i > 0:
        j = back[i]
        tokens.append(word[j:i])
        i = j
    return list(reversed(tokens))

# Small example unigram vocabulary with log-probabilities
unigram_lp = {
    'low': math.log(0.10), 'er': math.log(0.08), 'est': math.log(0.07),
    'new': math.log(0.09), 'wide': math.log(0.06), 'run': math.log(0.08),
    'lo': math.log(0.03), 'w': math.log(0.02), 'r': math.log(0.04),
    'n': math.log(0.02), 'e': math.log(0.05), 's': math.log(0.03),
    't': math.log(0.03), 'i': math.log(0.02), 'd': math.log(0.02),
}
words = ['lower', 'newest', 'wider', 'runner', 'lowest']
print(f'{"Word":<12} {"Viterbi Segmentation"}')
for w in words:
    segs = viterbi_segment(w, unigram_lp)
    print(f'{w:<12} {segs}')
```

## EM Training and Pruning

EM training alternates between computing the best (or expected) segmentation of the corpus (E-step) and re-estimating token log-probabilities from segmentation counts (M-step). To prune, each token t is removed from the vocabulary and the loss in corpus log-likelihood is computed: tokens with the smallest loss impact are pruned. A pruning rate of 10–20% per round means that from an initial vocabulary of 100K, reaching a target of 32K takes roughly 5–8 rounds of EM + pruning. Unlike BPE (which adds tokens one by one), the Unigram LM approach works top-down by removing tokens, giving it more global control over the final vocabulary distribution.

## Byte Fallback

SentencePiece's byte fallback feature handles characters not covered by the vocabulary: any character that cannot be tokenized is split into its UTF-8 bytes, each encoded as a special token in the form <0xHH> where HH is the hex byte value. This guarantees that even rare CJK characters, emoji, or unusual Unicode can be encoded without [UNK]. LLaMA-1's tokenizer has 256 reserved byte fallback tokens (<0x00> through <0xFF>). The byte fallback vocabulary slots cost only 256 entries but enable complete Unicode coverage. Byte tokens have very low probability scores and are pruned last during Unigram LM training.

```python
# Demonstrate byte fallback encoding for rare Unicode characters
# (without requiring a trained model)

def utf8_byte_tokens(char):
    """Return SentencePiece-style byte fallback tokens for a character."""
    return [f'<0x{b:02X}>' for b in char.encode('utf-8')]

rare_chars = [
    ('\U0001F600', 'emoji (U+1F600)'),
    ('\u4e2d',     'CJK \u4e2d (U+4E2D)'),
    ('\u03b1',     'Greek \u03b1 (U+03B1)'),
    ('\u2192',     'Arrow \u2192 (U+2192)'),
    ('\u00f1',     'Latin \u00f1 (U+00F1)'),
    ('\u0436',     'Cyrillic \u0436 (U+0436)'),
]
print('Byte fallback encoding for rare Unicode characters:')
print(f'{"Char":<8} {"Unicode":<22} {"UTF-8 bytes":<20} {"Fallback tokens"}')
print('-' * 75)
for char, label in rare_chars:
    utf8 = list(char.encode('utf-8'))
    tokens = utf8_byte_tokens(char)
    print(f'{repr(char):<8} {label:<22} {str(utf8):<20} {tokens}')

print('\nByte fallback uses 256 reserved token slots <0x00>...<0xFF>.')
print('Any Unicode character decomposes into at most 4 byte tokens.')
```

## Subword Regularization

During training, subword regularization samples from the distribution of valid tokenizations rather than always using the Viterbi-best segmentation. For a word with probability distribution over valid token sequences, the E-step can sample instead of taking the argmax, exposing the model to multiple valid tokenizations of the same text. At inference time, the best (Viterbi) tokenization is used. Subword regularization is controlled by two parameters: nbest_size (number of candidate tokenizations to sample from; -1 = full lattice) and alpha (flatness of the sampling distribution; 0 = uniform, 1 = proportional to probability). It acts as a data augmentation technique that improves robustness to tokenization artifacts.

```python
import sentencepiece as spm

# Reuse model trained in the first code block
sp = spm.SentencePieceProcessor(model_file=model_prefix + '.model')

text = 'natural language processing'
print(f'Text: {repr(text)}')
print()

# Deterministic best segmentation
best = sp.encode(text, out_type=str)
print(f'Best (Viterbi): {best}')
print()

# Sample multiple tokenizations (subword regularization)
print('Sampled tokenizations (nbest_size=-1, alpha=0.1):')
seen = set()
for _ in range(50):
    sampled = sp.sample_encode(text, -1, 0.1, out_type=str)
    key = '|'.join(sampled)
    if key not in seen:
        seen.add(key)
        print(f'  {sampled}')
    if len(seen) >= 6:
        break

print()
print(f'Unique segmentations found: {len(seen)}')
print('Use sample_encode during training to expose model to tokenization variants.')
print('At inference always use encode (Viterbi-best) for deterministic output.')
```

> **Subword Regularization for Training Robustness**: Unigram LM tokenizer supports subword regularization (sample_encode with nbest_size=-1) during training — this exposes the model to multiple valid tokenizations of the same text, improving robustness to tokenization artifacts at inference. In practice, use alpha=0.1–0.2 (low alpha = near-best segmentation; high alpha = uniform random). Always switch to deterministic Viterbi encoding (sp.encode) at inference time to ensure consistent token sequences.

## Practical Usage

Load a SentencePiece model in Python with sentencepiece.SentencePieceProcessor(model_file='path.model'). The .model binary file is fully self-contained: no additional vocabulary files are needed. HuggingFace wraps SentencePiece behind the LlamaTokenizer and T5Tokenizer classes, which add special token handling and the HuggingFace tokenizer API. When working with LLaMA-2, the BOS token (ID 1) must be prepended manually if using the raw SentencePiece API, as the model expects it; HuggingFace's LlamaTokenizer adds it automatically via add_special_tokens=True.

| Property | BPE Mode | Unigram LM Mode |
| --- | --- | --- |
| Training direction | Bottom-up: merge characters | Top-down: prune from large vocab |
| Merge criterion | Highest frequency count | Lowest log-likelihood loss on removal |
| Segmentation | Deterministic (merge order) | Probabilistic (Viterbi-best or sampled) |
| Handles rare chars | Byte-level BPE only | Yes, via byte fallback tokens |
| Vocabulary control | Exact (one slot per merge) | Approximate (pruning rate) |
| Subword regularization | No native support | Yes: sample_encode API |
| Used by | GPT-2/3/4, RoBERTa | T5, mT5, LLaMA-1/2, Gemma, Mistral |

## Key Takeaways

- SentencePiece treats whitespace as a regular character (marked with ▁), enabling language-agnostic tokenization without pre-splitting.
- Unigram LM training starts with a large vocabulary and prunes iteratively using EM; unlike BPE it operates top-down.
- Viterbi decoding finds the segmentation that maximises the product of unigram token probabilities.
- Byte fallback encodes any Unicode character via its UTF-8 bytes as <0xHH> tokens, guaranteeing zero OOV with only 256 extra slots.
- Subword regularization (sample_encode) samples from the tokenization distribution during training, improving model robustness.
- The .model file is self-contained; the .vocab file is optional metadata. Ship only the .model file for inference.
- LLaMA-1/2 use a 32K SentencePiece vocabulary; Gemma uses 256K. Larger vocabulary reduces fertility but requires more embedding parameters.

---

