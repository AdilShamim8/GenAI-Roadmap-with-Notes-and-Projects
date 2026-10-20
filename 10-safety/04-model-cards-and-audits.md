# Model Cards & Audits

> **Level:** INT · **Last verified:** 2026-10-20 · **Sources:** [Model Cards for Model Reporting](https://arxiv.org/abs/1810.03993), [EU AI Act timeline](https://artificialintelligenceact.eu/implementation-timeline/)

## Why this matters

Every model you use has known limitations, biases, and intended-use constraints documented in its model card. Ignoring these is both an ethical risk and a legal one (EU AI Act, sectoral regs). Reading the card takes 5 minutes; not reading it can cost millions.

## Core concepts

### What's in a model card

- **Intended use** — what the model is designed for.
- **Out-of-scope uses** — what the provider explicitly says not to do.
- **Training data summary** — high-level description.
- **Eval results** — benchmarks, including subgroup performance.
- **Known limitations** — hallucination rate, language coverage, etc.
- **Ethical considerations** — bias, dual-use, environmental.
- **Citation** — how to attribute.

### Where to find them

| Provider | Where |
|----------|-------|
| OpenAI | https://openai.com/index/ (per-model announcements) + system card PDFs |
| Anthropic | https://www.anthropic.com/news (model release posts) + model card PDFs |
| Google | https://deepmind.google/technologies/gemini/ (per-model docs) |
| Meta (Llama) | https://llama.meta.com/model-card/ |
| HuggingFace | Per-model README.md tab |

### Auditing your stack

For every model in production, you should know:
- Model name and exact version snapshot.
- Provider's intended use statement.
- Known limitations relevant to your use case.
- Data handling terms (training on your inputs? retention?).
- Compliance certifications (SOC 2, HIPAA, ISO 27001).

## The audit checklist

Maintain a `model_audit.md` per project:

```markdown
# Model Audit — Project X

## Production models
| Model | Version snapshot | Provider | Intended use | Data handling | Last reviewed |
|-------|------------------|----------|--------------|---------------|---------------|
| GPT-6.1 Sol | gpt-6.1-sol-2026-09-29 | OpenAI | Chat, reasoning | Zero-retention enterprise | 2026-10-20 |
| Claude Sonnet 5.5 | claude-sonnet-5-5 (dated alias) | Anthropic | Chat, vision | Standard | 2026-10-20 |

## Known limitations impacting us
- GPT-5: weaker on non-English (per system card).
- Claude: stricter content filtering; some legit queries blocked.

## Compliance
- SOC 2: both providers compliant.
- HIPAA: only OpenAI enterprise tier; Anthropic BAA available.
- EU AI Act: classify our use as "limited risk"; documentation in /docs/eu-ai-act.md.
```

### EU AI Act timeline (verified 2026-10-20)

The Act entered into force 2024-08-01. Prohibited-practice bans applied 2025-02-02; GPAI-model obligations (transparency, copyright, training-data summaries) since 2025-08-02; high-risk system obligations phase in from 2026-08-02. If you integrate third-party foundation models, you inherit documentation duties under Article 50 and the GPAI chain-of-interest rules. Source: artificialintelligenceact.eu timeline.

## Production concerns

- **Latency:** None.
- **Cost:** None.
- **Failure modes:** Models get deprecated; audits get stale. Refresh quarterly.
- **Security:** Audit docs may reference internal architectures; treat as confidential.

## Anti-patterns

- ❌ **Not reading model cards.** You'll use models out-of-scope.
- ❌ **No model audit doc.** Can't answer compliance questions quickly.
- ❌ **Static audit doc.** Models change; audits must too.

## References

- [Model Cards for Model Reporting (paper)](https://arxiv.org/abs/1810.03993) — verified 2026-10-20
- [OpenAI GPT-5 system card](https://openai.com/index/gpt-5/) — verified 2026-10-20
- [Anthropic Claude model cards](https://www.anthropic.com/news) — verified 2026-10-20
