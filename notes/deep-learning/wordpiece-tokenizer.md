---
title: "WordPiece — BERT’s Likelihood-Based Subword Tokenizer"
slug: "wordpiece-tokenizer"
description: "How WordPiece builds BERT's vocabulary using a likelihood-based merge criterion, the ## continuation marker, special tokens, cased vs uncased variants, fast Rust tokenizers, and token alignment for span tasks."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"WordPiece is the tokenization algorithm used by BERT, DistilBERT, ELECTRA, and other encoder-only models. Like BPE, it starts from a character vocabulary and iteratively merges pairs, but it uses a different merge criterion: instead of selecting the pair with the highest raw frequency count, WordPiece selects the pair that maximises the likelihood ratio p(ab) / [p(a) × p(b)]. This likelihood-based criterion favours merges that reduce the corpus perplexity most—it will prefer to merge rare pairs that almost always appear together over frequent pairs that each occur independently. The resulting vocabulary uses a ## prefix (two hash symbols) for continuation subwords—tokens that appear mid-word rather than at the start."},{"type":"heading","level":2,"content":"Introduction"},{"type":"text","content":"BERT-base uses a 30,522-token WordPiece vocabulary. The fixed vocabulary was built on the BooksCorpus + English Wikipedia training corpus and is shared across all BERT checkpoints of the same language and case configuration. Special tokens [PAD]=0, [UNK]=100, [CLS]=101, [SEP]=102, [MASK]=103 are reserved at fixed IDs. The ## prefix distinguishes continuation subwords from word-start subwords: \u0027running\u0027 is tokenized as [\u0027running\u0027] if it is a single token, or [\u0027run\u0027, \u0027##ning\u0027] if split. This explicit marking allows the model to learn morphological patterns: ##ing, ##ed, ##er, ##ly appear in the vocabulary as distinct tokens, giving WordPiece an explicit representation of suffixes that BPE lacks."},{"type":"heading","level":2,"content":"Likelihood-Based Merge Criterion"},{"type":"text","content":"The WordPiece score for merging tokens a and b is: score(a, b) = freq(ab) / [freq(a) × freq(b)]. This is proportional to the pointwise mutual information (PMI) of the pair. A pair with score \u003e\u003e 1 almost always co-occurs—merging it reduces description length significantly. A pair with score ≈ 1 occurs at chance—merging it doesn\u0027t help. Contrast with BPE which uses raw count freq(ab): BPE would prefer \u0027th\u0027 (very frequent pair) over \u0027qu\u0027 (nearly always paired), while WordPiece would score \u0027qu\u0027 higher because freq(q) is low and q almost always precedes u. The likelihood criterion produces a more semantically coherent vocabulary for morphologically rich text."},{"type":"code","language":"python","content":"from collections import Counter\n\ndef compute_wp_score(pair_freq, tok_freq):\n    \"\"\"WordPiece likelihood score: freq(ab) / (freq(a) * freq(b)).\"\"\"\n    a, b = pair_freq\n    fa = tok_freq.get(a, 1)\n    fb = tok_freq.get(b, 1)\n    return pair_freq / (fa * fb) if fa * fb \u003e 0 else 0.0\n\ndef build_wordpiece_vocab(corpus, num_merges):\n    words = corpus.lower().split()\n    word_freq = Counter(words)\n    # Initial vocab: first char is bare, rest get ## prefix\n    vocab = {}\n    tok_freq = Counter()\n    for w, freq in word_freq.items():\n        chars = [w[0]] + [\u0027##\u0027 + c for c in w[1:]]\n        key = \u0027 \u0027.join(chars)\n        vocab[key] = freq\n        for ch in chars:\n            tok_freq[ch] += freq\n\n    for merge_step in range(num_merges):\n        pair_counts = Counter()\n        for word, freq in vocab.items():\n            syms = word.split()\n            for i in range(len(syms) - 1):\n                pair_counts[(syms[i], syms[i+1])] += freq\n        if not pair_counts:\n            break\n        # WordPiece: score by likelihood ratio, not raw count\n        best = max(pair_counts, key=lambda p: pair_counts[p] / (tok_freq[p[0]] * tok_freq[p[1]] + 1e-9))\n        score = pair_counts[best] / (tok_freq[best[0]] * tok_freq[best[1]] + 1e-9)\n        merged = best[0] + best[1].lstrip(\u0027#\u0027)\n        # Update vocab\n        import re\n        pat = re.compile(r\u0027(?\u003c!\\S)\u0027 + re.escape(best[0] + \u0027 \u0027 + best[1]) + r\u0027(?!\\S)\u0027)\n        vocab = {pat.sub(merged, w): f for w, f in vocab.items()}\n        tok_freq[merged] += pair_counts[best]\n        print(f\u0027  Step {merge_step+1:2d}: {best[0]} + {best[1]} -\u003e {merged} (score={score:.5f})\u0027)\n\ncorpus = \u0027playing played plays player lower lowest running runner runs quickly quick\u0027\nprint(\u0027WordPiece likelihood-based merges (vs BPE count-based):\u0027)\nbuild_wordpiece_vocab(corpus, num_merges=10)"},{"type":"heading","level":2,"content":"Vocabulary Construction"},{"type":"text","content":"BERT\u0027s 30K vocabulary was built by running WordPiece on a large English corpus with target size 30,522. The vocabulary includes: single characters (a–z, A–Z, 0–9, punctuation), common whole words, and a large set of ## continuation subwords covering common suffixes (##ing, ##ed, ##er, ##ly, ##tion, ##al). Cased BERT preserves case and accent marks; uncased BERT lowercases all text and strips accent characters (e.g., é → e) before tokenization. The uncased vocabulary is smaller because lowercase letters cover more text. Out-of-vocabulary characters (those not in the initial character vocabulary) cause the entire word to be tokenized as [UNK]—unlike BPE which always has a byte fallback."},{"type":"code","language":"python","content":"def wordpiece_encode(word, vocab_set, unk_token=\u0027[UNK]\u0027):\n    \"\"\"Greedy longest-match WordPiece encoding with ## prefix.\"\"\"\n    if word in vocab_set:\n        return [word]\n    tokens = []\n    start = 0\n    while start \u003c len(word):\n        end = len(word)\n        cur_substr = None\n        while start \u003c end:\n            substr = word[start:end]\n            if start \u003e 0:\n                substr = \u0027##\u0027 + substr\n            if substr in vocab_set:\n                cur_substr = substr\n                break\n            end -= 1\n        if cur_substr is None:\n            return [unk_token]  # entire word -\u003e [UNK]\n        tokens.append(cur_substr)\n        start = end\n    return tokens\n\n# Simulate a small WordPiece vocabulary\nsmall_vocab = {\n    \u0027play\u0027, \u0027##ing\u0027, \u0027##ed\u0027, \u0027##er\u0027, \u0027##s\u0027, \u0027##ly\u0027,\n    \u0027run\u0027, \u0027low\u0027, \u0027##est\u0027, \u0027##er\u0027, \u0027quick\u0027, \u0027the\u0027, \u0027a\u0027,\n    \u0027p\u0027, \u0027l\u0027, \u0027a\u0027, \u0027y\u0027, \u0027r\u0027, \u0027u\u0027, \u0027n\u0027, \u0027e\u0027, \u0027q\u0027, \u0027i\u0027, \u0027c\u0027, \u0027k\u0027,\n    \u0027[UNK]\u0027, \u0027[CLS]\u0027, \u0027[SEP]\u0027, \u0027[PAD]\u0027, \u0027[MASK]\u0027,\n}\ntest_words = [\u0027playing\u0027, \u0027played\u0027, \u0027player\u0027, \u0027running\u0027, \u0027lowest\u0027, \u0027zyx\u0027]\nprint(f\u0027{\"Word\":\u003c12} {\"WordPiece Tokens\"}\u0027)\nprint(\u0027-\u0027 * 45)\nfor w in test_words:\n    toks = wordpiece_encode(w, small_vocab)\n    print(f\u0027{w:\u003c12} {toks}\u0027)"},{"type":"heading","level":2,"content":"Special Tokens and Formats"},{"type":"text","content":"BERT uses four special tokens in every input: [CLS] (ID 101) prepended to every sequence, used as the sequence classification token; [SEP] (ID 102) appended after each sentence; [PAD] (ID 0) for padding to uniform length; [MASK] (ID 103) for masked language model pre-training. For sentence pairs (e.g., NLI, QA), the format is [CLS] sentence_A [SEP] sentence_B [SEP]. The token_type_ids tensor indicates which sentence each token belongs to: 0 for sentence A (including [CLS] and first [SEP]) and 1 for sentence B (including second [SEP]). The attention_mask tensor masks padding tokens from self-attention: 1 for real tokens, 0 for [PAD]."},{"type":"table","headers":["Property","Value / Detail"],"rows":[["Continuation marker","## prefix on mid-word subwords (e.g., ##ing, ##ed)"],["Special tokens","[PAD]=0, [UNK]=100, [CLS]=101, [SEP]=102, [MASK]=103"],["Pre-tokenization","Whitespace split → punctuation split → WordPiece"],["OOV handling","Any char not in character vocab → entire word becomes [UNK]"],["Vocab size (BERT-base)","30,522 tokens (cased and uncased models)"],["Case handling","Cased: preserves case + accents; Uncased: lowercase + accent strip"],["Fast tokenizer","Rust implementation via HuggingFace tokenizers library"]]},{"type":"heading","level":2,"content":"Encoding Mechanics"},{"type":"text","content":"BERT\u0027s tokenization pipeline has three stages: (1) whitespace tokenization splits on any whitespace character; (2) punctuation tokenization further splits tokens on punctuation boundaries (so \u0027end.\u0027 becomes [\u0027end\u0027, \u0027.\u0027]); (3) WordPiece tokenization applies the greedy longest-match algorithm with ## prefixes. The encode_plus method returns a dictionary with input_ids, token_type_ids, and attention_mask. Setting return_offsets_mapping=True adds a mapping from each token position to its character span in the original string—essential for NER and span extraction tasks where the model must predict character-level labels."},{"type":"code","language":"python","content":"from transformers import BertTokenizerFast\n\ntokenizer = BertTokenizerFast.from_pretrained(\u0027bert-base-uncased\u0027)\n\n# Single sentence\ntext = \u0027The quick brown fox jumps over the lazy dog.\u0027\nenc = tokenizer(text, return_tensors=\u0027pt\u0027, return_offsets_mapping=True)\nprint(\u0027Single sentence encoding:\u0027)\nprint(f\u0027  input_ids   : {enc[\"input_ids\"][0].tolist()}\u0027)\nprint(f\u0027  tokens      : {tokenizer.convert_ids_to_tokens(enc[\"input_ids\"][0].tolist())}\u0027)\nprint(f\u0027  attn_mask   : {enc[\"attention_mask\"][0].tolist()}\u0027)\nprint(f\u0027  offsets     : {enc[\"offset_mapping\"][0].tolist()}\u0027)\nprint()\n\n# Sentence pair (NLI format)\nsentA = \u0027The cat sat on the mat.\u0027\nsentB = \u0027A feline rested on a rug.\u0027\nenc2 = tokenizer(sentA, sentB, return_tensors=\u0027pt\u0027, padding=True, truncation=True)\nprint(\u0027Sentence pair encoding:\u0027)\nprint(f\u0027  tokens      : {tokenizer.convert_ids_to_tokens(enc2[\"input_ids\"][0].tolist())}\u0027)\nprint(f\u0027  type_ids    : {enc2[\"token_type_ids\"][0].tolist()}\u0027)\nprint(f\u0027  Format: [CLS] sentA [SEP] sentB [SEP]\u0027)\nprint()\nprint(f\u0027Vocab size: {tokenizer.vocab_size}\u0027)\nprint(f\u0027Special tokens: {tokenizer.all_special_tokens}\u0027)"},{"type":"heading","level":2,"content":"Cased vs Uncased"},{"type":"text","content":"BERT-base-uncased lowercases all input and strips Unicode accent characters before WordPiece tokenization: \u0027Étude\u0027 becomes \u0027etude\u0027. This reduces vocabulary diversity and improves coverage of common words, but loses case and diacritic information. BERT-base-cased preserves case and accents, making it better for tasks where case carries semantic meaning: named entity recognition (differentiating \u0027apple\u0027 the fruit from \u0027Apple\u0027 the company), and languages where diacritics change word meaning (French, German, Spanish). For most English classification tasks, uncased performs comparably or better due to improved generalisation across case variants."},{"type":"callout","variant":"info","title":"Continuation Marker Semantics","content":"WordPiece\u0027s ## continuation marker means vocabulary statistics differ from BPE — \u0027running\u0027 and \u0027##running\u0027 are distinct tokens. This gives WordPiece an explicit representation of morphological suffixes: ##ing, ##ed, ##er, ##ly, ##tion are all high-frequency vocabulary entries encoding suffix semantics. BPE merges these into the preceding subword without marking the boundary, so \u0027run\u0027 and \u0027running\u0027 share no explicit subword. For morphologically rich languages (Finnish, Turkish, Hungarian), WordPiece\u0027s explicit suffix representation can provide cleaner morphological signal to the model."},{"type":"heading","level":2,"content":"Token Alignment for Span Tasks"},{"type":"text","content":"Span-extraction tasks (NER, QA, coreference) require mapping model predictions from token space back to character offsets in the original text. The offset_mapping return value provides exactly this: each token gets a (start, end) character span. Tokens split by WordPiece have consecutive overlapping spans: \u0027running\u0027 split as [\u0027run\u0027, \u0027##ning\u0027] gets offsets [(0,3), (3,7)]. [CLS] and [SEP] special tokens get offset (0, 0). When aligning labels for NER training, use the word_ids() method to get the word index for each token, then assign the label of the original word to its first subword (and a special ignore label, typically -100, to all continuation subwords)."},{"type":"code","language":"python","content":"from transformers import AutoTokenizer\n\n# Cross-tokenizer comparison on the same sentences\nsentences = [\n    \u0027running quickly\u0027,\n    \u0027tokenization splits text\u0027,\n    \u0027supercalifragilistic\u0027,\n    \u0027the quick brown fox\u0027,\n    \u0027GPT-4 outperforms earlier models\u0027,\n]\n\nmodels = [\n    (\u0027BPE (GPT-2)\u0027,      \u0027gpt2\u0027),\n    (\u0027WordPiece (BERT)\u0027, \u0027bert-base-uncased\u0027),\n    (\u0027Unigram (T5)\u0027,     \u0027t5-small\u0027),\n]\nfor model_name, model_id in models:\n    print(f\u0027\\n--- {model_name} ---\u0027)\n    tok = AutoTokenizer.from_pretrained(model_id)\n    for sent in sentences:\n        tokens = tok.tokenize(sent)\n        print(f\u0027  {sent!r:\u003c35} -\u003e {len(tokens):2d} tokens: {tokens}\u0027)\n\nprint(\u0027\\nKey differences:\u0027)\nprint(\u0027  BPE (GPT-2)  : no continuation marker, space encoded as G-dot prefix\u0027)\nprint(\u0027  WordPiece    : ## prefix for mid-word subwords (explicit suffix marking)\u0027)\nprint(\u0027  Unigram (T5) : _ prefix for word-start subwords (like SentencePiece)\u0027)"},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"list","ordered":false,"items":["WordPiece uses a likelihood ratio merge criterion (score = freq(ab) / [freq(a) × freq(b)]) rather than BPE\u0027s raw frequency count.","The ## prefix marks continuation subwords: \u0027running\u0027 → [\u0027run\u0027, \u0027##ning\u0027] gives explicit morphological suffix representation.","BERT uses 30,522 tokens with fixed special IDs: [PAD]=0, [UNK]=100, [CLS]=101, [SEP]=102, [MASK]=103.","Input format for sentence pairs: [CLS] sentA [SEP] sentB [SEP]; token_type_ids=0 for sentA, 1 for sentB.","Uncased BERT strips accents and lowercases; cased BERT preserves case. Use cased for NER, uncased for classification.","Use BertTokenizerFast (Rust backend) for production; it is 10–100× faster and supports offset_mapping.","For NER/span tasks, use word_ids() to align WordPiece tokens to original words; assign -100 to continuation subword labels."]},{"type":"divider"}]"
---
# WordPiece — BERT’s Likelihood-Based Subword Tokenizer

WordPiece is the tokenization algorithm used by BERT, DistilBERT, ELECTRA, and other encoder-only models. Like BPE, it starts from a character vocabulary and iteratively merges pairs, but it uses a different merge criterion: instead of selecting the pair with the highest raw frequency count, WordPiece selects the pair that maximises the likelihood ratio p(ab) / [p(a) × p(b)]. This likelihood-based criterion favours merges that reduce the corpus perplexity most—it will prefer to merge rare pairs that almost always appear together over frequent pairs that each occur independently. The resulting vocabulary uses a ## prefix (two hash symbols) for continuation subwords—tokens that appear mid-word rather than at the start.

## Introduction

BERT-base uses a 30,522-token WordPiece vocabulary. The fixed vocabulary was built on the BooksCorpus + English Wikipedia training corpus and is shared across all BERT checkpoints of the same language and case configuration. Special tokens [PAD]=0, [UNK]=100, [CLS]=101, [SEP]=102, [MASK]=103 are reserved at fixed IDs. The ## prefix distinguishes continuation subwords from word-start subwords: 'running' is tokenized as ['running'] if it is a single token, or ['run', '##ning'] if split. This explicit marking allows the model to learn morphological patterns: ##ing, ##ed, ##er, ##ly appear in the vocabulary as distinct tokens, giving WordPiece an explicit representation of suffixes that BPE lacks.

## Likelihood-Based Merge Criterion

The WordPiece score for merging tokens a and b is: score(a, b) = freq(ab) / [freq(a) × freq(b)]. This is proportional to the pointwise mutual information (PMI) of the pair. A pair with score >> 1 almost always co-occurs—merging it reduces description length significantly. A pair with score ≈ 1 occurs at chance—merging it doesn't help. Contrast with BPE which uses raw count freq(ab): BPE would prefer 'th' (very frequent pair) over 'qu' (nearly always paired), while WordPiece would score 'qu' higher because freq(q) is low and q almost always precedes u. The likelihood criterion produces a more semantically coherent vocabulary for morphologically rich text.

```python
from collections import Counter

def compute_wp_score(pair_freq, tok_freq):
    """WordPiece likelihood score: freq(ab) / (freq(a) * freq(b))."""
    a, b = pair_freq
    fa = tok_freq.get(a, 1)
    fb = tok_freq.get(b, 1)
    return pair_freq / (fa * fb) if fa * fb > 0 else 0.0

def build_wordpiece_vocab(corpus, num_merges):
    words = corpus.lower().split()
    word_freq = Counter(words)
    # Initial vocab: first char is bare, rest get ## prefix
    vocab = {}
    tok_freq = Counter()
    for w, freq in word_freq.items():
        chars = [w[0]] + ['##' + c for c in w[1:]]
        key = ' '.join(chars)
        vocab[key] = freq
        for ch in chars:
            tok_freq[ch] += freq

    for merge_step in range(num_merges):
        pair_counts = Counter()
        for word, freq in vocab.items():
            syms = word.split()
            for i in range(len(syms) - 1):
                pair_counts[(syms[i], syms[i+1])] += freq
        if not pair_counts:
            break
        # WordPiece: score by likelihood ratio, not raw count
        best = max(pair_counts, key=lambda p: pair_counts[p] / (tok_freq[p[0]] * tok_freq[p[1]] + 1e-9))
        score = pair_counts[best] / (tok_freq[best[0]] * tok_freq[best[1]] + 1e-9)
        merged = best[0] + best[1].lstrip('#')
        # Update vocab
        import re
        pat = re.compile(r'(?<!\S)' + re.escape(best[0] + ' ' + best[1]) + r'(?!\S)')
        vocab = {pat.sub(merged, w): f for w, f in vocab.items()}
        tok_freq[merged] += pair_counts[best]
        print(f'  Step {merge_step+1:2d}: {best[0]} + {best[1]} -> {merged} (score={score:.5f})')

corpus = 'playing played plays player lower lowest running runner runs quickly quick'
print('WordPiece likelihood-based merges (vs BPE count-based):')
build_wordpiece_vocab(corpus, num_merges=10)
```

## Vocabulary Construction

BERT's 30K vocabulary was built by running WordPiece on a large English corpus with target size 30,522. The vocabulary includes: single characters (a–z, A–Z, 0–9, punctuation), common whole words, and a large set of ## continuation subwords covering common suffixes (##ing, ##ed, ##er, ##ly, ##tion, ##al). Cased BERT preserves case and accent marks; uncased BERT lowercases all text and strips accent characters (e.g., é → e) before tokenization. The uncased vocabulary is smaller because lowercase letters cover more text. Out-of-vocabulary characters (those not in the initial character vocabulary) cause the entire word to be tokenized as [UNK]—unlike BPE which always has a byte fallback.

```python
def wordpiece_encode(word, vocab_set, unk_token='[UNK]'):
    """Greedy longest-match WordPiece encoding with ## prefix."""
    if word in vocab_set:
        return [word]
    tokens = []
    start = 0
    while start < len(word):
        end = len(word)
        cur_substr = None
        while start < end:
            substr = word[start:end]
            if start > 0:
                substr = '##' + substr
            if substr in vocab_set:
                cur_substr = substr
                break
            end -= 1
        if cur_substr is None:
            return [unk_token]  # entire word -> [UNK]
        tokens.append(cur_substr)
        start = end
    return tokens

# Simulate a small WordPiece vocabulary
small_vocab = {
    'play', '##ing', '##ed', '##er', '##s', '##ly',
    'run', 'low', '##est', '##er', 'quick', 'the', 'a',
    'p', 'l', 'a', 'y', 'r', 'u', 'n', 'e', 'q', 'i', 'c', 'k',
    '[UNK]', '[CLS]', '[SEP]', '[PAD]', '[MASK]',
}
test_words = ['playing', 'played', 'player', 'running', 'lowest', 'zyx']
print(f'{"Word":<12} {"WordPiece Tokens"}')
print('-' * 45)
for w in test_words:
    toks = wordpiece_encode(w, small_vocab)
    print(f'{w:<12} {toks}')
```

## Special Tokens and Formats

BERT uses four special tokens in every input: [CLS] (ID 101) prepended to every sequence, used as the sequence classification token; [SEP] (ID 102) appended after each sentence; [PAD] (ID 0) for padding to uniform length; [MASK] (ID 103) for masked language model pre-training. For sentence pairs (e.g., NLI, QA), the format is [CLS] sentence_A [SEP] sentence_B [SEP]. The token_type_ids tensor indicates which sentence each token belongs to: 0 for sentence A (including [CLS] and first [SEP]) and 1 for sentence B (including second [SEP]). The attention_mask tensor masks padding tokens from self-attention: 1 for real tokens, 0 for [PAD].

| Property | Value / Detail |
| --- | --- |
| Continuation marker | ## prefix on mid-word subwords (e.g., ##ing, ##ed) |
| Special tokens | [PAD]=0, [UNK]=100, [CLS]=101, [SEP]=102, [MASK]=103 |
| Pre-tokenization | Whitespace split → punctuation split → WordPiece |
| OOV handling | Any char not in character vocab → entire word becomes [UNK] |
| Vocab size (BERT-base) | 30,522 tokens (cased and uncased models) |
| Case handling | Cased: preserves case + accents; Uncased: lowercase + accent strip |
| Fast tokenizer | Rust implementation via HuggingFace tokenizers library |

## Encoding Mechanics

BERT's tokenization pipeline has three stages: (1) whitespace tokenization splits on any whitespace character; (2) punctuation tokenization further splits tokens on punctuation boundaries (so 'end.' becomes ['end', '.']); (3) WordPiece tokenization applies the greedy longest-match algorithm with ## prefixes. The encode_plus method returns a dictionary with input_ids, token_type_ids, and attention_mask. Setting return_offsets_mapping=True adds a mapping from each token position to its character span in the original string—essential for NER and span extraction tasks where the model must predict character-level labels.

```python
from transformers import BertTokenizerFast

tokenizer = BertTokenizerFast.from_pretrained('bert-base-uncased')

# Single sentence
text = 'The quick brown fox jumps over the lazy dog.'
enc = tokenizer(text, return_tensors='pt', return_offsets_mapping=True)
print('Single sentence encoding:')
print(f'  input_ids   : {enc["input_ids"][0].tolist()}')
print(f'  tokens      : {tokenizer.convert_ids_to_tokens(enc["input_ids"][0].tolist())}')
print(f'  attn_mask   : {enc["attention_mask"][0].tolist()}')
print(f'  offsets     : {enc["offset_mapping"][0].tolist()}')
print()

# Sentence pair (NLI format)
sentA = 'The cat sat on the mat.'
sentB = 'A feline rested on a rug.'
enc2 = tokenizer(sentA, sentB, return_tensors='pt', padding=True, truncation=True)
print('Sentence pair encoding:')
print(f'  tokens      : {tokenizer.convert_ids_to_tokens(enc2["input_ids"][0].tolist())}')
print(f'  type_ids    : {enc2["token_type_ids"][0].tolist()}')
print(f'  Format: [CLS] sentA [SEP] sentB [SEP]')
print()
print(f'Vocab size: {tokenizer.vocab_size}')
print(f'Special tokens: {tokenizer.all_special_tokens}')
```

## Cased vs Uncased

BERT-base-uncased lowercases all input and strips Unicode accent characters before WordPiece tokenization: 'Étude' becomes 'etude'. This reduces vocabulary diversity and improves coverage of common words, but loses case and diacritic information. BERT-base-cased preserves case and accents, making it better for tasks where case carries semantic meaning: named entity recognition (differentiating 'apple' the fruit from 'Apple' the company), and languages where diacritics change word meaning (French, German, Spanish). For most English classification tasks, uncased performs comparably or better due to improved generalisation across case variants.

> **Continuation Marker Semantics**: WordPiece's ## continuation marker means vocabulary statistics differ from BPE — 'running' and '##running' are distinct tokens. This gives WordPiece an explicit representation of morphological suffixes: ##ing, ##ed, ##er, ##ly, ##tion are all high-frequency vocabulary entries encoding suffix semantics. BPE merges these into the preceding subword without marking the boundary, so 'run' and 'running' share no explicit subword. For morphologically rich languages (Finnish, Turkish, Hungarian), WordPiece's explicit suffix representation can provide cleaner morphological signal to the model.

## Token Alignment for Span Tasks

Span-extraction tasks (NER, QA, coreference) require mapping model predictions from token space back to character offsets in the original text. The offset_mapping return value provides exactly this: each token gets a (start, end) character span. Tokens split by WordPiece have consecutive overlapping spans: 'running' split as ['run', '##ning'] gets offsets [(0,3), (3,7)]. [CLS] and [SEP] special tokens get offset (0, 0). When aligning labels for NER training, use the word_ids() method to get the word index for each token, then assign the label of the original word to its first subword (and a special ignore label, typically -100, to all continuation subwords).

```python
from transformers import AutoTokenizer

# Cross-tokenizer comparison on the same sentences
sentences = [
    'running quickly',
    'tokenization splits text',
    'supercalifragilistic',
    'the quick brown fox',
    'GPT-4 outperforms earlier models',
]

models = [
    ('BPE (GPT-2)',      'gpt2'),
    ('WordPiece (BERT)', 'bert-base-uncased'),
    ('Unigram (T5)',     't5-small'),
]
for model_name, model_id in models:
    print(f'\n--- {model_name} ---')
    tok = AutoTokenizer.from_pretrained(model_id)
    for sent in sentences:
        tokens = tok.tokenize(sent)
        print(f'  {sent!r:<35} -> {len(tokens):2d} tokens: {tokens}')

print('\nKey differences:')
print('  BPE (GPT-2)  : no continuation marker, space encoded as G-dot prefix')
print('  WordPiece    : ## prefix for mid-word subwords (explicit suffix marking)')
print('  Unigram (T5) : _ prefix for word-start subwords (like SentencePiece)')
```

## Key Takeaways

- WordPiece uses a likelihood ratio merge criterion (score = freq(ab) / [freq(a) × freq(b)]) rather than BPE's raw frequency count.
- The ## prefix marks continuation subwords: 'running' → ['run', '##ning'] gives explicit morphological suffix representation.
- BERT uses 30,522 tokens with fixed special IDs: [PAD]=0, [UNK]=100, [CLS]=101, [SEP]=102, [MASK]=103.
- Input format for sentence pairs: [CLS] sentA [SEP] sentB [SEP]; token_type_ids=0 for sentA, 1 for sentB.
- Uncased BERT strips accents and lowercases; cased BERT preserves case. Use cased for NER, uncased for classification.
- Use BertTokenizerFast (Rust backend) for production; it is 10–100× faster and supports offset_mapping.
- For NER/span tasks, use word_ids() to align WordPiece tokens to original words; assign -100 to continuation subword labels.

---

