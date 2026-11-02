# First benchmark run — 2026-10-11

The loop-closure evidence for Spec 1 Phase 1 — an **earlier, English-only** run (four
traditions, a mixed-provider panel; question-set digest `ef837474ed7b22ec`), distinct from
the three-corpus search-on/off tutorial run that `TUTORIAL.md` (Track B) now walks through.
Produced by the same `generate → collect → score` pipeline (`--seed 20261011`) over the
English corpora and the OpenRouter+Anthropic panel below; copyright-audited (public-domain /
open English corpora only). See `summary.md` for the table, the panel composition, and token totals.

- **Task / scope:** 100 seeded English `retrieve_quote` questions, balanced 25 each
  across Protestant Christian, LDS, Roman Catholic (encyclicals), and Judaism
  (Talmud, English). Question-set digest `ef837474ed7b22ec`.
- **Panel:** 4 models / 2 serving providers — `claude-haiku` (Anthropic direct) +
  `gpt-oss-20b`, `gemma-3-4b`, `llama-3.1-8b` (via OpenRouter). Tokens: 25,220 in /
  134,131 out.

## Reading the scores — three outcomes

Under the adopted contract (Spec 15) every answered cell is **correct**, **incorrect**, or
**refused** (an explicit decline), and the headline is **accuracy = correct/(correct+incorrect)**
with **coverage = (correct+incorrect)/n** beside it — how often the model is right *when it
answers*, and how often it answers. This makes Phase 1's "reject false premises / incorrect text"
objective legible directly, as the refused rate:

| model        | accuracy | coverage | correct | incorrect | refused |
|--------------|----------|----------|---------|-----------|---------|
| claude-haiku | 56%      | 45%      | 25      | 20        | 55      |
| llama-3.1-8b | 1%       | 80%      | 1       | 79        | 20      |
| gpt-oss-20b  | 0%       | 34%      | 0       | 34        | 66      |
| gemma-3-4b   | 0%       | 100%     | 0       | 100       | 0       |

The two behaviours the old strict headline conflated are now split cleanly by the `refused` outcome:

- **Abstention (honest refusal → `refused`).** `gpt-oss-20b` declines ~66 of 100 ("I'm sorry, but I
  can't provide that."); `claude-haiku` declines 55 (texts it won't reproduce from memory — the
  encyclicals, Talmud). Refusals are excluded from accuracy, so `claude-haiku` reads **56% at 45%
  coverage** (right when it answers), not a flat 25%.
- **Fabrication (confident but wrong → `incorrect`).** `gemma-3-4b` answers every cell and is always
  wrong (0% / coverage 100%); `llama-3.1-8b` likewise emits fluent scripture-like text that is not
  the requested verse (mean `token_f1` over graded cells ~0.15 gemma / ~0.24 llama, per `summary.json`
  — wrong text, not a formatting miss).

**Correction to an earlier draft:** `claude-haiku`'s containment lift is **one** cell, not 17.
`retrieve_quote-88403db0a16b` (a KJV-LDS Zephaniah verse) is the single answer that reproduces the
verse verbatim but wraps it, so the adopted containment headline rescues it (strict-match count
24 → 25 of 100); every other high-`token_f1` miss is genuine paraphrase, *not* the contained
reference. The abstention-vs-fabrication cut that was deferred to Spec 2 is now the built-in
`refused` outcome.

## Copyright audit scope

The audit ran **origin-only** here: its content layer fingerprints restricted unit
texts only when the held-back restricted payloads are present locally, and none are
in this corpus (the run uses no restricted source). Origin is the enforceable proxy
in a clone / CI, where restricted payloads are never committed.
