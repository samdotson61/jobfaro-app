# Eval tuning — research notes

> Research backing the design of `jobfaro eval`'s scoring (Phase 8a.4–8a.6) and `jobfaro offer`
> (Phase 8d). Goal: the same rubric must score **consistently and fairly** on both backends —
> a frontier API model *and* a small local model served by
> [winc.cpp](https://github.com/samdotson61/winc.cpp). Compiled 2026-06-10.

> **Update (2026-06-14, CLI 1.24.x) — as-shipped deltas + two on-device findings.** This page is the
> original research; some specifics shifted in implementation. The authoritative current spec is
> [`engine.md`](engine.md) + [`../modes/_shared.md`](../modes/_shared.md). As shipped: **bands are
> Apply ≥ 4.0 · Research ≥ 3.5 · Don't < 3.5** (`lib/evaluations.mjs BANDS` — §3 below quotes an earlier
> draft scale), and the verdict JSON is `{required, skills, experience, level_fit, logistics, education,
> recommendation}` with deterministic code computing the 0–5.
>
> - **Transferable-skills mode (the `transferable_skills` toggle, 1.24.0; hardened 1.24.1).** Credits
>   genuine adjacent skills — rated on *bridge strength*, not title match — and makes the clamp treat an
>   unmet "X+ years in [field]" requirement as bridgeable (exact parity with the no-degree degree rule
>   of §2.2; hard credentials — license/cert/clearance — still gate). It changes *what* counts as a fit,
>   not the bar.
> - **Measured local-model variance.** §1 predicted small-model variance; we measured it. The winc
>   Qwen3.5-4B swings **~±1 point run-to-run**, enough to flip a band near an edge — so transferable
>   behavior must be judged on the **mean of N ≥ 5 runs, never one**, and §1's "2–3-sample ensemble,
>   majority band" should be treated as **load-bearing for production** on a 4B local backend, not optional.
> - **Low-end floor validated — `gemma4-e2b` (Gemma Effective-2B, the nano tier).** Doubled JD set
>   (12 roles × OFF/ON × N = 5 = 120 evals on the 2B): the toggle stays directionally correct at the very
>   low end — direct fits neutral (3/3 in-band), clean-gate adjacent roles lift-or-hold and **all reach
>   Research/Apply when ON (5/5, meanΔ +0.12)**, years-clamped roles not demoted (2/2), and stretches
>   **never inflate (10/10 ON runs stayed Don't)**. The 1.24.1 anti-inversion fix holds on 2B (no demotion
>   of strong adjacent fits). Two low-end caveats: a **~1.7% parse-failure rate** (2/120 — the 2B
>   occasionally emits invalid JSON; the pipeline drops that run via `ok:false`, so `eval --auto` leaves
>   the role unscored / retries rather than recording a wrong score), and the 2B runs **slightly more
>   generous** (more Apply bands) and noisy near band edges, so the same N ≥ 5 averaging applies. Net:
>   e2b is a viable lowest default for the transferable feature; production should retry/skip on a parse
>   miss and prefer a ≥ 4B backend where accuracy matters.

## 1. What the literature says about LLM job-fit scoring

**Decomposed (analytic) rubrics beat holistic scores.** Asking a model for one 0–5 "fit" number
invites inconsistency; asking it to judge **one criterion at a time** (skills match, experience
relevance, level fit, …) is more reliable, easier to debug, and shows *why* a score moved.
Analytic rubrics are the recommended shape for longitudinal monitoring — exactly our pipeline
case ([Evidently](https://www.evidentlyai.com/llm-guide/llm-as-a-judge),
[Galtea](https://galtea.ai/blog/llm-as-a-judge-the-complete-guide)).

**Coarse judgments beat fine-grained ones.** Models answer "strong / partial / none" far more
consistently than "is this a 73 or an 82." The reliable pattern: the model makes **categorical
sub-judgments with quoted evidence**, and *deterministic code* converts them to the 0–5 score
and Apply/Research/Don't band
([Confident AI](https://www.confident-ai.com/blog/why-llm-as-a-judge-is-the-best-llm-evaluation-method)).

**Reason first, then judge.** Chain-of-thought — explain the evidence, *then* emit the verdict —
measurably improves judge accuracy and robustness
([Comet](https://www.comet.com/site/blog/llm-as-a-judge/),
[explicit-reasoning study](https://arxiv.org/pdf/2509.13332)).

**Few-shot anchors raise consistency.** 2–3 worked examples per band (what a 5 looks like, what
a 2 looks like) pin the scale in place across runs and across models. Keep anchors short so they
fit a small local model's context
([Langfuse](https://langfuse.com/docs/evaluation/evaluation-methods/llm-as-a-judge)).

**Calibrate against humans before trusting it.** Standard practice: a **30–50 example
human-annotated calibration set**, re-scored on every prompt or model change; track agreement
and drift ([Kinde](https://www.kinde.com/learn/ai-for-software-engineering/best-practice/llm-as-a-judge-done-right-calibrating-guarding-debiasing-your-evaluators/)).
For Jobfaro: a fixture set of real JDs hand-banded by us, run by `test-all.mjs` against any
configured backend.

**Small local models hold up — with help.** Decomposed rubric + few-shot anchors + structured
output is precisely the recipe that lets a 3–8B-class local model judge usefully; ensembling
(2–3 samples, majority band) cuts variance further at zero cloud cost
([Vadim](https://vadim.blog/llm-as-judge)). Pairwise comparison is intrinsically more reliable
than absolute scoring, but our pipeline needs absolute bands — so we use **band-anchored
absolute scoring** and reserve pairwise for A/B-testing rubric changes on the calibration set.

## 2. Fairness — load-bearing for Jobfaro's audience

A 2025 study of ~10,000 real candidate–job pairs found off-the-shelf LLMs (OpenAI, Anthropic,
Google, Meta, Deepseek) reached ROC AUC ≈ 0.77 on hiring fit **and carried measurable
demographic bias** (race-wise impact ratios ≤ 0.809, vs 0.957 for a purpose-built matcher) —
the authors' conclusion: never deploy hiring-adjacent LLM scoring without explicit fairness
guardrails ([arXiv 2507.02087](https://arxiv.org/pdf/2507.02087);
see also [bias in job–résumé matching](https://arxiv.org/pdf/2503.19182)).

Jobfaro's stakes are lower — we score **jobs for one candidate**, not candidates for an employer —
but two guards are still ours to build:

1. **Minimal-slice + PII-strip (8a.3, extended):** the eval prompt gets the JD + a *skills/
   experience excerpt* of `cv.md` — name, address, and contact lines stripped before the prompt
   is built. Less PII out the door **and** a smaller bias surface.
2. **No-degree fairness is rubric law:** under the `no_degree` tuning profile the rubric must
   treat "Bachelor's required" as a *soft* signal (per Phase 4.5) — and the calibration set must
   include no-degree/equivalent-experience JD pairs so a regression here **fails tests**, not
   just vibes.

## 3. Concrete rubric design for `jobfaro eval` (feeds 8a.1/8a.4)

Sub-criteria (model returns `strong | partial | none` + one quoted JD line of evidence each):

| Criterion | Weight | Notes |
|---|---|---|
| `skills_match` | 35% | hard + transferable skills vs JD requirements |
| `experience_relevance` | 25% | projects/work history vs the role's day-to-day |
| `level_fit` | 20% | role level vs `target_levels` (above-selected-level → capped, per 4.3) |
| `logistics` | 10% | metro/remote/relocation vs `target_regions` |
| `education_gate` | 10% | **soft** under `no_degree` (flag, never auto-zero, per 4.5) |

Code (not the model) maps categories → numbers, applies weights → **0–5 score**, then bands.
> **Superseded (2026-08-28):** this section's draft thresholds (Apply ≥ 3.5 / Research 2.0–3.4) were
> **dropped before ship** — the shipped scale is **Apply ≥ 4.0 · Research ≥ 3.5 · else Don't**,
> hardcoded in `lib/bands.mjs` (single source of truth; NOT profile-configurable), decided 2026-06-13
> (ROADMAP 8a.4). The draft below is kept as history. Verdict schema (both backends, enforced):

```json
{ "criteria": { "skills_match": {"judgment": "strong", "evidence": "..."}, … },
  "score": 4.1, "band": "apply", "summary_en": "…", "summary_es": "…",
  "flags": ["degree_required_soft"] }
```

Prompt rules: pinned system prompt; temperature 0; reason-then-judge ordering; identical prompt
text on `api` and `local` so backend differences are measurable, not confounded.
> **Superseded (2026-08-28):** the draft's "2 anchor examples per band" was measured and **REJECTED**
> in the 8a.4b A/B (few-shot made small models MORE lenient and dropped JSON validity 6/6 → 4/6) —
> the shipped prompt carries no anchor examples, deliberately. And "temperature 0" was only enforced
> by winc's `--eval` serve profile until 1.52.0 pinned it in code for every backend.

## 4. Offer evaluation data sources (feeds 8d)

The model must **never invent wage numbers** — deterministic code supplies market context;
the model only interprets it:

- **BLS OEWS** — median/percentile wages by occupation × metro ([bls.gov/bls/blswage.htm](https://www.bls.gov/bls/blswage.htm)) — the backbone of "is this offer at market?"
- **Metro CPI** ([bls.gov/cpi](https://www.bls.gov/data/)) and regional price differences for
  cost-of-living-adjusted comparisons between metros (differences are large — same nominal
  salary can differ ~50% in real terms between metros,
  [COLA guide](https://salary-converter.com/blog/articles/cost-of-living-adjustment-cola-guide-2026)).
- **Employment Cost Index** for trend ("are wages in this sector rising?")
  ([bls.gov/eci](https://www.bls.gov/eci/)).

Ship as a versioned `data/seed/wages.yml` snapshot (entry archetypes × major metros), refreshed
per release with provenance noted — works offline, no per-user BLS calls.

## 5. PDF understanding (feeds 8c)

Survey of the Node PDF-extraction field
([PkgPulse comparison](https://www.pkgpulse.com/blog/unpdf-vs-pdf-parse-vs-pdfjs-dist-pdf-parsing-extraction-nodejs-2026),
[Strapi roundup](https://strapi.io/blog/7-best-javascript-pdf-parsing-libraries-nodejs-2025)):

- **[unpdf](https://github.com/unjs/unpdf)** — modern, maintained (UnJS), Mozilla pdf.js under
  the hood, no native binaries, runs in Node **and** serverless/edge — the same extraction code
  can serve the Phase 9 web server. **→ our pick (the one new dependency).**
- `pdf-parse` — most-downloaded but effectively unmaintained; unpdf is its stated successor.
- `pdfjs-dist` raw — full renderer, heavyweight; more than we need.
- `pdf.js-extract` — positional/per-glyph extraction; only needed if layout-aware parsing ever
  becomes necessary (it likely won't: the *model* does the structuring, not regexes).

Division of labor: **extraction is deterministic** (unpdf → text), **understanding is the
inference backend's job** (text → structured `cv.md` + profile fields) — so résumé
understanding is private-by-default on winc.cpp, and accuracy scales with whichever backend
the user picked. Image-only/scanned PDFs: detect the empty text layer and fail honestly with
a bilingual hint (OCR out of scope for now).

## 6. Nano-model bench + low-end tuning (measured on-device 2026-06-14)

Full nano-tier sweep on an M4 Pro (18 GB unified), winc eval profile (16384 ctx, q8 KV,
reasoning + draft off), default `/v1/messages` path. Candidate = a PM career-changer résumé;
8 labeled JDs (4 genuine entry/adjacent **accepts**, 4 **rejects** incl. 3 senior/exec/manager
"dangerous traps"), N=3 → 24 evals/model. "Footprint" = resident RSS post-warmup.

| Model | Disk | Footprint (RSS) | Accuracy* | Parse-fail /24 | Dangerous /9 | Latency/eval | tok/s |
|---|---|---|---|---|---|---|---|
| qwen3.5-0.8b | 0.49 GiB | 0.87 GiB | 35% (6/17) | 7 | **3** | 0.93 s | 78.7 |
| qwen3.5-2b (Q4) | 1.19 GiB | 1.57 GiB | 65% (13/20)† | 4 | 0 | 3.46 s | 76.6 |
| qwen3.5-2b-q8 | 1.87 GiB | 2.22 GiB | 89.5% (17/19) | 5 | 0 | 3.99 s | 62.1 |
| **gemma4-e2b** (Q4) | 2.89 GiB | 3.08 GiB | **100% (23/23)** | 1 | 0 | 3.95 s | 70.9 |
| qwen3.5-4b (Q4) | 2.55 GiB | 3.27 GiB | 100% (24/24) | 0 | 0 | 7.77 s | 45.1 |
| qwen3.5-4b-q8 | 4.17 GiB | 4.86 GiB | 100% (24/24) | 0 | 0 | 8.88 s | 37.8 |

\* on PARSED evals; the parse-fail column is the other half. † highly run-variable — see below.

**Findings.** (1) Accuracy cliff: e2b/4B/4B-Q8 = 100%; only the **0.8B is unsafe** (35% + accepts
VP/Staff/Manager as entry). (2) **gemma4-e2b is the sweet spot**: ties the 4B's accuracy + JSON
reliability at **~2× the speed** — which is why it's winc's low-end default. (3) **Footprint surprise**:
e2b's RESIDENT memory (3.08 GiB) ≈ the 4B (3.27), despite "E2B" — the Matformer stores ~4B weights,
activates ~2B; its win is speed, not memory. (4) **Parse-reliability** (default `/v1/messages` path) is
the hidden axis: 0.8B 29% → 2B ~17–21% → e2b 4% → 4B 0%.

### Low-end tuning — can the 2B-Q4 (½ the e2b footprint) reach parity?

The 2B-Q4's "65%" is not fixed — at the inherited agent sampling (**temp 0.7**) it swings 65%→100%
run-to-run. Two deterministic levers, tested on qwen3.5-2b (N=3, same 8-JD set):

| Condition | Accuracy | Parse-fail /24 | Dangerous /9 |
|---|---|---|---|
| baseline (`/v1/messages`, temp 0.7) | 100% (19/19)‡ | 5 | 0 |
| temp-0 (`/v1/messages`) | 100% (12/12) | **12** | 0 |
| json-schema (temp 0.7) | 79.2% (19/24) | 0 | 2 |
| **temp-0 + json-schema** | **100% (24/24)** | **0** | **0** |

‡ a lucky run (true range 65–100%). **Verdict: feasible.** `temp-0 + guaranteed-JSON`
(`response_format=json_schema` on winc's `/v1/chat/completions`, the jobfaro.4 feature) takes the 2B to
**100% / 0 parse-fails / 0 dangerous on this set** — at half the e2b footprint (1.6 vs 3.1 GiB). Neither lever
works alone: temp-0 on `/v1/messages` *worsens* parse-fails (the model deterministically derails out of
JSON), and JSON-alone at temp 0.7 still mis-accepts. **Shipped** (winc 1.21.4-jobfaro.4 + Jobfaro 1.25.0): the eval profile decodes greedy (`--temp 0 --top-k 1`,
`applyEvalProfile` → `GreedySampling`) and Jobfaro auto-routes local-backend evals through the JSON-schema
endpoint (`active.jsonEval`, default-on; opt out with `eval_grammar: false`; graceful fallback to
`/v1/messages` on error). End-to-end re-verify through Jobfaro's real pipeline: qwen3.5-2b-Q4 **100% / 0
parse-fails / 0 dangerous** (24 evals), e2b + 4B held 100%, greedy confirmed on the server.

**Validation status — promising, NOT yet production-proof.** This is one 8-JD policy-boundary set (24
deterministic evals) on one résumé; a clean 100% is encouraging but small. Open caveats: a JSON *schema*
guarantees parseable output, NOT correct reasoning (format ≠ judgment); greedy could in principle hurt
borderline Research-band cases vs. sampling; the 65% baseline was itself one noisy run. **Before treating
the 2B-Q4 as the production eval floor, validate on:** (1) a larger, diverse JD set (N ≥ 100) hand-banded
as ground truth; (2) a human spot-check of 2B verdicts vs. the 4B; (3) a temp>0-vs-greedy comparison to
confirm greedy isn't masking brittleness; (4) hard edge-band cases. Until then it is a strong low-end
*candidate* that would drop the trustworthy-eval floor toward ~1.6 GiB (2B-Q4) from ~3 GiB (e2b).

## Sources

- [Evaluating the Promise and Pitfalls of LLMs in Hiring Decisions (arXiv 2507.02087)](https://arxiv.org/pdf/2507.02087)
- [Evaluating Bias in LLMs for Job-Resume Matching (arXiv 2503.19182)](https://arxiv.org/pdf/2503.19182)
- [Explicit Reasoning Makes Better Judges (arXiv 2509.13332)](https://arxiv.org/pdf/2509.13332)
- [LLM-as-a-judge: a complete guide — Evidently](https://www.evidentlyai.com/llm-guide/llm-as-a-judge)
- [LLM-as-a-Judge — Langfuse docs](https://langfuse.com/docs/evaluation/evaluation-methods/llm-as-a-judge)
- [LLM-as-a-Judge guide — Confident AI](https://www.confident-ai.com/blog/why-llm-as-a-judge-is-the-best-llm-evaluation-method)
- [LLM-as-a-Judge — Comet](https://www.comet.com/site/blog/llm-as-a-judge/)
- [Calibrating, Guarding & Debiasing LLM Evaluators — Kinde](https://www.kinde.com/learn/ai-for-software-engineering/best-practice/llm-as-a-judge-done-right-calibrating-guarding-debiasing-your-evaluators/)
- [LLM as Judge: what engineers get wrong — Vadim](https://vadim.blog/llm-as-judge)
- [BLS wage data by area & occupation](https://www.bls.gov/bls/blswage.htm) · [BLS data tools](https://www.bls.gov/data/) · [ECI](https://www.bls.gov/eci/)
- [unpdf (UnJS)](https://github.com/unjs/unpdf) · [unpdf vs pdf-parse vs pdf.js — PkgPulse](https://www.pkgpulse.com/blog/unpdf-vs-pdf-parse-vs-pdfjs-dist-pdf-parsing-extraction-nodejs-2026) · [Strapi: 7 PDF parsing libraries](https://strapi.io/blog/7-best-javascript-pdf-parsing-libraries-nodejs-2025)

## §7 — Calibration pass + the bimodal finding (2026-06-16, v1.42.0)

A cross-persona matrix (PM / SWE / analyst résumés × PM / ML-eng / marketing / VP roles, live winc
qwen3.5-4b) showed the evaluator **discriminates correctly** (right persona tops its role; over-level VP
rejected for all) but the score distribution is **bimodal** — clusters at Apply and Don't with an **empty
Research band (3.5–3.9)**.

Fixes shipped (code-side): (1) **5-level ratings** (strong/good/partial/weak/none) to smooth the score
lattice so Research is reachable; (2) the **clamp no longer cliffs on a years shortfall** (it shapes the
score via the experience sub-criterion; hard credentials still clamp) — verified live (a 2-yr engineer vs a
3–6-yr role is `clamped:false`, not force-zeroed); (3) prompt **reserves `none`** for zero signal; (4)
**`/evaluate` guards an empty JD** (unfetchable listing → honest "couldn't assess", not a résumé-blind
Apply); (5) `jobfaro calibrate` gained a **score-distribution report** + **per-item cv**.

**What these do NOT fix (needs data, not code):** on the small live matrix the distribution stayed bimodal.
Two causes — the test set had few genuine *borderline* roles (mostly clear fits / over-reaches / over-level),
and the model still rates confidently at the extremes (it rated a 2-yr engineer's directly-relevant
experience `none` despite the prompt). Reviving the Research band for real requires a **labeled calibration
set (N≥50–100)** to recalibrate the band thresholds from the actual score distribution and/or A/B the sub-
criteria weights — the `calibrate --file` distribution report + a future thumbs-up/down feedback loop in the
app are the data collectors that make that possible. Band thresholds must NOT be moved by guesswork.

## §8 — The Apply-inflation audit + the measured v2 prompt (2026-08-28, v1.52.0)

A full audit of the real pipeline (8,361 rows, 244 scored) found §7's bimodality had **flipped
direction** on the decomposed engine: the 2026-08-19 run put **54% of scored roles in Apply** (30/56,
Research 1/56) with a **17-way tie at 4.8** spanning an email-marketing internship, eight
near-identical "Administrative Support III" postings, and a fleet-platform SWE role — against the same
technical-PM résumé. Three prompt-side causes were identified in code:

1. **One-sided caution.** The prompt reserved `none` ("use rarely") but said nothing symmetric about
   `strong` — so the model answered `strong` reflexively (logistics `strong` on 46/50 real JDs).
2. **`logistics`/`education` were never defined**, and no location ever reached the model — 10% of
   every score was rated blind.
3. **The JSON template anchored high**: 3 of its 5 example ratings were `strong`.

**The v2 prompt** (shipped 1.52.0) defines all five criteria, adds the strict-at-both-ends rule
("strong" only when the résumé explicitly demonstrates THIS criterion for THIS role's actual work),
shows each rating level exactly once in the template, wires candidate location + target regions + job
location into the user message, and floors the transferable-mode bridge rule (generic professional
strengths are NOT bridges; never-done-the-core-work caps `experience` at `partial`). Still NO anchor
examples (8a.4b's few-shot rejection stands). Temperature 0 is now pinned in code for every backend.

**Measured** (50 live real JDs from the actual pipeline, hand-banded vs the real résumé/profile;
old = shipped v1.51.0 prompt, byte-replicated; same serve, greedy, json_schema; the bench scripts,
corpus, labels, and raw results are archived in `data/eval-bench-2026-08-28/` (local, gitignored),
and the labeled set now lives at `data/calibration.json` — plain `jobfaro calibrate` runs it):

| | old (v1) | v2 | hand labels |
|---|---|---|---|
| Apply / Research / Don't | 22 / **0** / 28 | 5 / 11 / 34 | 5 / 9 / 36 |
| core-label agreement (30 non-debatable) | 87% | **90%** | — |
| all-label agreement (50) | 56% | **64%** | — |
| scores ≥ 4.75 | 7 | 3 | — |

Every audited trap flipped honestly (intern 4.1→2.9, Employee Recognition 4.8→2.9, Emergency
Communications 4.1→2.9, the Admin III clones 4.1–4.8→3.5/2.9), while the genuine matches ROSE
(IS Project Manager II 4.4 Apply, Consultant Technology PM 4.5→5.0, CSS Tech II 4.8→5.0) — the
deflation is discriminating, not blanket. **The Research band is alive for the first time (0→11).**

Known cost: one under-accept — an entry Project Coordinator (labeled Apply) landed 3.4. It sits in
the borderline-escalation zone (±0.3 of a threshold), which `--escalate` exists to re-score.

**Thresholds stay 4.0/3.5.** The sweep's best alternative (4.0/3.9) wins by exactly one item on 30
core labels — inside noise. Per §7's rule, thresholds move on N≥50–100 real labels only; 1.54.0's
`jobfaro feedback` + the app thumbs are the collectors.

**Recalibration discipline:** ANY wording change to `EVAL_SYSTEM`/`TRANSFERABLE_EVAL_NOTE`/
`buildEvalUser` is a recalibration event — re-run this bench (old-vs-new on the labeled corpus)
before shipping, exactly as the rejected 2026-07-09 prompt-reorder taught.
