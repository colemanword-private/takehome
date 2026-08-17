# Evertune Take-home Exercise: Adding Gemini 2.5 Flash

This repo contains a small sample of our LLM vendor integration. We'd like you to add support for Gemini 2.5 Flash on Google Vertex and report back on your findings.

# Setup

You'll need the `gcloud` CLI installed and configured against our project, which we will provide for you.

# What to build

Implement Gemini 2.5 Flash as a provider in this system, and demonstrably prove it will hold up at production scale. We care about both halves of that sentence: a working integration *and* the evidence that it will not fall over when we point real traffic at it.

How you structure the code is up to you — the existing providers are a reference, not a template. If something about Gemini doesn't fit those patterns, deviate and tell us why.

For the "prove it works at scale" half: design and run whatever load tests, harnesses, or experiments you'd want to see before signing off on this for production. Show us the numbers, the failure modes you uncovered, and the headroom (or lack thereof) you found.

# Deliverables

We're less interested in a "completed checklist" and more interested in what you learned. In your write-up, we'd like to see:

- How the integration behaves under realistic load. Pick a workload, run it, and tell us what you observed.
- Anything you discovered about this model — quirks, failure modes, parameters that mattered, things that surprised you compared to other LLMs you've used.
- Decisions you made and the tradeoffs behind them. If you tried something that didn't work, that's worth including too.
- What you'd want to do next if this were going to production, and what you'd want to know before getting there.

# Submission

The write-up is **[FINDINGS.md](FINDINGS.md)**; the numbers it cites are
hash-backed in `evidence/gemini/gemini-2.5-flash/*-summary.{json,md}`.

- Provider: `llm/gemini.py` (retry/backoff engine in `llm/retry.py`).
- Harnesses: `load_test.py` (single-process open-loop), `multi_load.py`
  (multi-process shards for rates above one event loop), `quality_eval.py`
  (golden-dataset factorial).
- Quickstart: `make bootstrap && make test` (offline, no credentials).
  Live targets (`provider-smoke`, `sharded-bracket`, `quota-probe`,
  `operating-point`, …) need `gcloud` ADC and `GOOGLE_CLOUD_PROJECT` in `.env`;
  reproduction commands are at the bottom of FINDINGS.md.