---
title: "Multilingual Tokenization — Token Fertility Across Scripts and Languages"
slug: "multilingual-tokenization"
description: "Token fertility measures how many subword tokens a tokenizer produces per word across languages. Covers fertility imbalances between English and non-Latin scripts, mBERT/XLM vocabulary allocation, alpha-sampling for low-resource upsampling, and practical API cost implications."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Token fertility is the average number of subword tokens a tokenizer produces per word. For English, vocabularies trained predominantly on English text achieve fertility near 1.0–1.3 tokens per word — most common words appear directly in the vocabulary. For languages with complex morphology or non-Latin scripts, the same tokenizer can produce 2–5× more tokens for equivalent semantic content. This imbalance drives up inference costs, consumes more context window, and degrades model quality for low-resource languages in production deployments."},{"type":"heading","level":2,"content":"Token Fertility — English Baseline and Script Comparison"},{"type":"text","content":"Fertility is formally defined as tokens produced per word. English achieves near-baseline fertility because its morphology is simple and corpus dominance ensures rich vocabulary coverage. Thai lacks word boundaries and uses compound characters, reaching 3–5× English fertility. Arabic\u0027s rich morphology and right-to-left script produce roughly 2× fertility. Finnish\u0027s agglutinative morphology causes common compound words to split into 3–4 tokens despite using the Latin alphabet. Chinese and Japanese typically yield 2–3× fertility since individual characters encode more meaning per slot than English words, yet require 2–3 tokens each in most BPE vocabularies."},{"type":"heading","level":2,"content":"Cross-Lingual Fertility Analysis"},{"type":"code","language":"python","content":"import tiktoken\n\ndef compute_fertility(encode_fn, texts_by_lang):\n    # avg tokens per character for each language\n    results = {}\n    for lang, texts in texts_by_lang.items():\n        total_tokens = sum(len(encode_fn(t)) for t in texts)\n        total_chars = sum(len(t) for t in texts)\n        results[lang] = total_tokens / max(total_chars, 1)\n    return results\n\nenc = tiktoken.get_encoding(\u0027cl100k_base\u0027)\nsample_texts = {\n    \u0027en\u0027: [\u0027The attention mechanism revolutionized NLP.\u0027, \u0027machine learning models\u0027],\n    \u0027zh\u0027: [\u0027注意力机制改变了自然语言处理。\u0027, \u0027机器学习\u0027],\n    \u0027ar\u0027: [\u0027آلية الانتباه في معالجة اللغة الطبيعية.\u0027],\n    \u0027th\u0027: [\u0027กลไกความสนใจการประมวลผลภาษาธรรมชาติ\u0027],\n    \u0027fi\u0027: [\u0027Huomiokyky mullisti luonnollisen kielen kasittelyn.\u0027, \u0027koneoppimismallit\u0027],\n    \u0027hi\u0027: [\u0027ध्यान तंत्र ने एनएलपी में क्रांति ला दी।\u0027],\n    \u0027ko\u0027: [\u0027주의 메커니즘이 자연어 처리를 혁신했습니다.\u0027],\n    \u0027de\u0027: [\u0027Der Aufmerksamkeitsmechanismus revolutionierte NLP-Forschung.\u0027],\n    \u0027ja\u0027: [\u0027注意機構は自然言語処理に革命をもたらした。\u0027],\n    \u0027ru\u0027: [\u0027Механизм внимания произвёл революцию в обработке языка.\u0027],\n}\nfertility = compute_fertility(enc.encode, sample_texts)\nen_rate = fertility[\u0027en\u0027]\nprint(\u0027Language  Tok/Char  Relative\u0027)\nfor lang, rate in fertility.items():\n    rel = rate / en_rate\n    print(f\u0027{lang:\u003c10} {rate:.4f}   {rel:.2f}x\u0027)"},{"type":"heading","level":2,"content":"Vocabulary Coverage in Multilingual Models"},{"type":"text","content":"In mBERT and XLM-R, the shared vocabulary is allocated proportionally to corpus size after alpha-smoothing. English, Chinese, and German receive the largest vocabulary slices. Languages like Swahili or Burmese, with small web corpora, receive far fewer vocabulary slots and rely on byte-fallback or character-level tokenization. This creates a vocabulary coverage disparity: equivalent concepts require more tokens in low-resource languages, degrading model capacity and generation throughput. The proportion of a language\u0027s vocabulary coverage directly correlates with its downstream task performance in multilingual benchmarks."},{"type":"code","language":"python","content":"from transformers import AutoTokenizer\n\ndef analyze_vocab_coverage(model_name, texts_by_lang):\n    tokenizer = AutoTokenizer.from_pretrained(model_name)\n    results = {}\n    for lang, texts in texts_by_lang.items():\n        all_ids = []\n        for text in texts:\n            ids = tokenizer.encode(text, add_special_tokens=False)\n            all_ids.extend(ids)\n        unk_id = tokenizer.unk_token_id\n        unk_count = sum(1 for t in all_ids if t == unk_id)\n        results[lang] = {\n            \u0027total_tokens\u0027: len(all_ids),\n            \u0027unique_types\u0027: len(set(all_ids)),\n            \u0027unk_rate\u0027: unk_count / max(len(all_ids), 1),\n        }\n    return results\n\nmodel_name = \u0027xlm-roberta-base\u0027\ntexts = {\n    \u0027en\u0027: [\u0027Transformer architecture with self-attention layers.\u0027],\n    \u0027zh\u0027: [\u0027具有自注意力层的变换器架构。\u0027],\n    \u0027ar\u0027: [\u0027بنية المحول مع طبقات الانتباه الذاتي.\u0027],\n    \u0027sw\u0027: [\u0027Muundo wa transformer na tabaka za kujizingatia.\u0027],\n    \u0027gu\u0027: [\u0027ટ્રાન્સફોર્મર આર્કિટેક્ચર સ્વ-ધ્યાન સ્તરો સાથે.\u0027],\n}\ncoverage = analyze_vocab_coverage(model_name, texts)\nprint(f\u0027Coverage: {model_name}\u0027)\nfor lang, stats in coverage.items():\n    total = stats[\u0027total_tokens\u0027]\n    unk = stats[\u0027unk_rate\u0027]\n    uniq = stats[\u0027unique_types\u0027]\n    print(f\u0027  {lang}: {total} tokens, unique={uniq}, unk_rate={unk:.3f}\u0027)"},{"type":"heading","level":2,"content":"Temperature-Based Upsampling for Vocabulary Training"},{"type":"text","content":"Alpha-sampling adjusts how many tokens each language contributes during vocabulary training. With alpha=1.0, sampling is proportional to corpus size — large corpora dominate. With alpha=0.7 (default in XLM and mBERT), small corpora are upsampled: a language with 1/100 the data of English receives roughly 1/100^0.7 ≈ 1/21 of the probability mass instead of 1/100. This gives low-resource languages more vocabulary coverage at the cost of slightly lower vocabulary efficiency for high-resource languages. The typical range is alpha=0.5 to 0.7; alpha=1.0 reproduces raw proportional sampling."},{"type":"code","language":"python","content":"import numpy as np\n\ndef alpha_sampling_weights(corpus_sizes, alpha=0.7):\n    # alpha=1.0: proportional to corpus size (favours large corpora)\n    # alpha=0.0: uniform across all languages\n    # alpha=0.7: typical multilingual compromise used in XLM/mBERT\n    langs = list(corpus_sizes.keys())\n    sizes = np.array([corpus_sizes[l] for l in langs], dtype=float)\n    smoothed = sizes ** alpha\n    probs = smoothed / smoothed.sum()\n    return dict(zip(langs, probs))\n\ncorpus_sizes = {\n    \u0027en\u0027: 50_000_000, \u0027zh\u0027: 10_000_000, \u0027ar\u0027: 3_000_000,\n    \u0027sw\u0027: 200_000,    \u0027my\u0027: 100_000,    \u0027th\u0027: 1_500_000,\n    \u0027fi\u0027: 2_000_000,  \u0027hi\u0027: 4_000_000,\n}\nprint(\u0027Language  Corpus       p(a=1.0)  p(a=0.7)  p(a=0.3)\u0027)\nfor lang, size in corpus_sizes.items():\n    p10 = alpha_sampling_weights(corpus_sizes, alpha=1.0)[lang]\n    p07 = alpha_sampling_weights(corpus_sizes, alpha=0.7)[lang]\n    p03 = alpha_sampling_weights(corpus_sizes, alpha=0.3)[lang]\n    print(f\u0027{lang:\u003c5}  {size:\u003e12,}  {p10:.4f}    {p07:.4f}    {p03:.4f}\u0027)\nsw_10 = alpha_sampling_weights(corpus_sizes, 1.0)[\u0027sw\u0027]\nsw_07 = alpha_sampling_weights(corpus_sizes, 0.7)[\u0027sw\u0027]\nprint(f\u0027Swahili upsampling gain (a=0.7 vs a=1.0): {sw_07/sw_10:.1f}x\u0027)"},{"type":"heading","level":2,"content":"Multilingual Tokenizer Usage with mT5 and XLM-R"},{"type":"code","language":"python","content":"from transformers import AutoTokenizer\n\ndef tokenize_multilingual(text_by_lang, model_name):\n    tokenizer = AutoTokenizer.from_pretrained(model_name)\n    results = {}\n    for lang, text in text_by_lang.items():\n        ids = tokenizer.encode(text, add_special_tokens=False)\n        tokens = tokenizer.convert_ids_to_tokens(ids)\n        results[lang] = {\u0027ids\u0027: ids, \u0027tokens\u0027: tokens, \u0027n\u0027: len(ids)}\n    return results\n\nsentence = {\n    \u0027en\u0027: \u0027The tokenizer splits text into subword units.\u0027,\n    \u0027zh\u0027: \u0027分词器将文本拆分为子词单元。\u0027,\n    \u0027ar\u0027: \u0027يقسم المحلل النصي النص إلى وحدات كلمة فرعية.\u0027,\n    \u0027ja\u0027: \u0027トークナイザーはテキストをサブワード単位に分割します。\u0027,\n    \u0027fi\u0027: \u0027Tokenisaattori jakaa tekstin aliosiin.\u0027,\n    \u0027th\u0027: \u0027ตัวแยกคำแบ่งข้อความออกเป็นหน่วยย่อย\u0027,\n}\nfor model in [\u0027google/mt5-small\u0027, \u0027xlm-roberta-base\u0027]:\n    print(f\u0027Model: {model}\u0027)\n    results = tokenize_multilingual(sentence, model)\n    for lang, info in results.items():\n        n_tok = info[\u0027n\u0027]\n        toks = info[\u0027tokens\u0027][:6]\n        print(f\u0027  {lang}: {n_tok} tokens | {toks}\u0027)\n    print()"},{"type":"heading","level":2,"content":"Token Fertility by Language"},{"type":"table","headers":["Language","Script Family","Tokens/Word (approx)","Relative to English","Tokenizer Sensitivity"],"rows":[["English","Latin","1.2","1.0x (baseline)","Low"],["Spanish","Latin","1.3","1.1x","Low"],["French","Latin","1.4","1.2x","Low"],["German","Latin (compounds)","1.8","1.5x","Medium"],["Chinese","Logographic (CJK)","2.0–2.5","1.8x","High"],["Japanese","CJK + Kana","2.0–3.0","2.1x","High"],["Korean","Hangul (agglutinative)","2.5–3.5","2.4x","High"],["Arabic","Abjad (RTL)","2.0–2.5","2.1x","High"],["Thai","Abugida (no spaces)","3.0–5.0","3.5x","Very High"],["Hindi","Devanagari","2.0–3.0","2.3x","High"],["Finnish","Latin (agglutinative)","1.8–2.5","1.7x","Medium-High"],["Code (Python)","ASCII + symbols","1.0–1.5","1.1x","Low (tokenizer-dependent)"]]},{"type":"heading","level":2,"content":"Zero-Shot Cross-Lingual Transfer and Code-Switching"},{"type":"text","content":"Zero-shot cross-lingual transfer — training on English and evaluating on another language — works partly because multilingual models share subword tokens for cognates, technical terms, named entities, and numerals. English \u0027transformer\u0027 and German \u0027Transformer\u0027 often map to identical tokens. URLs, code identifiers, and proper nouns are frequently identical across languages, creating strong cross-lingual anchors in the embedding space. The proportion of shared tokens between a language pair strongly correlates with zero-shot transfer performance on benchmarks like XTREME and XGLUE."},{"type":"text","content":"Code-switching refers to mixed-language sequences where users switch languages within a single prompt. SentencePiece handles this via byte-fallback: any character not in the trained vocabulary is encoded as its individual UTF-8 bytes (e.g., \u003c0xE4\u003e\u003c0xB8\u003e\u003c0xAD\u003e), ensuring no out-of-vocabulary failures at the cost of very high fertility for rare scripts. LangID prefix tokens like __en__ or __zh__ can be prepended to signal the target language, guiding mT5 and NLLB models toward the correct generation language without changing the tokenizer\u0027s vocabulary allocation."},{"type":"heading","level":2,"content":"API Cost and Infrastructure Implications"},{"type":"callout","variant":"warning","title":"API Cost Varies 3–5x by Language","content":"API cost for multilingual LLM applications can vary 3–5x based on language — always benchmark token counts in your target languages before estimating infrastructure costs. A Thai or Arabic response with equivalent semantic content to an English response consumes proportionally more tokens, directly increasing per-request cost and reducing effective context window capacity. Use the tokenizer\u0027s encode() method on representative production samples in each target language before committing to an API pricing tier."},{"type":"list","ordered":false,"items":["Fertility affects API pricing: charge-per-token APIs cost 3–5x more for high-fertility languages at equal content.","Context window: a 4096-token window holds significantly less content for Arabic or Thai than for English.","Generation latency: higher token counts increase autoregressive generation time proportionally.","Batching efficiency: mixed-language batches have variable sequence lengths, reducing GPU utilization.","Vocabulary allocation: reserve minimum vocabulary slots per script when training custom multilingual tokenizers.","Benchmark fertility on real production samples — synthetic test sentences often underestimate real-world fertility."]},{"type":"text","content":"Practical mitigation strategies include using language-specific tokenizers for single-language deployments (achieving lower fertility than multilingual tokenizers), compressing prompts by removing redundant tokens before API calls, and monitoring per-language token counts in production observability dashboards. For mT5 and NLLB-based deployments, the tokenizers are specifically calibrated for multilingual coverage, achieving materially lower fertility for non-English languages than GPT-series tokenizers trained predominantly on English corpora."},{"type":"divider"}]"
---
# Multilingual Tokenization — Token Fertility Across Scripts and Languages

Token fertility is the average number of subword tokens a tokenizer produces per word. For English, vocabularies trained predominantly on English text achieve fertility near 1.0–1.3 tokens per word — most common words appear directly in the vocabulary. For languages with complex morphology or non-Latin scripts, the same tokenizer can produce 2–5× more tokens for equivalent semantic content. This imbalance drives up inference costs, consumes more context window, and degrades model quality for low-resource languages in production deployments.

## Token Fertility — English Baseline and Script Comparison

Fertility is formally defined as tokens produced per word. English achieves near-baseline fertility because its morphology is simple and corpus dominance ensures rich vocabulary coverage. Thai lacks word boundaries and uses compound characters, reaching 3–5× English fertility. Arabic's rich morphology and right-to-left script produce roughly 2× fertility. Finnish's agglutinative morphology causes common compound words to split into 3–4 tokens despite using the Latin alphabet. Chinese and Japanese typically yield 2–3× fertility since individual characters encode more meaning per slot than English words, yet require 2–3 tokens each in most BPE vocabularies.

## Cross-Lingual Fertility Analysis

```python
import tiktoken

def compute_fertility(encode_fn, texts_by_lang):
    # avg tokens per character for each language
    results = {}
    for lang, texts in texts_by_lang.items():
        total_tokens = sum(len(encode_fn(t)) for t in texts)
        total_chars = sum(len(t) for t in texts)
        results[lang] = total_tokens / max(total_chars, 1)
    return results

enc = tiktoken.get_encoding('cl100k_base')
sample_texts = {
    'en': ['The attention mechanism revolutionized NLP.', 'machine learning models'],
    'zh': ['注意力机制改变了自然语言处理。', '机器学习'],
    'ar': ['آلية الانتباه في معالجة اللغة الطبيعية.'],
    'th': ['กลไกความสนใจการประมวลผลภาษาธรรมชาติ'],
    'fi': ['Huomiokyky mullisti luonnollisen kielen kasittelyn.', 'koneoppimismallit'],
    'hi': ['ध्यान तंत्र ने एनएलपी में क्रांति ला दी।'],
    'ko': ['주의 메커니즘이 자연어 처리를 혁신했습니다.'],
    'de': ['Der Aufmerksamkeitsmechanismus revolutionierte NLP-Forschung.'],
    'ja': ['注意機構は自然言語処理に革命をもたらした。'],
    'ru': ['Механизм внимания произвёл революцию в обработке языка.'],
}
fertility = compute_fertility(enc.encode, sample_texts)
en_rate = fertility['en']
print('Language  Tok/Char  Relative')
for lang, rate in fertility.items():
    rel = rate / en_rate
    print(f'{lang:<10} {rate:.4f}   {rel:.2f}x')
```

## Vocabulary Coverage in Multilingual Models

In mBERT and XLM-R, the shared vocabulary is allocated proportionally to corpus size after alpha-smoothing. English, Chinese, and German receive the largest vocabulary slices. Languages like Swahili or Burmese, with small web corpora, receive far fewer vocabulary slots and rely on byte-fallback or character-level tokenization. This creates a vocabulary coverage disparity: equivalent concepts require more tokens in low-resource languages, degrading model capacity and generation throughput. The proportion of a language's vocabulary coverage directly correlates with its downstream task performance in multilingual benchmarks.

```python
from transformers import AutoTokenizer

def analyze_vocab_coverage(model_name, texts_by_lang):
    tokenizer = AutoTokenizer.from_pretrained(model_name)
    results = {}
    for lang, texts in texts_by_lang.items():
        all_ids = []
        for text in texts:
            ids = tokenizer.encode(text, add_special_tokens=False)
            all_ids.extend(ids)
        unk_id = tokenizer.unk_token_id
        unk_count = sum(1 for t in all_ids if t == unk_id)
        results[lang] = {
            'total_tokens': len(all_ids),
            'unique_types': len(set(all_ids)),
            'unk_rate': unk_count / max(len(all_ids), 1),
        }
    return results

model_name = 'xlm-roberta-base'
texts = {
    'en': ['Transformer architecture with self-attention layers.'],
    'zh': ['具有自注意力层的变换器架构。'],
    'ar': ['بنية المحول مع طبقات الانتباه الذاتي.'],
    'sw': ['Muundo wa transformer na tabaka za kujizingatia.'],
    'gu': ['ટ્રાન્સફોર્મર આર્કિટેક્ચર સ્વ-ધ્યાન સ્તરો સાથે.'],
}
coverage = analyze_vocab_coverage(model_name, texts)
print(f'Coverage: {model_name}')
for lang, stats in coverage.items():
    total = stats['total_tokens']
    unk = stats['unk_rate']
    uniq = stats['unique_types']
    print(f'  {lang}: {total} tokens, unique={uniq}, unk_rate={unk:.3f}')
```

## Temperature-Based Upsampling for Vocabulary Training

Alpha-sampling adjusts how many tokens each language contributes during vocabulary training. With alpha=1.0, sampling is proportional to corpus size — large corpora dominate. With alpha=0.7 (default in XLM and mBERT), small corpora are upsampled: a language with 1/100 the data of English receives roughly 1/100^0.7 ≈ 1/21 of the probability mass instead of 1/100. This gives low-resource languages more vocabulary coverage at the cost of slightly lower vocabulary efficiency for high-resource languages. The typical range is alpha=0.5 to 0.7; alpha=1.0 reproduces raw proportional sampling.

```python
import numpy as np

def alpha_sampling_weights(corpus_sizes, alpha=0.7):
    # alpha=1.0: proportional to corpus size (favours large corpora)
    # alpha=0.0: uniform across all languages
    # alpha=0.7: typical multilingual compromise used in XLM/mBERT
    langs = list(corpus_sizes.keys())
    sizes = np.array([corpus_sizes[l] for l in langs], dtype=float)
    smoothed = sizes ** alpha
    probs = smoothed / smoothed.sum()
    return dict(zip(langs, probs))

corpus_sizes = {
    'en': 50_000_000, 'zh': 10_000_000, 'ar': 3_000_000,
    'sw': 200_000,    'my': 100_000,    'th': 1_500_000,
    'fi': 2_000_000,  'hi': 4_000_000,
}
print('Language  Corpus       p(a=1.0)  p(a=0.7)  p(a=0.3)')
for lang, size in corpus_sizes.items():
    p10 = alpha_sampling_weights(corpus_sizes, alpha=1.0)[lang]
    p07 = alpha_sampling_weights(corpus_sizes, alpha=0.7)[lang]
    p03 = alpha_sampling_weights(corpus_sizes, alpha=0.3)[lang]
    print(f'{lang:<5}  {size:>12,}  {p10:.4f}    {p07:.4f}    {p03:.4f}')
sw_10 = alpha_sampling_weights(corpus_sizes, 1.0)['sw']
sw_07 = alpha_sampling_weights(corpus_sizes, 0.7)['sw']
print(f'Swahili upsampling gain (a=0.7 vs a=1.0): {sw_07/sw_10:.1f}x')
```

## Multilingual Tokenizer Usage with mT5 and XLM-R

```python
from transformers import AutoTokenizer

def tokenize_multilingual(text_by_lang, model_name):
    tokenizer = AutoTokenizer.from_pretrained(model_name)
    results = {}
    for lang, text in text_by_lang.items():
        ids = tokenizer.encode(text, add_special_tokens=False)
        tokens = tokenizer.convert_ids_to_tokens(ids)
        results[lang] = {'ids': ids, 'tokens': tokens, 'n': len(ids)}
    return results

sentence = {
    'en': 'The tokenizer splits text into subword units.',
    'zh': '分词器将文本拆分为子词单元。',
    'ar': 'يقسم المحلل النصي النص إلى وحدات كلمة فرعية.',
    'ja': 'トークナイザーはテキストをサブワード単位に分割します。',
    'fi': 'Tokenisaattori jakaa tekstin aliosiin.',
    'th': 'ตัวแยกคำแบ่งข้อความออกเป็นหน่วยย่อย',
}
for model in ['google/mt5-small', 'xlm-roberta-base']:
    print(f'Model: {model}')
    results = tokenize_multilingual(sentence, model)
    for lang, info in results.items():
        n_tok = info['n']
        toks = info['tokens'][:6]
        print(f'  {lang}: {n_tok} tokens | {toks}')
    print()
```

## Token Fertility by Language

| Language | Script Family | Tokens/Word (approx) | Relative to English | Tokenizer Sensitivity |
| --- | --- | --- | --- | --- |
| English | Latin | 1.2 | 1.0x (baseline) | Low |
| Spanish | Latin | 1.3 | 1.1x | Low |
| French | Latin | 1.4 | 1.2x | Low |
| German | Latin (compounds) | 1.8 | 1.5x | Medium |
| Chinese | Logographic (CJK) | 2.0–2.5 | 1.8x | High |
| Japanese | CJK + Kana | 2.0–3.0 | 2.1x | High |
| Korean | Hangul (agglutinative) | 2.5–3.5 | 2.4x | High |
| Arabic | Abjad (RTL) | 2.0–2.5 | 2.1x | High |
| Thai | Abugida (no spaces) | 3.0–5.0 | 3.5x | Very High |
| Hindi | Devanagari | 2.0–3.0 | 2.3x | High |
| Finnish | Latin (agglutinative) | 1.8–2.5 | 1.7x | Medium-High |
| Code (Python) | ASCII + symbols | 1.0–1.5 | 1.1x | Low (tokenizer-dependent) |

## Zero-Shot Cross-Lingual Transfer and Code-Switching

Zero-shot cross-lingual transfer — training on English and evaluating on another language — works partly because multilingual models share subword tokens for cognates, technical terms, named entities, and numerals. English 'transformer' and German 'Transformer' often map to identical tokens. URLs, code identifiers, and proper nouns are frequently identical across languages, creating strong cross-lingual anchors in the embedding space. The proportion of shared tokens between a language pair strongly correlates with zero-shot transfer performance on benchmarks like XTREME and XGLUE.

Code-switching refers to mixed-language sequences where users switch languages within a single prompt. SentencePiece handles this via byte-fallback: any character not in the trained vocabulary is encoded as its individual UTF-8 bytes (e.g., <0xE4><0xB8><0xAD>), ensuring no out-of-vocabulary failures at the cost of very high fertility for rare scripts. LangID prefix tokens like __en__ or __zh__ can be prepended to signal the target language, guiding mT5 and NLLB models toward the correct generation language without changing the tokenizer's vocabulary allocation.

## API Cost and Infrastructure Implications

> **API Cost Varies 3–5x by Language**: API cost for multilingual LLM applications can vary 3–5x based on language — always benchmark token counts in your target languages before estimating infrastructure costs. A Thai or Arabic response with equivalent semantic content to an English response consumes proportionally more tokens, directly increasing per-request cost and reducing effective context window capacity. Use the tokenizer's encode() method on representative production samples in each target language before committing to an API pricing tier.

- Fertility affects API pricing: charge-per-token APIs cost 3–5x more for high-fertility languages at equal content.
- Context window: a 4096-token window holds significantly less content for Arabic or Thai than for English.
- Generation latency: higher token counts increase autoregressive generation time proportionally.
- Batching efficiency: mixed-language batches have variable sequence lengths, reducing GPU utilization.
- Vocabulary allocation: reserve minimum vocabulary slots per script when training custom multilingual tokenizers.
- Benchmark fertility on real production samples — synthetic test sentences often underestimate real-world fertility.

Practical mitigation strategies include using language-specific tokenizers for single-language deployments (achieving lower fertility than multilingual tokenizers), compressing prompts by removing redundant tokens before API calls, and monitoring per-language token counts in production observability dashboards. For mT5 and NLLB-based deployments, the tokenizers are specifically calibrated for multilingual coverage, achieving materially lower fertility for non-English languages than GPT-series tokenizers trained predominantly on English corpora.

---

