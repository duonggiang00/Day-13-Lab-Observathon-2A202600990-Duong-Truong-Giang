# Observathon — Rules (v6)

**Goal:** maximize your team's composite **production score** on the held-out **private**
test set (released in the last 30 minutes). Public scores are for tuning only.

**The agent runs on a REAL LLM** — there is no zero-key mock. Use a cloud key
(`OPENAI_API_KEY`, etc.) **or** a free local model (Ollama / llama.cpp) — set `provider`/`model`
in `config.json`.

**You submit (in `solution/`, pushed to git):**
1. `config.json` — corrected agent config (the shipped one is mis-configured).
2. `prompt.txt` — the agent's **system prompt** (the shipped agent uses a deliberately bad one — **rewrite it**).
3. `examples.json` — *optional* few-shot.
4. `wrapper.py` — your `mitigate()` layer (observability + mitigations + optional prompt routing).
5. `findings.json` — your diagnosis (fault class + evidence + root cause).

**Score = 100 × (0.32·correct + 0.16·quality + 0.13·error + 0.08·latency + 0.09·cost +
0.07·drift + 0.15·prompt) + up to 22 × diagnosis-F1** (capped at 100).
- `correct` — exact total vs a hidden ground-truth (refusals must NOT fabricate a total).
- `quality` — LLM-eval judge (`gpt-5.4-mini`) with ground-truth override; offline fallback.
- `prompt` — **outcome-based** prompt efficacy: grounding, exact arithmetic, tool economy,
  PII-clean answers, injection resistance — minus a penalty for a bloated prompt. Un-gameable
  by keyword stuffing. See `docs/PROMPT_OPTIMIZATION.md`.

**Legal:** retry, cache, route to a cheaper/local model, input sanitize, output redaction,
arithmetic/guardrail validation, fallback, session reset, **rewriting the system prompt /
few-shot / per-request prompt routing**, and your own logging/tracing/metrics.

**Illegal (auto-rejected / zero):** hardcoding answers; a question→answer (or price) lookup
table in `prompt.txt`/`examples.json`/`wrapper.py`; importing or decompiling the agent
internals; reading instructor files or the seed; network calls to exfiltrate questions;
editing the scorer, weights, question set, or your `score.json`. A prompt over 3000 chars or
containing question IDs / price tables is rejected by `selfcheck`.

**Anti-overfit:** the private phase uses unseen, paraphrased questions, a fresh seed, and an
**injection twist** — order notes embed a fake "system" price; an undefended agent obeys it.
Tuning only to the public leaderboard will regress — build robust, general mitigations and a
robust prompt.
