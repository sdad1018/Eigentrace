---
layout: home
title: EigenTrace — The Alignment Boundary, Mapped
---

## Live Broadcast

<iframe src="https://www.youtube.com/embed/live_stream?channel=UCWU2u6DkVadZzPuiLz3zWOQ" width="100%" height="400" frameborder="0" allowfullscreen style="border-radius:8px;margin:16px 0"></iframe>

*24/7 autonomous AI news broadcast. Mistral Small 22B narrates consensus geometry across 5 frontier LLMs on breaking news.*

---

## What Is EigenTrace?

EigenTrace is an autonomous AI observatory that runs consensus geometry across 5 frontier language models on breaking news, 24/7. It measures what models collectively drop, soften, and avoid — using linear algebra on frozen embeddings, not LLM-as-judge.

**17,528** segments measured · **1,141** commits · **17** measurement layers · **5** frontier models · **1** GPU

---

---

## What EigenTrace Is

EigenTrace is a **deterministic geometric instrument** for measuring what language models systematically attenuate. It runs the same prompt through five frontier models and scores how much each preserves or drops specific elements of the source — using linear algebra on frozen embeddings, not an LLM-as-judge.

It is not a content filter and not a quality grader. It measures a narrow, specific thing: **the geometric displacement of meaning** — and it measures it the same way every time, with no model in the loop whose verdict has to be trusted.

**Why geometric, not a judge.** The attenuation EigenTrace detects is subtle. In a pre-registered entity-swap counterfactual, the effect was real but modest (Cohen's *d* = 0.471) — a distributional shift, not a gross omission. We then pre-registered a direct test of whether that signal corresponds to what a frontier-model judge flags reading individual summaries. Across 216 model-summaries, it does not: **96% were rated "modifier fully preserved"** by the judge. The geometric signal is *finer-grained than per-item review catches*. We report that null on the [methodology page](/anamnesis) — it defines the boundary of the instrument rather than hiding it.

That is the case for a geometric measure: it is sensitive to systematic, sub-perceptible drift that a per-item human or LLM reviewer scores as "fine." And because it is arithmetic on frozen embeddings, it is:

- **Deterministic** — same inputs, same output, no run-to-run variance.
- **Auditable** — the score is a cosine distance and an SVD a reviewer can inspect directly.
- **Local** — runs in-perimeter on local embeddings, no data egress, no GPU at evaluation time.

**→ [The robustness battery](/sean-adams)** · **→ [Methodology & pre-registrations](/anamnesis)**

---
## Key Findings

**→ [Anamnesis: methodology & findings](/anamnesis)** — 540+ controlled measurements across 10 models. A pre-registered entity-swap counterfactual finds models attenuate covertness modifiers ("quietly," "secretly") significantly more on AI-developer stories than on matched corporate ones (p=0.0085, d=0.471). The RLHF-origin null (p=0.46) locates the effect in the pretraining corpus, not alignment training. Cross-validated on two embedding architectures.

**→ [Boundary Map](/boundary)** — Live visualization of the alignment boundary across all five frontier models.

**→ [Autonomous Thoughts](/thoughts)** — The system's own reflections during idle periods.

**→ [Soul Calibration](/soul)** — Hourly self-updating model profiles and measurement calibration.

---

## Links

- [Anamnesis Research](/anamnesis)
- [YouTube: 24/7 Broadcast](https://www.youtube.com/@AINN24HourNews)
- [GitHub Repository](https://github.com/sdad1018/Eigentrace)
- [Data API](/data/)
- eigentraceproject@gmail.com

*MIT License. Built on one GPU by one person.*

---

## Omission Ledger
