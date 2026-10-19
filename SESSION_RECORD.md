# MemGate — Session Record

**Capstone Project** · SVKM's NMIMS, Indore Campus
Simar Singh Khanuja & Yash Ramchandani
Session 1: 12 August 2026 · Session 2: 17 August 2026 · Session 3: 24 August 2026 · Session 4: 27 August 2026
Session 5: 17 September 2026 · Session 6: 25 September 2026

A complete record of what was discussed, decided, built and found in these
working sessions. Written so it can be picked up cold later.

---

> ## ⚠ READ FIRST — Session 2 corrected the Step 0 headline numbers
>
> Session 2 found an **evaluation leak**: the memory policy was reading
> `fact_id`, which is the *ground-truth answer key*, when deciding what to keep.
> The Step 0 results in §6 and the "95% vs 10%" claim in the **Review 1 deck**
> are inflated by it and **must not be presented again as they stand**.
>
> | Synthetic set @ 800 tokens | As presented | Honest |
> |---|---|---|
> | P1 MemGate | 95.0% | **50.0%** |
> | P0 sliding window | 10.0% | 10.0% |
>
> The leak is fixed, pinned by a regression test, and the project now has real
> LoCoMo numbers. Full detail in **§13**.
>
> ## ⚠ ALSO READ — Session 3 changed the headline claim
>
> §22 concluded that the compression machinery was a **net loss** against
> simply keeping everything and retrieving. Session 3 imposed the missing
> **storage budget** and re-ran it. The corrected finding:
>
> * **Selection wins.** Forgetting by scored utility rather than oldest-first
>   is worth **+8.7 answer-recall points** at identical storage and identical
>   fidelity — that gap is the decision policy and nothing else.
> * **Compression still loses.** Compressing on eviction wins *evidence*
>   recall and loses *answer* recall, because a gist keeps the ids of a turn
>   whose text it discarded.
>
> Do not present tiered compression as validated. Full detail in **§23**.
>
> ## ⚠ SESSION 4 — the project is now results-complete
>
> §24 closes every open item. Headline claims now carry clustered confidence
> intervals, and **one earlier claim did not survive**: the select-vs-RAG gain
> on *evidence* recall is **not significant** (p = 0.16). The *answer*-recall
> gain is (+8.67, CI [+4.77, +14.27]). Quote the answer metric only.
>
> The rate-distortion prediction from §23.4 — that compression must eventually
> beat selection — is **falsified to 182x compression** (§24.1).
>
> `REPORT.md` at the project root is the paper-ready writeup.
>
> ## ⚠ SESSION 5 — the critical path is closed
>
> §29 completes the **full 715-question end-task run**. The headline claim no
> longer rests on context recall alone: **+6.0 of the +8.7 points are realised
> as correct answers** (95% CI [+3.3, +9.1] clustered, 69% of the ceiling gap),
> against a **1.7% closed-book floor**.
>
> No earlier number is withdrawn by this. The end-task pilot figures quoted
> anywhere as "12 questions" are superseded by §29.3 — do not present them.
>
> ## ⚠ SESSION 6 — the §23 headline does not replicate, and we know why
>
> §30 ran LongMemEval. At storage matched to LoCoMo's retention, scored
> selection **loses to FIFO by 21 answer points** where LoCoMo gives +8.67.
>
> The cause is not the mechanism. `HeuristicScorer`'s separation between
> evidence and non-evidence turns **reverses sign** between the two corpora
> (+0.0476 → −0.0346), so eviction discards evidence preferentially. It is a
> scorer transfer failure — the heuristic was written for LoCoMo's 32-token
> dialogue lines and LongMemEval's turns are 210-token prose.
>
> **The +8.67 claim still stands on LoCoMo** and no earlier number is
> withdrawn. What changes is its scope: it is what a policy recovers *given a
> scorer suited to the corpus*. The paper now carries that limitation.
>
> Two things must happen before any LongMemEval number is published: the
> `split[0]=0` re-run of §30.4, and the missing S=32,768 point. And **never
> quote LongMemEval strict recall for a compressing arm** (§30.6).

---

## 1. What the project is

**Original topic:** AI Memory Compression for LLM Agents — "an operating system
for AI memory".

**Working name:** **MemGate** (just a name; can be changed freely).

**One-line definition:**
> MemGate is a software layer that wraps an existing LLM (open model or hosted
> API) and controls what enters the prompt on each turn. It decides what to
> **keep**, **compress**, **forget** and **recall**, so long multi-session
> conversations stay inside a fixed token budget without losing what matters.

It treats the base model as a **black box**. We train nothing.

**Explicitly out of scope:** re-training/fine-tuning the base model, image or
audio memory, a polished product or UI, production/multi-user serving.

---

## 2. Key decisions taken this session

| # | Decision | Rationale |
|---|---|---|
| 1 | Deck must use the **NMIMS template** (red bands, logo, serif) | Faculty requirement; matched the EcoHazNet reference deck exactly |
| 2 | Build **real editable diagrams**, not AI-image placeholders | More original than the reference deck, and editable |
| 3 | **Base paper = MemGPT** (Packer et al., 2023) | Matches the "LLM as an OS" framing; our work extends its missing decision policy |
| 4 | Scope = **P0–P3 only**; **P4 (interactive) on hold** | Pending faculty approval; keeps the core project safe from UX risk |
| 5 | Rename "Importance Scoring" → **Adaptive Memory Decision Engine** | Clearer, and names the actual contribution |
| 6 | Replace "learned scoring" → **"adaptive importance scoring policy"** | More precise wording in the literature-review gaps |
| 7 | **Sharpen the positioning** (see §4) | Tiered memory alone is no longer novel — production systems ship it |
| 8 | Step 0 metric = **context recall @ budget** | Isolates the memory policy from model reasoning; no API key needed |
| 9 | **Build the evaluation harness before the clever parts** | Makes every later idea a measurable experiment, not a guess |

---

## 3. The four panel objections, and the answers

### Q1 — Is this project really required in the current phase?

**Yes.** The objection assumes large context windows solved this. Evidence says
they relocated the problem rather than removing it.

* **Context rot** — Chroma Research (July 2025) tested 18 frontier models
  (GPT-4.1, Claude 4, Gemini 2.5, Qwen3): accuracy degrades **30–50% well before
  the documented context limit**. A 200K window can show serious loss at ~50K
  tokens. It is an *architectural property of attention*, not a training gap —
  so bigger windows don't fix it, curation does.
* **Cost and latency** — on LoCoMo, full-context ≈ 72.9% accuracy at ~26,000
  tokens and 9.87 s median / 17.12 s p95 latency; selective memory ≈ 66.9% at
  ~1,800 tokens and 0.71 s / 1.44 s. Roughly **14× cheaper, ~91% lower p95**.
* **Live industry problem** — a whole product category exists: Letta/MemGPT,
  Mem0, Zep, Cognee. Independent comparisons report up to **15-point accuracy
  gaps between memory architectures** on temporal queries.

### Q2 — Is it feasible?

**Yes**, because we train nothing.

* Inference only — a single GPU or Colab runs a 7–8B open model; the large model
  is reached by API.
* Public benchmarks already exist (LoCoMo, LongMemEval, LongBench) — no data
  collection.
* Every heavy component is mature open-source (embeddings, vector search,
  summarisation).
* Staged phases, each independently demoable.
* Only recurring cost is limited API calls.

### Q3 — Is more research required in this area?

**This is the one the panel was right about.** Tiered memory with forgetting is
*already shipped* by Letta, Mem0 and Zep. Presented as "a memory layer with
three tiers", the honest verdict is that it has been built.

The novelty must sit one level deeper — in the **decision policy** — and that is
exactly where the field says the gap is:

* A 2026 review states current systems **"do not solve the fundamental
  challenge: deciding what to remember and what to forget"**.
* **Adaptive compression is still heuristic**; **relevance scoring lacks
  theoretical guarantees**.
* Memory **staleness** and cross-session consolidation are named open problems.
* Temporal reasoning is the hardest category (~25% loss when scaling 10×).

**The measurable gap:**
* LongMemEval — oracle retrieval ≈ **92%**, same model interactive ≈ **58%**:
  a **34-point gap** that is purely memory-selection failure, not reasoning.
* LoCoMo — selective memory is ~14× cheaper but still **~6 points behind**
  full-context.

**Theory now exists, but no system:** *"What to Keep, What to Forget: A
Rate–Distortion View of Memory Compaction in LLMs and Agents"* (Colaco &
Lahjouji, arXiv:2607.08032, July 2026) argues all memory-compaction decisions
are one problem — a rate–distortion decision about what to retain, at what
fidelity, under a budget, to preserve downstream utility. It is a *framework,
not a system*. That is our opening.

### Q4 — What is the end product?

1. **MemGate library** — installable Python package wrapping any LLM.
2. **Evaluation harness** — reports accuracy *and* tokens *and* latency together.
3. **Empirical results** — policy comparison + ablations + frontier plots.
4. **Report + demo** — paper-shaped report, plus a live long-conversation demo.

---

## 4. Sharpened project statement (use from Review 2 onward)

> MemGate is not "another memory layer". It is a study of **the memory decision
> policy itself**: we treat keep / compress / forget as a **rate–distortion
> problem under a fixed token budget**, implement several scoring policies
> (heuristic, LLM-judged salience, and a distilled scorer), and measure them on
> a common **accuracy-per-token frontier** against full-context and existing
> memory systems.
>
> **Research question:** how much of the 6-point cost–quality gap and the
> 34-point oracle gap can a better decision policy recover, and at what token
> budget?

---

## 5. Technical design

### The three tiers — a lifecycle, not a partition

Everything enters Tier 1. The routing decision happens **on eviction** from
Tier 1 (cheaper: each item is scored once, after the point where it's still
trivially available).

| Tier | Holds | Criterion | In context? |
|---|---|---|---|
| **1 — Short-term** | raw verbatim turns | **When** — recent? (FIFO, no scoring) | Always |
| **2 — Working** | compressed summaries | **Gist** — continuity worth keeping? | Always (small) |
| **3 — Long-term** | atomic facts + embeddings | **What** — durable, retrievable? | Only on retrieval match |

Tiers are **not mutually exclusive** — one evicted segment can drop a fact into
Tier 3 *and* contribute a line to the Tier 2 summary.

### Routing rule

```
u >= tau_fact   -> Tier 3 (durable fact), embed + dedupe
u >= tau_low    -> Tier 2 (compressed gist)
otherwise       -> dropped from context
```

Defaults used: `tau_fact = 0.45`, `tau_low = 0.15`, buffer `N = 6`,
budget split `(short 25%, working 25%, long 50%)`.

### Four scoring signals

1. **Durability** — entities, numbers, dates, decisions, preferences, constraints
2. **Novelty** — cosine distance to nearest existing memory (dedupe)
3. **Reference-likelihood** — is this the kind of thing asked about later?
4. **Filler detection** — greetings, acknowledgements

### Memory staleness

Handled by `superseded_by` on the record, plus `last_accessed`, `access_count`
and `source_ids`. A later "Actually, push the deadline to April 2" marks the
earlier March 15 fact as superseded. This is one of the open problems named in
the 2026 literature.

### Tier 2 consolidation

Tier 2 cannot grow forever. Over budget → recursively re-summarise the oldest
half; anything carrying a durable fact demotes to Tier 3, the rest is dropped.
That is the cache → RAM → disk demotion path.

### The four policies

| | Policy | Scoring | Status |
|---|---|---|---|
| P0 | Sliding window | recency only, **budget-driven** | done |
| P1 | MemGate heuristic | rules + shallow NER + novelty | done |
| P2 | LLM-judged salience | small LLM rates importance 0–1 + type | Phase 3 |
| P3 | Distilled scorer | trained on P2's labels — P2 quality at P1 cost | Phase 3 |

### P4 — Interactive (ON HOLD, pending faculty)

Discussed but deferred. The idea: ask the user whether to save an item.

* Naive version fails — friction/consent fatigue, doesn't scale, users can't
  predict future needs, **and it breaks offline benchmark evaluation**.
* Workable version: **confidence-gated active learning** — auto-route when
  confident, ask *only* in the uncertainty band. Plus explicit commands
  ("remember that…"), batched end-of-session review, passive correction.
* Upside: every user answer is a **training label** for P3, and it adds a second
  axis — *accuracy per user question*.
* Can be evaluated offline with a **simulated user** (benchmark QA pairs reveal
  which facts were needed later).

---

## 6. Step 0 — what was built and what it showed

### Built (~1,150 lines, 30/30 tests passing, zero dependencies)

```
memgate/
  memgate/
    types.py     MemoryItem, Turn, Question (incl. superseded_by)
    utils.py     tokenizer + hashing embedder   [SWAP-IN marked]
    store.py     three-tier store, dedupe, supersession, consolidation
    scoring.py   P0/P1 implemented; P2/P3 stubs on the same interface
    policies.py  baselines + MemGate, routing + budget-aware assembly
    data.py      synthetic generator + integrity assertions + LoCoMo stub
    harness.py   metrics, sweep, table/CSV output
  run_experiment.py    diagnose.py    test_memgate.py    README.md
```

Runs with **no API key, no GPU, no downloads**.

### Results (synthetic set: 600 turns / 20 sessions / 40 probes)

> **⚠ SUPERSEDED — these numbers contain the evaluation leak. See §13.**

| Policy | Budget | Recall | Avg tokens |
|---|---|---|---|
| Full-context | unlimited | 100.0% | 5451 |
| Oracle (diagnostic bound) | 3200 | 100.0% | 16 |
| P0 sliding window | 800 | 10.0% | 800 |
| **P1 MemGate** | 800 | **95.0%** | 626 |
| P0 sliding window | 3200 | 57.5% | 3198 |
| **P1 MemGate** | 1600 | **100.0%** | 976 |

**Headline:** MemGate reaches the same **100% recall as full-context using
5.6× fewer tokens**; at an equal 800-token budget it recalls **95% vs P0's 10%**.

### Honest caveat to state before anyone asks

This is a **synthetic sanity set, not a research result**. It proves the
pipeline and metrics are correct. Real numbers need LoCoMo. The embedder is a
hashing bag-of-words and the summariser is extractive — both marked `SWAP-IN`.

---

## 7. Bugs found and fixed (worth knowing — they show method)

1. **P0 was a strawman.** First version gave the sliding window a fixed 12-turn
   window → 0% everywhere. Changed to **budget-driven**: P0 now spends exactly
   the same token budget as MemGate, so the only difference is *which* turns are
   chosen. Its score rose to 57.5% and MemGate still dominates — a defensible
   comparison.
2. **Duplicate fact statements.** Two different `fact_id`s rendered *identical
   text*; the deduper correctly collapsed them, making one permanently
   unanswerable. Looked like a memory failure but was a **dataset artefact**.
   Fixed by giving each fact a unique subject (100 unique combinations) and
   adding `_assert_wellformed()` so it can't recur silently.
3. **Duplicate probe questions** — caught by the new assertion immediately after
   fixing #2 (the "project" template's probe didn't reference the unique subject).
4. **`retrieve_k` bound before the budget did**, flattening the frontier. Raised
   k so the *budget* is the binding constraint.
5. **Deck:** references slide rendered `[object Object]` (text-run nesting);
   Gantt legend collided with the footer; long titles wrapped and overlapped
   body text in the NMIMS template (fixed by forcing placeholder geometry and
   disabling autofit at the XML level).

> Lesson worth repeating in the report: building the **harness first** is what
> surfaced #1–#4. A measurement artefact that looks like a model failure is the
> most dangerous kind of bug.

---

## 8. Deliverables produced

| File | What it is |
|---|---|
| `MemGate_Capstone_Review1_NMIMS_v3.pptx` | 17-slide Review 1 deck in the NMIMS template |
| `MemGate_Defence_and_Build_Plan_FINAL.pdf` | 6-page evidence-backed answers to the four objections + full build plan |
| `MemGate_Technology_Stack.pdf` | One-page tech stack + architecture mapping |
| `memgate/` | Step 0 source code, tests, harness |
| `SESSION_RECORD.md` | This document |

**Deck structure (17 slides):** Title → Introduction → Problem Statement →
Objectives → Scope → Need → Proposed System → System Architecture →
Implementation Workflow → Tools & Technology → Feasibility → Literature Review
(1–2) → Gantt Chart → References → Thank You → *Backup: Implementation Roadmap*.

---

## 9. Literature (10 verified citations)

Author lists, venues and years were each verified against source pages.

1. **Packer et al. (2023)** — *MemGPT: Towards LLMs as Operating Systems*, arXiv:2310.08560 ← **base paper**
2. Zhong et al. (2024) — *MemoryBank*, AAAI 38(17), 19724–19731
3. Park et al. (2023) — *Generative Agents*, UIST '23
4. Xiao et al. (2024) — *StreamingLLM / Attention Sinks*, ICLR
5. Zhang et al. (2023) — *H2O: Heavy-Hitter Oracle*, NeurIPS
6. Jiang et al. (2023) — *LLMLingua*, EMNLP, 13358–13376
7. Mu, Li & Goodman (2023) — *Learning to Compress Prompts with Gist Tokens*, NeurIPS
8. Chevalier et al. (2023) — *Adapting Language Models to Compress Contexts*, EMNLP
9. Zhang et al. (2024) — *Survey on the Memory Mechanism of LLM-Based Agents*, arXiv:2404.13501
10. Xu et al. (2025) — *A-MEM: Agentic Memory for LLM Agents*, NeurIPS, arXiv:2502.12110

**Additional 2025–2026 sources** used for the defence document: Chroma Research
*Context Rot* (2025); Colaco & Lahjouji, arXiv:2607.08032 (2026); LongMemEval
(arXiv:2410.10813); LoCoMo (Maharana et al., 2024); 2026 agent-memory benchmark
and framework surveys.

> Note: several 2026 performance figures come from **vendor blogs** and should
> be treated as indicative. Re-measuring them under one harness is itself part
> of the contribution.

---

## 10. Build plan — remaining steps

| Step | Work | Done when |
|---|---|---|
| ~~0~~ | ~~Harness + baselines~~ | ✅ **complete** |
| 1 | Wire `load_locomo()`; swap in `sentence-transformers` | Real benchmark numbers reproduced |
| 2 | Real abstractive summariser in the compressor | Budget never exceeded, quality holds |
| 3 | P2 LLM-judge; then distil into P3 | P3 approaches P2 accuracy at far lower cost |
| 4 | Full sweep, ablations, frontier plots, second model | Frontier chart complete |
| 5 | Report, demo, packaging | Submitted |

**Ablations planned:** remove each scoring signal; vary token budget; vary buffer
size N; disable retrieval fallback — to show which component earns the gain.

---

## 11. Open items

* **P4 (interactive memory)** — on hold pending faculty opinion.
* **Project name** — "MemGate" is provisional.
* **Real-data demo** — running MemGate over *this session's own transcript* was
  proposed as a second, non-synthetic demo (dogfooding). Not yet done.
* **Blocker:** the sandbox needs free space on the **internal** drive to run
  code; an external volume doesn't provide its scratch space. P2/P3 build is
  waiting on this.

---

## 12. How to run

```bash
cd ~/Documents/Capstone\ Project/memgate
python3 test_memgate.py      # expect: 30 passed, 0 failed
python3 run_experiment.py    # table + results/step0_results.csv + frontier.png
python3 diagnose.py          # miss analysis by cause
```

Python 3.8+. `matplotlib` only for the plot; everything else is standard library.

---

# Session 2 — 17 August 2026

## 13. The evaluation leak, and what it was hiding

### 13.1 What was found

`store.py` consulted `MemoryItem.fact_id` in two decisions:

```python
if it.fact_id or it.utility >= 0.5:      # consolidation: promote to Tier 3
if source.type_label == "update" and source.fact_id:   # supersession target
```

`fact_id` is the **ground-truth evaluation label** (`types.py`) — the harness
scores a policy by asking whether the gold `fact_id` reached the context. So the
policy was reading the answer key to decide what to keep.

Isolating the single promotion clause on the synthetic set:

| Budget | P1 as presented | P1 leak-free | P0 |
|---|---|---|---|
| 400 | 92.5% | **45.0%** | 5.0% |
| 800 | **95.0%** | **50.0%** | 10.0% |
| 1600 | 100.0% | **52.5%** | 27.5% |
| 3200 | 100.0% | **52.5%** | **57.5%** |

Roughly **45–47 points** of the headline was the leak. The Review 1 claim
"95% vs 10% at 800 tokens" does not survive; the honest figure is **50% vs 10%**,
and at 3200 tokens **P0 overtakes MemGate**.

### 13.2 What the leak was hiding — a dead consolidation path

Removing it exposed a structural flaw. Routing sends items scoring
`u >= tau_fact (0.45)` straight to Tier 3, and `u >= tau_low (0.15)` to Tier 2.
Consolidation then promotes out of Tier 2 only if `u >= 0.5`. But **every item in
Tier 2 scored below 0.45 by construction**, so nothing can ever clear 0.5.

Tier 2 was a death chamber: everything entering it was eventually discarded.
`it.fact_id` had been silently performing the retention that the consolidation
policy was supposed to perform. On LoCoMo this shows up starkly — of 419 turns in
`conv-26`, only **30 (7.2%)** are retained anywhere.

This is the design in §5 ("recursively re-summarise the oldest half") not
actually being implemented — consolidation *discards* rather than re-summarises.
**Implementing it properly is now the main technical task**, and it is exactly
the rate–distortion question the project claims as its contribution.

### 13.3 Guard against recurrence

`test_memgate.py` pins it: the store must come out **bit-identical** when every
`fact_id`/`is_filler` is stripped from the input turns.

```
PASS  routing is invariant to ground-truth labels
```

Any future decision that reads a label fails this test. Same discipline as
`_assert_wellformed()` for dataset artefacts.

### 13.4 A second scorer bug found the same way

`UPDATE_HINTS` contained `"instead"`, so *"I decided to use Django for the board
**instead of** Rails"* was classed as a correction. 6 turns were labelled
`update` on a set that plants exactly **1**. Because those decision sentences are
near-identical in wording, semantic supersession then had them **retire each
other** — a cascade costing ~10 recall points. Fixed by separating genuine
correction cues (`actually`, `no longer`, `revised`, …) from contrastive
phrasing.

### 13.5 Fairness fix: budget-aware store sizing

`working_capacity_tokens` was pinned at 400 regardless of budget, so MemGate
could not fill a 4096-token budget however well it scored — it spent 1336. That
is the **same strawman that was fixed for P0 in Step 0**, pointed the other way.
Tier 2 is now sized from the budget. Effect on LoCoMo: 8.9% → **10.8%** at 2048,
9.1% → **15.1%** at 4096.

---

## 14. LoCoMo is wired (Step 1)

`load_locomo()` is implemented. 10 conversations, **5882 turns**, **1527
scoreable questions**.

**Two data hazards, both silent if unhandled:**

1. **`dia_id` is unique only within a conversation** — 5882 turns share just
   1033 distinct ids; `D1:1` exists in every conversation. Ids are namespaced
   `<sample_id>/<dia_id>`, otherwise evidence matches turns from unrelated
   conversations.
2. **9 questions cite evidence turns that do not exist**, plus 4 with empty
   evidence — unanswerable by construction, so dropped rather than left to
   depress every policy equally.

**Category mapping was verified from the data, not assumed:** category 1
averages 3.13 evidence turns (max 19) vs category 4's 1.07, and all 446
category-5 items carry an `adversarial_answer` field.
→ 1 multi-hop, 2 temporal, 3 open-domain, 4 single-hop, 5 adversarial.

**Adversarial (category 5) is excluded from the headline metric.** Those
questions *do* carry evidence, but the correct behaviour is to decline to
answer, so retrieving the evidence does not indicate success.

**The metric is now multi-evidence** — a multi-hop question needs up to 19
turns, and retrieving 18 of 19 answers nothing:
* **strict recall** — every evidence turn present (headline)
* **soft recall** — mean fraction present (partial credit)

They coincide on single-evidence questions, which is why Step 0 needed only one.

## 15. First real LoCoMo numbers

**MiniLM 384d + tiktoken (`cl100k_base`)**, budget-aware sizing.
`strict` = every evidence turn present; `soft` = mean fraction present.

| Policy | Budget | Strict | Soft | Avg tokens |
|---|---|---|---|---|
| Full-context | unlimited | 100.0% | 100.0% | 18 959 |
| Oracle | 512 | 99.9% | 100.0% | 65 |
| P0 sliding window | 512 | 1.6% | 1.9% | 509 |
| **P1 MemGate** | 512 | **7.0%** | 8.7% | 487 |
| P0 sliding window | 1024 | 4.3% | 4.9% | 1022 |
| **P1 MemGate** | 1024 | **8.5%** | 10.5% | 899 |
| P0 sliding window | 2048 | 10.1% | 11.4% | 2047 |
| **P1 MemGate** | 2048 | **11.0%** | 13.3% | 1432 |
| P0 sliding window | 4096 | **18.8%** | 21.8% | 4094 |
| P1 MemGate | 4096 | 15.3% | 18.2% | 2058 |

### 15.1 The embedder buys almost nothing — as predicted

| Budget | P1 hashing | P1 MiniLM | Δ |
|---|---|---|---|
| 512 | 6.0% | 7.0% | +1.0 |
| 1024 | 8.1% | 8.5% | +0.4 |
| 2048 | 10.8% | 11.0% | +0.2 |
| 4096 | 15.1% | 15.3% | +0.2 |

**This was predicted before the run and is the strongest methodological result
of the session.** The diagnostic showed retrieval reaching 6.7% against a
write-path ceiling of 9.4% — nearly saturated — so a better embedder had almost
nothing left to recover. Swapping a bag-of-words hash for a 384-dimension
transformer moves the headline by **0.2 points at the working budget**.

The corollary matters for planning: **effort spent on retrieval, re-ranking or
a larger embedding model is effort wasted** until the write path stops
discarding 93% of the conversation. The embedder does earn its place — but on
supersession (§16.1), not on recall.

### 15.2 Per-category, at 2048 tokens

| Policy | multi-hop | temporal | open-domain | single-hop |
|---|---|---|---|---|
| Oracle | 100.0% | 100.0% | 100.0% | 100.0% |
| P0 sliding window | **2.2%** | 9.4% | 7.9% | 13.2% |
| P1 MemGate | 0.7% | **13.4%** | **12.4%** | **13.3%** |
| *(n questions)* | *278* | *320* | *89* | *840* |

MemGate wins on temporal, open-domain and single-hop, and is **crushed on
multi-hop (0.7% vs 2.2%)**. That is arithmetic, not a separate defect: multi-hop
questions cite 3.13 evidence turns on average, strict recall demands *all* of
them, and only ~7% of turns are retained. Retention failure compounds
multiplicatively with evidence count. Fixing the write path should lift
multi-hop fastest.

**Read this honestly: on real data the current heuristic does not work.** It
wins at tight budgets (6.0% vs 1.6% at 512) and at 2048, but P0 overtakes it at
4096. Multi-hop recall is ~0%.

The diagnosis is unambiguous and it is **not** retrieval:

```
conv-26:  turns retained anywhere        30/419  (7.2%)
          WRITE-PATH CEILING              9.4%
          read path (k=60, no budget cap) 6.7%
```

Retrieval reaches 6.7% against a ceiling of 9.4% — it is nearly saturated. **The
write path throws away 93% of the conversation.** No retrieval or embedding
improvement can beat 9.4% until Tier 2 stops discarding.

This is a real, defensible result: the P1 heuristic was tuned on synthetic data
where facts are explicit declaratives ("The deadline is March 15"). Natural
dialogue carries durable information diffusely, and a keyword-and-regex scorer
does not see it. **That is precisely the gap P2/P3 exist to close**, and it is now
measured rather than assumed.

`diagnose.py` attributes the leak-free synthetic misses the same way:

```
CAUSE SUMMARY: {'scorer_miss': 18, 'dedupe_collapse': 1, 'retrieval_miss': 2}
```

**The scorer is the bottleneck by an order of magnitude.** Both datasets agree,
and each cause is localised to one swappable component — which is what makes
Phase 3 a measurable experiment rather than a guess.

## 16. Component swaps

| Component | Was | Now |
|---|---|---|
| Tokenizer | `words × 1.3` | **tiktoken `cl100k_base`** ✅ |
| Embedder | hashing bag-of-words | **all-MiniLM-L6-v2, 384d** ✅ |

The weights are vendored at `models/all-MiniLM-L6-v2/` (90 868 376 bytes,
verified) because the Hub download failed repeatedly on this connection — Xet
`IncompleteBody`, consistency-check failures, and curl restarting instead of
resuming. `_local_model_ok()` checks the exact byte size, since a truncated file
loads as `InvalidHeaderDeserialization`.

The embedder is pluggable (`MEMGATE_EMBEDDER=auto|hash|minilm`) and the hashing
backend is retained deliberately as the ablation that shows how much of the
result depends on embedding quality.

**`backend_info()` is recorded into every results row.** This is not
bookkeeping: a resumed download produced a corrupt `model.safetensors`, the
`auto` path silently fell back to hashing, and only that provenance field
prevented a table being labelled MiniLM that was actually hashing. Fallback is
now a loud warning.

### 16.1 Supersession — the first clean component ablation

A prediction was made before the swap: with hashing, the genuine supersession
scored only **0.101** cosine against its target, so semantic supersession was
non-functional and MiniLM should fix it. **Confirmed, and sharper than expected.**

| Embedder | → true target | → nearest competitor | Outcome |
|---|---|---|---|
| **MiniLM 384d** | **0.865** | 0.741 | **Correct**, at every threshold 0.50–0.70 |
| Hashing BoW | 0.500 | **0.583** | **Wrong** — ranking inverted |

Under hashing the nearest competitor *outranks* the true target, so the
mechanism either retires the wrong record or stays silent. Under MiniLM it
retires the right one with a 0.124 margin and is insensitive to the threshold.

This is the first result attributing a gain to a single swapped component,
which is exactly the ablation structure the build plan calls for. It is also the
one place so far where the embedder is demonstrably load-bearing — on the
synthetic recall numbers MiniLM and hashing are near-identical (50.0% either
way), consistent with the scorer, not the embedder, being the bottleneck.

### 16.2 A dataset artefact found on the way

The result above was only obtainable after fixing the probe. The planted update
read *"Actually, we pushed **that deadline** to April 2"* — a bare anaphor with
no antecedent, fired ten sessions after its target, competing with four other
deadline facts. No mechanism could resolve it, and semantic supersession duly
retired the wrong record; the apparent "failure" was the dataset, not the policy.

It now names its subject (*"we pushed the bakery module deadline…"*), and
`_assert_wellformed()` refuses to build a set where an update does not reference
the fact it corrects. Third artefact of this class caught by an assertion —
see §7.

### 16.3 Provenance is not bookkeeping

`backend_info()` is recorded into every results row. A resumed download produced
a corrupt `model.safetensors`, the `auto` path silently fell back to hashing,
and only that field prevented a table being labelled MiniLM that was actually
produced by the baseline. Fallback is now a loud stderr warning.

## 17. Where this leaves the project

The story is **stronger**, not weaker — but it must be told accurately.

* The panel's Q3 objection ("has this not been built?") is now answerable with
  evidence: tiered memory is shipped, and **it does not work well** — a
  well-formed three-tier system scores 15% on LoCoMo where full-context scores
  100%.
* The 34-point oracle gap cited from LongMemEval is reproduced in our own
  harness: **Oracle 100% at 65 tokens vs P1 15% at 2055**. The gap is entirely
  memory selection.
* Building the harness first is what surfaced all of this — the lesson from §7,
  now with a much sharper example.

**Do not re-present the Review 1 numbers.** Use §15 and frame the write-path
ceiling as the identified research problem.

### Immediate next steps

1. **Fix consolidation** — re-summarise on eviction instead of discarding, so
   Tier 2 stops being a death chamber. Highest-value change; lifts the 9.4%
   ceiling directly.
2. Finish the MiniLM download; re-run and quantify the embedder's contribution.
3. P2 (LLM-judge) — the heuristic is the demonstrated bottleneck.
4. Consider an **answer-presence** metric: a Tier 2 summary is truncated to 14
   words but still carries its `fact_id`, so it counts as a hit even when the
   answer was cut. LoCoMo ships gold answer strings, so this is checkable and
   the current metric is generous to MemGate.

## 19. The answer-presence metric

Evidence recall asks "did the gold turn's **id** reach the context". That is
generous: a Tier 2 gist is truncated but keeps its id, so it scores a hit even
when the answer text was cut. LoCoMo ships gold answers, so this is checkable.

**It cannot simply replace the headline metric.** Only **41.7%** of
non-adversarial answers appear verbatim in their own evidence turns:

| Category | answer present in evidence |
|---|---|
| single-hop | 61% |
| multi-hop | 34% |
| temporal | 8% |
| open-domain | 4% |

Temporal answers are dates derived from session timestamps and open-domain
answers are commonsense inferences — neither is in the turn text. A global
answer-presence metric would cap even a perfect oracle at 41.7% and would
measure the benchmark's phrasing, not the memory policy.

So it is scored **only over the 715 questions whose answer is recoverable from
evidence text** (`Question.answer_recoverable`). On that subset it is exact, and
validated: **Full-context and Oracle both score 100.0%**, which is the check
that the subsetting is right. Stopwords are dropped, so "the deadline is March
15" is not judged present because "the" and "is" survived.

**It immediately earned its place.** During the consolidation work, strict
recall rose with budget (8.1% → 14.8%) while answer recall stayed pinned at
12.8%. The extra "recall" was pure id bookkeeping from merged gists with no
answer content behind it. Evidence recall alone would have reported that as
progress.

## 20. Fixing consolidation — and two wrong turns on the way

The target: Tier 2 must re-summarise on eviction instead of discarding, so it
stops being a death chamber (§13.2).

**Attempt 1 — merge the sub-threshold remainder into one gist.** Retention went
7.2% → 100% and the write-path ceiling 9.4% → 100%. Both were **fictitious**.
Merging is recursive, so `covered_ids` accumulated while the text was
re-truncated each pass; one item claimed **373 turns in 221 tokens**. Coverage
on paper, nothing in the tokens. Answer recall did not move, correctly refusing
to credit it.

**Fix — per-fragment accounting.** A merged gist now carries `(ids, text)`
fragments and may claim only ids whose text it still physically contains; a
fragment that does not fit is dropped **together with its ids**. Honest numbers:
retention **18.1%**, ceiling **25.5%**. That is the real rate–distortion trade —
fewer tokens for a lossier but truthful representation — rather than free credit.

**Attempt 2 — one merged block.** Ceiling up, but realized recall went *down*
(−1.2 strict at 2048). Diagnosis: a merged item is **atomic at assembly time**;
it fits the Tier 2 share whole or is skipped whole. Collapsing ~27 individually
packable items into one 512-token block lost more in granularity than density
won.

**Fix — chunked merging** (`chunk_tokens = 64`), plus Tier 2 packing ordered by
**conversation-per-token** rather than recency, so a dense gist is no longer
always last in line. Density is computed from `len(fragments)`, a structural
property — deliberately **not** from `covered_ids`, which are evidence ids and
would smuggle the answer key back into the policy.

### Result — FINAL, MiniLM + tiktoken, all fixes in

| Policy | Budget | Strict | Soft | Answer | Avg tokens |
|---|---|---|---|---|---|
| Full-context | unlimited | 100.0% | 100.0% | 100.0% | 18 959 |
| Oracle | 512 | 99.9% | 99.9% | 100.0% | 65 |
| P0 sliding window | 512 | 1.6% | 1.9% | 4.9% | 509 |
| **P1 MemGate** | 512 | **7.7%** | **9.3%** | **12.0%** | 484 |
| P0 sliding window | 1024 | 4.3% | 4.9% | 9.1% | 1022 |
| **P1 MemGate** | 1024 | **9.4%** | **11.6%** | **16.1%** | 897 |
| P0 sliding window | 2048 | 10.1% | 11.4% | 18.3% | 2047 |
| **P1 MemGate** | 2048 | **12.4%** | **15.0%** | **19.2%** | 1430 |
| P0 sliding window | 4096 | **18.8%** | **21.8%** | **31.3%** | 4094 |
| P1 MemGate | 4096 | 16.6% | 20.3% | 21.1% | 2062 |

Gain from the consolidation fix (MiniLM, like-for-like against §15):

| Budget | P1 before | P1 after | Δ |
|---|---|---|---|
| 512 | 7.0% | **7.7%** | +0.7 |
| 1024 | 8.5% | **9.4%** | +0.9 |
| 2048 | 11.0% | **12.4%** | +1.4 |
| 4096 | 15.3% | **16.6%** | +1.3 |

**MemGate now leads P0 on every metric at every budget up to 2048** — including
answer recall (19.2% vs 18.3%), i.e. on content actually present, not just ids —
while spending 1430 tokens to P0's 2047. At 4096 P0 still wins outright.

Per-category strict recall at 2048:

| Policy | multi-hop | temporal | open-domain | single-hop |
|---|---|---|---|---|
| P0 sliding window | **2.2%** | 9.4% | 7.9% | 13.2% |
| P1 MemGate | 1.1% | **15.3%** | **10.1%** | **15.4%** |

Multi-hop improved (0.7% → 1.1%) but still trails P0. It needs *all* ~3.13 cited
turns, so retention failure compounds multiplicatively — it will be the last
category to move and the clearest signal that the write path is genuinely fixed.

**The honest reading:** the ceiling rose 9.4% → 25.5% but only ~1.4 points of it
converted. Head-truncation is too lossy a summariser to exploit the headroom it
creates. **This is precisely the Step 2 dependency** — a real abstractive
summariser retains far more content per token, and the ceiling is now there for
it to claim.

## 21. The compressor — choosing *which* words to keep

§20 left the diagnosis: the ceiling rose to 25.5% but only ~1.4 points
converted, because the gists retained turn **ids** while discarding turn
**content**. The cause was the compression rule itself. It was head-truncation
— keep the first N words — which on natural dialogue is close to the worst
possible choice:

```
"[Caroline] Hey Mel! Good to see you! How have you been?
 I finally signed up for the LGBTQ support group on 7 May 2023."

head-truncation (14 tok):  "[Caroline] Hey Mel! Good to see you! How"
informative    (14 tok):   "[Caroline] Mel! Good 7 May 2023."
```

The head of a turn is greeting and phatic filler; the durable content — dates,
names, numbers, places — sits later. Head-truncation spent the entire budget on
the least informative part of every turn. `7 May 2023` **is** the answer to
"When did Caroline go to the LGBTQ support group?", and truncation threw it away
while faithfully keeping "Hey Mel!".

`memgate/compress.py` scores each word (digits +4, month names +3, mid-sentence
capitalisation +2.5, stopwords −2, with a mild preference for earlier words to
break ties) and keeps the highest-scoring ones **in original order**, always
retaining the `[Speaker]` tag. It is the project's own rate–distortion question
applied at word level: given a token budget, which words preserve the most
downstream utility?

This is **extractive, not abstractive** — it selects, it does not rewrite.
Abstractive re-summarisation by the base LLM remains the Phase 2 target and
needs a generative model that is not available offline (no API key, no local
model). What this establishes is the **extractive baseline that an abstractive
summariser must beat to justify its cost**, which turns Phase 2 into a
measurable experiment rather than an assumption.

### Result — FINAL (MiniLM + tiktoken, all fixes in)

| Policy | Budget | Strict | Soft | Answer | Avg tokens |
|---|---|---|---|---|---|
| Full-context | unlimited | 100.0% | 100.0% | 100.0% | 18 959 |
| Oracle | 512 | 99.9% | 100.0% | 100.0% | 65 |
| P0 sliding window | 512 | 1.6% | 1.9% | 4.9% | 509 |
| **P1 MemGate** | 512 | **8.0%** | **9.8%** | **12.9%** | 484 |
| P0 sliding window | 1024 | 4.3% | 4.9% | 9.1% | 1022 |
| **P1 MemGate** | 1024 | **10.6%** | **12.8%** | **16.9%** | 900 |
| P0 sliding window | 2048 | 10.1% | 11.4% | 18.3% | 2047 |
| **P1 MemGate** | 2048 | **14.4%** | **17.3%** | **20.6%** | 1423 |
| P0 sliding window | 4096 | 18.8% | 21.8% | **31.3%** | 4094 |
| **P1 MemGate** | 4096 | **20.3%** | **24.6%** | 25.0% | 2051 |

**MemGate now beats the sliding window on strict recall at EVERY budget,
including 4096 (20.3% vs 18.8%) on half the tokens.** Every earlier version lost
that budget outright. P0 still wins answer recall at 4096 (31.3% vs 25.0%) —
with 4094 tokens it simply carries more raw text, and that is worth stating
plainly.

Progression of P1 strict recall across this session:

| Budget | leak-free start | + consolidation | + compressor |
|---|---|---|---|
| 512 | 7.0% | 7.7% | **8.0%** |
| 1024 | 8.5% | 9.4% | **10.6%** |
| 2048 | 11.0% | 12.4% | **14.4%** |
| 4096 | 15.3% | 16.6% | **20.3%** |

**+5.0 points at 4096 from the two write-path fixes.** The gain grows with
budget, which is the signature of a write-path fix: retained content only pays
off once there is room to put it in.

Per-category at 2048: temporal **17.2%** vs 9.4%, single-hop **17.9%** vs 13.2%,
open-domain **12.4%** vs 7.9%. Multi-hop remains the one loss, 1.4% vs 2.2% — it
needs *all* ~3.13 cited turns, so it is the last thing to move and the sharpest
remaining test of the write path.

## 22. Ablation study (Step 4) — and the uncomfortable result

`run_ablations.py` turns off exactly one component at a time and reports the
delta against the full system on LoCoMo at a 2048-token budget. Three families:
architecture, the eight scoring signals, and parameter sensitivity.

### 22.1 What each component is worth

MiniLM + tiktoken, budget 2048:

| Removed | Strict | Δ |
|---|---|---|
| *(full system)* | 14.4% | — |
| working memory (Tier 2) | 7.1% | **−7.3** |
| retrieval (Tier 3) | 7.3% | **−7.1** |
| consolidation merge | 12.4% | −2.0 |
| informative compressor | 12.4% | −2.0 |
| density packing | 12.6% | −1.8 |
| supersession | 14.3% | **−0.1** |

| Signal removed | Δ | | Signal removed | Δ |
|---|---|---|---|---|
| durable | **−3.9** | | filler | −0.3 |
| numeric | **−3.5** | | question | −0.1 |
| temporal | −2.4 | | update | −0.1 |
| proper | −2.2 | | speaker | **+0.0** |

`chunk_tokens` (32/64/128) makes no difference at all, and buffer `N` is nearly
flat (N=12 is +0.5). Those knobs are not where the behaviour lives.

Two components earn nothing on this benchmark. **Supersession** costs 0.0 —
LoCoMo has almost no explicit corrections, so the mechanism never fires (it did
earn its place on the synthetic set, §16.1). **The speaker down-weight** costs
0.0 because both LoCoMo speakers are humans, so the `speaker == "assistant"`
branch is dead. Both are honest "this signal is not doing anything here"
results, not bugs.

### 22.2 The finding that matters — the tiering does not earn its place

Parameter sensitivity turned up an effect far larger than any component:

| `tau_fact` | Strict (MiniLM) | Answer (MiniLM) | Strict (hash) | Tokens |
|---|---|---|---|---|
| **0.45** *(default)* | 14.4% | 20.6% | 14.1% | 1423 |
| 0.30 | 29.1% | 40.7% | 22.5% | 1690 |
| 0.20 | 57.7% | 70.6% | 39.2% | 1692 |
| **0.15** | **60.2%** | **71.2%** | 40.5% | 1693 |

**+45.8 points** from one untuned threshold — for reference, P0 at this budget
scores 10.1% and full-context scores 100% at 18 959 tokens.

Nearly **triple the recall at the same token cost**, from one threshold that was
set by intuition in Step 0 and never tuned.

But the reason is not that 0.15 is a better threshold. At `tau_fact = tau_low`
the Tier 2 branch can never fire, and the routing confirms it:

```
tau_fact=0.45 -> {long: 14,  working: 399, merges: 294}
tau_fact=0.15 -> {long: 413, working: 0,   merges: 0}
```

**Every item goes straight to Tier 3. Nothing is compressed, merged, or
dropped.** The 40.5% is plain retrieval over the entire conversation — a RAG
baseline, with the tiering machinery bypassed entirely. Three checks confirm it:

| Config @ 2048 (MiniLM) | Strict | Answer |
|---|---|---|
| MemGate `tau=0.15` | 60.2% | 71.2% |
| **store-everything (`tau=0.0`)** | **59.2%** | 69.8% |
| …without retrieval | **9.0%** | 8.8% |
| …without merging | 59.1% | 70.5% |
| …without compressor | 59.3% | 69.4% |

Retrieval contributes **~51 points**. Merging and compression together
contribute ~1. And "keep everything, retrieve top-k" scores within one point of
the tuned system.

### 22.2a This corrects §15.1 about the embedder

§15.1 concluded the MiniLM swap "buys almost nothing" (+0.2 at 2048). That was
true **and the reasoning was right for the regime it was measured in** —
retrieval was saturated against a 9.4% write-path ceiling, so a better embedder
had nothing left to recover.

Once the ceiling is removed, the same swap is worth **+19.7 points**
(hash 40.5% → MiniLM 60.2%). The embedder was never weak; its contribution was
masked by a write path that discarded 93% of the conversation before retrieval
ever saw it.

The general lesson is worth keeping for the report: **a component's measured
value is conditional on the bottleneck being elsewhere.** Ablations run against
a broken pipeline will systematically undervalue exactly the components that
would matter once it is fixed.

**Stated plainly: on LoCoMo, at a 2048-token context budget, the compression
machinery this project is about is a net loss against simply keeping everything
and retrieving.** All of §20 and §21's hard-won gains (+1.4, +3.6) are gains
*within a regime that should not have been entered*.

### 22.3 Why — and the methodological gap it exposes

The experiment constrains the **context** but never the **store**. Full-context
is charged 18 959 tokens per query; "store everything and retrieve" is charged
nothing for holding all 413 turns. Under that accounting, forgetting can only
ever lose information — there is no budget it saves.

A LoCoMo conversation is ~19K tokens. A 19K-token memory is free. Compression
cannot pay for itself at that scale, and our own ablation proves it.

This does not sink the project; it locates it. Keep/compress/forget only has
value where the store itself is bounded — and that constraint was never
imposed. **The fix is a storage budget**: cap the store at S tokens, sweep S,
and measure accuracy per *stored* token as well as per context token. That is
the axis on which compression must win, and if it does not win there either,
that is a publishable negative result about tiered memory.

**Do not present the tiered architecture as validated.** Present the frontier
honestly: at LoCoMo scale, retrieval dominates; the open question is where the
crossover lies as the store is squeezed.

## 18. How to run (updated)

```bash
cd ~/Documents/Capstone\ Project/memgate
python3 test_memgate.py       # 35 passed, 0 failed (34 under MEMGATE_EMBEDDER=hash)
python3 run_experiment.py     # synthetic
python3 run_locomo.py         # LoCoMo — the real benchmark

MEMGATE_EMBEDDER=hash python3 run_locomo.py    # embedder ablation
```

Data: `data/locomo/locomo10.json` (2.7 MB, from `snap-research/locomo`).

---

# Session 3 — 24 August 2026

## 23. The storage budget — and what it says about compression

§22.3 ended with the project's own ablation showing the compression machinery
to be a **net loss** against simply keeping everything and retrieving, and
located the cause precisely: the experiment constrained the **context** but
never the **store**. Full-context was charged 18 959 tokens per query while
"store everything and retrieve top-k" was charged *nothing* for holding all 419
turns. Under that accounting forgetting can only lose information — there is no
budget it saves — so compression cannot pay for itself and the ablation was
right to say so.

This session imposes the missing constraint and re-asks the question.

### 23.1 What was built

* **`store_budget` (S)** — a cap on total tokens held across all three tiers,
  enforced on every write (`ThreeTierStore.enforce_store_budget`). Cheapest
  loss first: reclaim superseded records → demote the lowest-utility Tier 3
  fact to a Tier 2 gist → drop from Tier 2. Tier 1 is never evicted.
* **`stored_tokens()`** on every policy, recorded in every results row, so
  accuracy per **stored** token is reportable alongside accuracy per context
  token.
* **`RAG store-all`** — §22.2's "keep everything and retrieve" configuration
  promoted from a footnote to a first-class baseline, because it is the thing
  compression has to beat. FIFO eviction under the cap: it has no scorer, which
  is the point.
* **Two new MemGate variants** (defaults untouched, so every §15–§22 number
  still reproduces exactly — verified):
  * **P1-A adaptive** — store verbatim while there is room; **compress on
    eviction**, so the compression rate follows storage pressure instead of
    being fixed at ingest.
  * **P1-S select** — identical, except an evicted item is **dropped rather
    than compressed**.
* **`run_storage_sweep.py`**, and `--store-budget` / `--adaptive` on
  `run_ablations.py` so the whole §22 battery re-runs under the corrected
  accounting.

The three retention regimes isolate one variable each at a fixed store size S:

| comparison | held constant | varies |
|---|---|---|
| P0 vs RAG | retention (same turns, same size) | **read path** — recency vs retrieval |
| RAG vs P1-S | storage, fidelity, retrieval | **which turns are forgotten** |
| P1-S vs P1-A | storage, selection | **fidelity** — drop vs compress |

### 23.2 Two under-fill bugs, both the §13.5 strawman pointed the other way

The first sweep showed MemGate **flatlining at 2148 stored tokens on a
16 384-token allowance** — it lost at every large S while refusing to use 87% of
the storage it was given. Same class of defect as §13.5, where MemGate could
not fill the *context* it was allowed; here it could not fill the *store*.

1. **Tier 2 was sized from the context budget**, not the store
   (`budget × split × 2` = 1024), so no storage allowance could make it grow.
2. **Tier 2 is not query-addressable.** Routing sends 399 of 413 items there,
   but Tier 2 is read *positionally* — packed by density — never ranked against
   the question. Only Tier 3 is retrievable, and it held 14 items.

(2) is the more interesting one, and it produced the session's sharpest
diagnostic: enlarging Tier 2 alone made recall **worse** (24.2% → 12.1% at
S=16 384). More stored, none of it reachable. **Stored content that is not
addressable earns nothing**, and a storage budget spent on it is worse than
wasted. Tier 2 items already carried embeddings, so making them retrievable
cost only the ranking.

A third, deeper limit remained: threshold mode compresses every turn to a
~14-word gist *on the way in*, so it cannot hold more than ~4735 tokens of a
19K conversation however large the budget. The compression rate was fixed in
advance rather than adapted to pressure — which is what P1-A exists to fix.

### 23.3 Result — LoCoMo, context budget fixed at 2048, store budget swept

MiniLM + tiktoken, 10 conversations, 1527 questions. `stored` is what the
policy still holds after ingest; `ctx` is what it spends per query.

| S | Policy | Strict | **Answer** | Stored | Ctx |
|---|---|---|---|---|---|
| 1024 | RAG store-all | 4.3% | 9.1% | 1005 | 987 |
| 1024 | P1-A adaptive | **9.1%** | 10.9% | 1002 | 984 |
| 1024 | **P1-S select** | 5.6% | **15.7%** | 1006 | 963 |
| 2048 | RAG store-all | 10.1% | 18.3% | 2031 | 1983 |
| 2048 | P1-A adaptive | **19.6%** | 23.4% | 2022 | 1758 |
| 2048 | **P1-S select** | 10.9% | **26.3%** | 2025 | 1932 |
| 4096 | RAG store-all | 17.8% | 28.1% | 4068 | 2018 |
| 4096 | P1-A adaptive | **30.5%** | 30.1% | 4042 | 1470 |
| 4096 | **P1-S select** | 19.8% | **36.8%** | 4077 | 2006 |

Delta against RAG store-all **at the same storage budget**:

| S | P1 threshold | P1-A adaptive | **P1-S select** |
| | strict / answer | strict / answer | strict / answer |
|---|---|---|---|
| 512 | +1.0 / +1.0 | +2.8 / +0.6 | +0.2 / **+2.5** |
| 1024 | +1.8 / +2.4 | +4.8 / +1.8 | +1.2 / **+6.6** |
| 2048 | +2.2 / −0.3 | +9.5 / +5.0 | +0.8 / **+8.0** |
| 4096 | −3.7 / −7.8 | +12.7 / +2.0 | +2.0 / **+8.7** |
| 8192 | −16.2 / −23.8 | +12.9 / **−6.9** | +0.7 / **+3.9** |
| 16384 | −38.9 / −45.9 | +5.0 / +0.0 | +5.4 / **+5.9** |
| unlim | −47.4 / −54.3 | +0.5 / +0.4 | +0.5 / +0.4 |

**§22.2's verdict is reversed, but not in the way the project expected.**

### 23.4 The finding: selection wins, compression loses

Read the two metrics against each other, as §19 requires. **P1-A wins strict
recall and loses answer recall** — at S=8192, +12.9 strict but **−6.9 answer**.
A demoted gist keeps the evidence ids of the turn it came from while the answer
text has been compressed away, so evidence recall credits it and
answer-presence refuses to. This is exactly the failure mode the answer metric
was built for in §19, and it fires here on the project's own headline variant.

Turning demotion **off** makes it unambiguous. Same storage, same selection,
the only change being drop-instead-of-compress:

| S | RAG answer | P1-A (compress) | **P1-S (drop)** |
|---|---|---|---|
| 1024 | 9.1% | 10.9% | **15.7%** |
| 2048 | 18.3% | 23.4% | **26.3%** |
| 4096 | 28.1% | 30.1% | **36.8%** |
| 8192 | 44.3% | 37.5% | **48.3%** |
| 16384 | 66.4% | 66.4% | **72.3%** |

**Compression is a net negative on the honest metric at every storage budget
tested.** What earns the gain is (a) imposing the cap at all, and (b) *scored*
eviction — choosing which turns to keep whole.

That second point is the cleanest result the project has produced. **RAG and
P1-S hold the same verbatim turns, in the same space, retrieved the same way,
and differ in one respect only: which turns are forgotten when the cap binds.**
RAG forgets oldest-first; P1-S forgets lowest-utility-first. The gap between
them — **+8.7 answer points at S=4096** — is the decision policy and nothing
else. That is precisely the quantity §4 set out to measure.

**The rate–distortion reading:** at LoCoMo dialogue scale the optimum sits at
the **vertex** — a *subset at full fidelity* beats *everything at reduced
fidelity*. Compression should only begin to pay once the store is squeezed far
enough that even the selected subset will not fit verbatim. The sweep bottoms
out at S=512 before reaching that regime (all policies are near the floor
there), so **where that second crossover lies is now the open question**, and
it needs either a tighter S or a longer conversation than LoCoMo provides.

### 23.5 Ablation under the corrected accounting

`run_ablations.py --budget 2048 --store-budget 4096 --adaptive`:

| Removed | Strict | Δ | Answer |
|---|---|---|---|
| *(full system)* | 30.5% | — | 30.1% |
| retrieval (Tier 3) | 0.2% | **−30.3** | 2.4% |
| demotion on pressure | 19.8% | −10.7 | **36.8** ↑ |
| scored eviction (→ FIFO) | 25.5% | **−5.0** | 23.4% |
| informative compressor | 26.7% | −3.8 | 27.8% |
| consolidation merge | 28.0% | −2.6 | 25.0% |
| supersession | 30.3% | −0.2 | 29.9% |
| density packing | 30.5% | +0.0 | 30.1% |
| working memory (Tier 2) | 30.5% | +0.0 | 30.1% |

Three things to state plainly:

* **Retrieval still dominates everything** (−30.3), as in §22.2. That has been
  true in every regime measured.
* **Scored eviction earns −5.0 strict and −6.7 answer** against FIFO. The
  decision engine is doing real work — but only where the budget binds. At
  S=8192 FIFO actually *beat* it by 3.4 strict, i.e. under light pressure
  recency is the better forgetting rule.
* **Density packing and Tier 2 read +0.0 because adaptive mode bypasses that
  path entirely** — the positional Tier 2 share is replaced by one ranked pool.
  They are no-ops here, not free components. Their §22.1 numbers still stand
  for threshold mode.

### 23.6 Guards added

`test_memgate.py` is at **57 passed, 0 failed**. New:

* no policy ever exceeds its storage budget (P0 / RAG / P1 / P1-A, four values
  of S each);
* **the label-invariance test now covers eviction and demotion** in both write
  modes. The storage budget introduced two new decision points — *which item to
  evict* and *which to demote* — and either could have read the answer key the
  way consolidation did in §13. Eviction ranks on `utility` and recency only;
  `_forget_key` is documented as label-blind and pinned by the test.
* a tight budget must force real loss, and adaptive mode must demote **nothing**
  when storage is free and something when it is not — otherwise the sweep would
  be measuring a constraint that never binds.

`count_tokens` is now memoised (pure function of its input); the cap re-counts
held items on every write, which is otherwise O(n²) per conversation.

### 23.7 Where this leaves the project

The Review-2 story is now a real experimental narrative rather than a claim:

1. Tiered memory with forgetting is already shipped by Letta/Mem0/Zep (§3, Q3).
2. Measured honestly, a well-formed three-tier system scores **14.4%** on
   LoCoMo where full-context scores 100% (§21).
3. Its own ablation then showed the compression machinery to be a **net loss**
   against keeping everything (§22.2) — and correctly diagnosed why: storage
   was never budgeted (§22.3).
4. With the store budgeted, **the decision policy is worth +8.7 answer points
   over forgetting oldest-first, at identical storage and identical fidelity**
   — but **compression itself still loses**. Keep a scored subset whole; do not
   compress everything.

That is a sharper and more defensible contribution than "we built a memory
layer", and (4) is a genuine negative result about tiered compression at this
scale, arrived at through the project's own metrics.

**Do not present tiered compression as validated.** Present the storage-budget
frontier: selection pays, compression does not (yet), and the crossover where
it should is the next thing to find.

### 23.8 Immediate next steps

1. **Push S below 512 and/or use a longer benchmark** to find the second
   crossover — the point where the selected subset no longer fits verbatim and
   compression must start paying. LongMemEval is the natural candidate; its
   conversations are far longer than LoCoMo's ~19K tokens.
2. **P2 (LLM-judge)** is now the highest-value scorer work, and its value is
   quantified in advance: scored eviction is worth −5.0 against FIFO, so a
   better scorer attacks a component that is *already demonstrably load-bearing*
   — unlike §15.1's embedder, which was masked by a broken write path.
3. **Charge for the embeddings.** `stored_tokens` counts text only; a 384-d
   float32 vector per item is real storage that RAG and P1-S pay on every
   retained turn and a compressed gist pays once. Under a byte-denominated
   budget the comparison may shift.
4. Report **accuracy per stored token** as a headline axis alongside accuracy
   per context token — the sweep already emits it (`strict_per_kstored`).

### 23.9 How to run (updated)

```bash
cd ~/Documents/Capstone\ Project/memgate
python3 test_memgate.py            # 57 passed, 0 failed
python3 run_locomo.py              # §21 table, unchanged
python3 run_storage_sweep.py       # §23 — the storage-budget frontier
python3 run_ablations.py --budget 2048 --store-budget 4096 --adaptive
```

Results: `results/storage_sweep.csv` (adds `stored_tokens`, `max_stored`,
`strict_per_kstored`).

---

# Session 4 — 27 August 2026

The project is **results-complete**. Every item §23.8 left open is closed, the
two components blocked on tooling are unblocked, and every headline number now
carries a confidence interval. `REPORT.md` is the paper-ready writeup.

## 24. Closing the open items

### 24.1 The rate–distortion prediction is falsified (`run_scaling.py`)

§23 predicted a second crossover: squeeze the store hard enough and a lossy
record must beat no record, so compression must eventually overtake selection.

Sweeping S *downward* cannot test that. By S=256 every policy sits at ~0.2%
strict / ~2.4% answer — the regime where compression should win is **below the
floor where anything works at all**, and the apparent crossing there is one or
two questions, i.e. noise.

**The missing axis was conversation length, not store size.** Concatenating k
LoCoMo conversations into one stream (to 186K tokens, 5882 turns) at fixed S
runs the compression ratio from 9× to 182×.

Answer recall at S=2048:

| Ratio | RAG | P1-A compress | **P1-S drop** |
|---|---|---|---|
| 9× | 18.3% | 23.4% | **26.3%** |
| 18× | 10.8% | 14.7% | **18.2%** |
| 45× | 7.8% | 11.2% | **11.7%** |
| 91× | 4.6% | 6.0% | **8.7%** |

**No crossover anywhere**, and the selection margin over RAG *widens* with
pressure (8.0 pts at 9×, 4.1 at 91× against RAG; drop beats compress at every
ratio). The prediction is falsified over the entire reachable range.

Caveat to state: concatenated streams are **not** natural long conversations —
each question concerns one constituent conversation, so the rest are
distractors. It is a stress test of retention under pressure, which is the
variable under study, not a long-dialogue benchmark. Turn ids were already
namespaced (§14), so evidence cannot alias across conversations.

### 24.2 The learned scorer (`train_scorer.py`)

P2 was blocked on a generative model, so P3 was filled from the other available
supervision: LoCoMo's own evidence sets, under **leave-one-conversation-out** —
the model scoring conv-26 was fitted on the other nine and has never seen a
conv-26 turn or label. At inference it sees text and speaker only, and the
label-invariance test covers it.

| Scorer | AUC | Strict | Answer |
|---|---|---|---|
| P1 heuristic | — | 10.9% | 26.3% |
| P3 learned, hand features | 0.746 | 13.1% | 27.7% |
| **P3 learned + MiniLM** | **0.793** | **17.0%** | **31.5%** |

**+6.2 strict / +5.2 answer.** The fitted weights are reported, and say
something the heuristic never encoded: **turn length is the strongest single
predictor of evidence-worthiness**, ahead of every hand-designed cue.

Not deployable — a live agent has no future questions. It **bounds the
headroom** of a learned decision policy: Oracle above, P1 below.

### 24.3 Byte-denominated storage (`run_cost_model.py`)

Token accounting charges for text and gives the **embedding index away free**.
A 384-d float32 vector is 1536 B against a turn's ~130 B of text — the index
outweighs the content ~12×, so the binding cost becomes the **number of items**,
not their length.

Two results:

1. **§23 is unit-robust.** Selection still beats compression, by +7.8 to +34.0
   answer points. Merging (which folds many turns into one vector) does not
   rescue compression either — it loses more content than the vector it saves.
2. **Below ~40 KiB an embedding index cannot earn its own storage.** P0 keeps no
   vectors and wins outright at 32 KiB (18.3% vs select's 15.1%), and is
   overtaken by 64 KiB. That regime is **invisible** when the budget counts text
   alone — as every accuracy-per-token number in this literature does, ours in
   §23 included.

### 24.4 Significance (`run_significance.py`)

Paired bootstrap (B=10,000) clustered by conversation, plus exact McNemar.
1527 questions from 10 conversations are **not** 1527 independent trials.

| Comparison | Metric | Δ | CI (clustered) | p |
|---|---|---|---|---|
| P1-S vs RAG | **answer** | **+8.67** | **[+4.77, +14.27]** | 1.1e-4 |
| P1-S vs RAG | strict | +1.96 | [−1.48, +5.52] | 0.16 **n.s.** |
| P1-S vs P1-A | answer | +6.71 | [+4.24, +9.54] | 3.6e-5 |
| P1-S vs P1-A | strict | −10.74 | [−13.65, −7.90] | 4.7e-20 |
| P1-S vs P0 | answer | +18.46 | [+14.68, +23.56] | 3.8e-17 |

**This corrects §23.** The strict-recall edge over RAG does **not** survive
clustering. Quote the answer-recall result only. `harness.run_policy` now
returns per-question `detail`, which is what makes paired testing possible.

### 24.5 Figures (`make_figures.py`)

Four publication figures, PNG + PDF at 300 dpi. The categorical palette was
**validated with a checker**, not chosen by eye (lightness band, chroma floor,
CVD separation, normal-vision floor); every series also carries a distinct
marker shape, so identity survives colour-blind readers and grayscale printing.

## 25. P2 — the local LLM judge (`memgate/judge.py`)

The blocker was tooling, not design: no API key and no local generative model.
Resolved by vendoring **Qwen2.5-0.5B-Instruct** (942 MB, verified byte size) and
running it on the machine's own GPU (Apple MPS). Offline, free, reproducible.

**No generation.** Asking for a digit and parsing it wastes an autoregressive
loop and fails on "I'd say 7". Instead: one forward pass, read the logits at the
final position restricted to the ten digit tokens, take the expectation
`sum(i·p_i)/9`. Faster, cannot fail to parse, and — the real reason —
**continuous**, so eviction ranking has no ties.

**Three engineering findings worth keeping:**

1. **NaN for exactly the short turns.** Batched scoring returned NaN for the
   fillers. The instinct is precision; float32 did **not** fix it. The cause is
   the **mask**: left padding puts pads first, a short sequence gets leading
   rows that are entirely masked, the attention softmax sees an all-`-inf` row,
   and Qwen2 on MPS returns NaN. Right padding + gathering at
   `attention_mask.sum(1)-1` fixes it. **The NaN guard is what surfaced this** —
   without it every filler would have scored NaN and silently inverted the
   eviction order.
2. **Right padding blew up memory** (4.78 GB): transformers then projects *every*
   position to the 151936-token vocabulary. Fix: run the base transformer and
   apply `lm_head` only to the gathered final hidden state.
3. With the mask fixed, **bfloat16 is safe and 6.8× faster** than float32
   (2.78 vs 0.41 turns/s) for the same score range.

Scores are cached to disk by text hash with periodic checkpointing, so the
~15-minute pass is paid once.

## 26. Where the project stands

**Results-complete.** The narrative, end to end:

1. Tiered memory with forgetting is already shipped (Letta/Mem0/Zep).
2. Measured honestly, a well-formed three-tier system scores 14.4% on LoCoMo
   where full context scores 100% (§21).
3. Its own ablation showed the compression machinery to be a **net loss**
   against keeping everything — and correctly diagnosed why: storage was never
   budgeted (§22.3).
4. With storage budgeted, **the decision policy is worth +8.7 answer points**
   over forgetting oldest-first at identical storage, fidelity and retrieval
   (CI [+4.77, +14.27]) — while **compression still loses 6.7** (§23, §24.4).
5. The crossover where compression should start paying is **not reachable**:
   falsified to 182× (§24.1).
6. Charging for the index inverts the ranking below ~40 KiB (§24.3).

**Practical guidance: keep a scored subset whole; do not compress everything.
And denominate the budget in bytes, including the index.**

### Still open

* **End-task accuracy** — we measure whether evidence reached the context, which
  is the *ceiling* on accuracy, not accuracy. The local model now makes this
  reachable; it is the single most valuable remaining experiment.
* **Abstractive compression** — the negative result is stated for *extractive*
  compression. A rewriting summariser might retain more per token.
* **A genuinely long benchmark** (LongMemEval) rather than concatenated streams.
* **Online learning** of the eviction policy, which would make a learned scorer
  deployable.

## 27. How to run (updated)

```bash
cd ~/Documents/Capstone\ Project/memgate
python3 test_memgate.py          # 59 passed
python3 run_locomo.py            # §21 context-budget frontier
python3 run_storage_sweep.py     # §23 storage budget
python3 run_scaling.py           # §24.1 compression ratio to 182x
python3 train_scorer.py          # §24.2 learned scorer
python3 run_cost_model.py        # §24.3 byte accounting
python3 run_significance.py      # §24.4 bootstrap + McNemar
python3 precompute_judge.py      # §25 P2 judge scores (~15 min, cached)
python3 make_figures.py          # §24.5 figures
```

`REPORT.md` (project root) is the paper-ready writeup.

## 28. The P2 judge, actually measured — and it loses

§25 built the judge; it had never been *evaluated against the alternative*.
`run_judge_eval.py` does that, as a **single-component swap**: policy, storage
budget, retrieval and compression pinned at the §23 winner (P1-S select,
context 2048, store 4096), and only the scorer varying. Anything that moves is
the scorer.

| Scorer | Evidence | Answer | Δ vs P1 | 95% CI (clustered) |
|---|---|---|---|---|
| P0 recency (no content judgement) | 12.6% | 25.6% | −11.19 | [−17.24, −6.19] |
| **P1 heuristic** (regex + shallow NER) | 19.8% | **36.8%** | — | — |
| P2 LLM judge (Qwen2.5-0.5B) | 14.0% | 30.9% | **−5.87** | [−10.77, −1.76] |
| P3 learned (LOCO, bound) | 33.4% | 48.3% | +11.47 | [+4.90, +17.86] |

**The LLM judge loses to the regex by 5.87 answer points, and the interval
excludes zero.** A real negative, not a wash — for ~15 minutes of GPU per corpus
against microseconds. Three things follow, and all three survive clustering:

1. **Scoring at all is load-bearing**: +11.19 over unscored recency. Without
   this row the rest of the table would not be worth reading — it establishes
   that the decision point is where the value is.
2. **P2 fails at it anyway.** The diagnosis is what the judge is *shown*: it
   rates each turn **in isolation**, and salience is not a property of a turn on
   its own. A phone number matters because something later asks for it.
3. **The headroom is real** (+11.47 to the learned bound), so P2 was not
   defeated by a missing ceiling. P3 sees the same isolated text and does
   better because it was fitted to which turns *turned out* to be cited —
   corpus-level base rates the judge has no way to see.

The CIs were added to `run_judge_eval.py` before any of this was quoted, per
§24.4: aggregates cannot support a paired comparison, and 1527 questions from
10 conversations are not 1527 independent trials.

### 28.1 Two numbers that look inconsistent and are not

`train_scorer.py` reports P3 at **31.5%** answer recall; the table above says
**48.3%**. Different storage budgets — train_scorer defaults to S=2048, the
judge eval runs at S=4096 — and P1 moves with it identically (26.3% → 36.8%).
The headroom over P1 grows with the budget: **+5.2 at S=2048, +11.5 at S=4096**.
Nothing is wrong; the pair must simply always be quoted with its S.

### 28.2 A stalled download turned a 90-second test suite into a 14-minute hang

`test_memgate.py` was left running and sat for 14 minutes at 0% CPU against an
ESTABLISHED socket to huggingface.co. Every model this project uses is a
verified local copy, but the loaders are Hub-aware even when handed a local
path, so they reach out anyway.

The hang is the symptom. The problem is that **a run which can silently fetch a
model is a run whose inputs are not pinned** — §16.3 already lost a results
table to a half-downloaded MiniLM. Importing `memgate` now sets
`HF_HUB_OFFLINE=1` when `models/` exists, with `MEMGATE_ALLOW_HUB=1` as the
deliberate escape hatch for adding a model.

Two tests pin it (**61 passed**, up from 59). The second matters more than the
first: if offline mode had made MiniLM unloadable, `_get_model()` would have
fallen back to hashing bag-of-words and quietly relabelled every subsequent
result — the exact failure §16.3 describes, re-armed by the fix for it.

---

# Session 5 — 17 September 2026

## 29. The end-task run, completed — the gap survives a real reader

The critical path named in §26 and in every deliverable since is closed. The
full **715-question** end-task run is made, and the project's central claim now
rests on what a model *answered*, not on what reached its prompt.

### 29.1 The weights were gone, and the test suite said so

All three vendored models had been stripped from `memgate/models/` — only the
config and tokenizer files remained. The symptom was honest and immediate:

```
FAIL  MiniLM still resolves with the Hub pinned off
      fell back to hash-bow/256d -- results would be mislabelled
```

This is precisely the guard §28.2 added, catching precisely the failure it was
written for. Without it, every number produced in this session would have been
silently relabelled from the hashing baseline. Re-fetched all three (MiniLM
90,868,376 B; Qwen2.5-0.5B 988,097,824 B; Qwen2.5-1.5B-4bit 868,628,559 B),
each verified against its safetensors header rather than its filename, and the
suite returned to **61 passed, 0 failed**.

### 29.2 The two-phase runner, and the proof it changed nothing

Holding PyTorch + MiniLM (assembly) and MLX (generation) resident together
exceeds 8 GB, so `run_endtask.py` grew `--dump-contexts` / `--from-contexts`:
each phase runs in its own process and releases its memory before the next.

The refactor's correctness was not asserted, it was *observed*. Contexts were
assembled by the new two-phase code; the generation cache is keyed by a hash of
the exact prompt text and had been filled by the old single-phase code. Four
arms came back **100% cached** (2,860 entries). Had the refactor altered one
byte of any context, every one of those would have missed.

Cache state at the start: **3,831 of 4,290 (89.3%)** — an earlier interrupted
run had got most of the way. 451 generations remained, 13.5 min at 0.25–0.51
gen/s.

### 29.3 The result

| Arm | Accuracy | F1 | Answer present | Acc. given present |
|---|---|---|---|---|
| closed-book *(floor)* | 1.7% | 5.0 | 0.0% | — |
| P0 sliding-window | 8.3% | 11.9 | 18.3% | 40.5% |
| RAG store-all | 12.4% | 17.7 | 28.1% | 42.3% |
| P1-A adaptive | 13.1% | 19.9 | 30.1% | 42.3% |
| **P1-S select** | **18.5%** | 24.7 | 36.8% | 49.4% |
| Oracle *(ceiling)* | 67.3% | 75.7 | 100.0% | 67.3% |

```
ceiling gap  (answer recall) : +8.7 pts
realised gap (accuracy)      : +6.0 pts   95% CI [+3.3, +9.1]   significant
conversion                   : 69% of the ceiling gap
closed-book floor            : 1.7%
```

Three things worth keeping:

1. **The closed-book floor is 1.7%.** Parametric knowledge contributes almost
   nothing on LoCoMo, so the margin above that floor is the memory layer and
   essentially nothing else. Had this been high, every arm would have looked
   good for reasons having nothing to do with memory.
2. **The advantage arrives through both routes.** P1-S places the answer in
   context more often (36.8% vs 28.1%) *and* its contexts are used more
   successfully when it does (49.4% vs 42.3%). Only the first was predicted.
3. **The oracle converts only 67.3%.** A perfect memory layer still loses a
   third of its questions to this reader, which locates the remaining headroom
   in the reader rather than in selection — and bounds what any policy could
   deliver here.

Accuracy given the answer was *absent* is below 1% for every arm: the reader is
not guessing its way to credit, so the accuracy column is reading the memory
layer and not the benchmark's phrasing.

### 29.4 Propagated

`endtask.csv` (n=715) → `paper/make_tables.py` (the n<715 guard released and
`tables/endtask.tex` written for the first time) → `make_figures.py` (fig5) →
`frontend/build_data.py` + the dashboard's stale "pilot, not a result" callout →
`docs/make_review2_deck.py` slide 17 → `REPORT.md` §3.8 → `memgate/README.md`.

In `paper/main.tex`: a new Section~\ref{sec:endtask} with the table and fig5, a
seventh contribution, the abstract, the conclusion, and the limitation that read
"we therefore report no end-task accuracy figures here" replaced by the one that
now bounds the claim — *a single reader model*.

### 29.5 Next

The measurement track is complete and the critical path is closed. What remains
is scoped rather than blocking: abstractive compression, LongMemEval, online
learning. **These are for the final review, not Review 2** — a rushed half-run
of any of them would be worth less than the clean "scoped, with estimates" slide
that already exists.

---

# Session 6 — 25/26 September 2026

## 30. LongMemEval, and the scorer that does not transfer

The three tracks §29.5 scoped for the final review were built on 21 September
(abstractive, online, LongMemEval). This session ran LongMemEval, and the result
is the most consequential of the project: **the §23 headline does not replicate,
and the reason is the scorer rather than the mechanism.**

### 30.1 The run

94 items (6 dropped without evidence), 46,733 turns at 497 per item, 62
answer-recoverable. MiniLM resolved properly — the §28.2 guard passed, so these
are not hashing-baseline numbers mislabelled.

Then a store-budget sweep, because LoCoMo and LongMemEval sit at very different
compression pressures:

```
              turns  tok/turn  tok total   store/total @ S=4096
LoCoMo          588      31.6     18,587        22.0%
LongMemEval     497     209.6    104,191         3.9%
```

Turn *counts* are nearly identical; turn *lengths* differ 6.6x. S was swept to
put LongMemEval at LoCoMo's retention (S=23,000 = 22.1%).

```
store   retention   P1-S select   RAG store-all     P1-S vs RAG (answer)
 4096       3.9%         14.5%            9.7%      +4.84  [ -3.23, +12.90] n.s.
 8192       7.9%         22.6%           14.5%      +8.06  [ -1.61, +17.74] n.s.
16384      15.7%         21.0%           27.4%      -6.45  [-17.74,  +4.84] n.s.
23000      22.1%         19.4%           40.3%     -20.97  [-33.87,  -8.06] SIG
```

LoCoMo's same contrast is **+8.67**. At matched retention LongMemEval gives
**-20.97**. RAG scales as a cache must (9.7 → 40.3); P1-S peaks at 8,192 and
then flattens or declines.

S=32,768 was not reached — the OS killed the sweep for memory. The four budgets
above are saved as `results/longmemeval_S{4096,8192,16384,23000}.csv`.

### 30.2 Three wrong explanations, discarded in order

Recorded because each was plausible and each was killed by a measurement, which
is the only reason the fourth is trustworthy.

**(a) "Multi-evidence questions cannot fit the context."** Wrong.
100% of LongMemEval questions have gold evidence fitting in 2048 tokens —
median 80 tokens, max 589, mean 1.8 evidence turns against LoCoMo's 1.5. The
structural ceiling on strict recall is 100%, not 2.1%.

**(b) "The read path is broken on long histories."** Wrong. Decomposing strict
recall into *survival in the store* and *retrieval given survival*: retrieval is
**100%** for both MemGate arms. Every gold turn that survives reaches the
context. (A RAG row in the first decomposition read 0.0% — instrumentation, not
measurement: `RAGPolicy` has no `.store`, it has `.items`.)

**(c) "Selection genuinely fails under pressure."** Not as stated. The failure
is localised to eviction: at S=23,000 P1-S retains gold evidence 25% of the time
where plain FIFO retains 50%. Scored eviction is *discarding evidence that FIFO
keeps*.

### 30.3 What it actually is

Scoring evidence and non-evidence turns directly with `HeuristicScorer`, no
policies or stores involved:

```
                    evidence    non-evidence    separation
LoCoMo                0.2484          0.2008       +0.0476
LongMemEval           0.3727          0.4074       -0.0346
```

**The heuristic's discrimination reverses sign.** On LoCoMo it ranks evidence
above average; on LongMemEval below, so `_forget_key` — `(utility,
turn_index)`, lowest evicted first — evicts evidence preferentially. That is
why scored eviction loses to no ranking at all.

This is a **generalisation failure of the scorer, not a bug**. The heuristic was
written against LoCoMo's short factual dialogue lines (31.6 tok/turn, dense in
regex-catchable cues); LongMemEval turns are 209.6-token conversational prose.
Consistent with §24.2, where the fitted scorer's strongest single feature is
turn length — a corpus-level regularity, not a semantic one.

Caveat on the percentile figures computed alongside these (50.3% / 45.5%): they
are deflated by ties, since strict inequality was counted on a discrete utility
distribution. The mean separation and its sign are the trustworthy part.

### 30.4 A confound found on the way, worth fixing

`MemGatePolicy.build_context` reserves a fixed 25% of the context for Tier 1
recency (`split=(0.25, 0.25, 0.50)`) before retrieval gets a say; `RAGPolicy`
spends the whole budget on retrieved items. So "P1-S vs RAG isolates which turns
are forgotten" — as `run_longmemeval.py` and §23 both claim — is not strictly
true: they also differ in guaranteed recency share.

This is not new code and LoCoMo results stand with it, but its cost is far
higher on LongMemEval: 512 tokens buys 2–3 turns there against ~16 on LoCoMo,
and the target session is drawn from 38–62, so recent turns are almost never
relevant. **The contrast should be re-run with `split[0]=0` before any
LongMemEval number is published.**

### 30.5 Statistical weight — read this before quoting anything above

| evidence | n |
|---|---|
| the four-budget sweep | 94 items, **62** answer-recoverable |
| survival decomposition | 8–20 items (so 25% = 2 of 8) |
| the scorer separation | 62 evidence turns vs 29,989 non-evidence |

The sweep is quotable with its intervals. **The decomposition numbers are not** —
they are diagnostics that located a cause, not measurements of an effect.

### 30.6 Strict recall is uninterpretable on LongMemEval

P1-A adaptive reaches 54.3% strict against P1-S's 3.2%, but the survival check
counted `fact_id` *and* `covered_ids`, and a gist carries those forward while
discarding the text behind them. This is exactly what §19 built the
answer-presence metric for. **Never quote LongMemEval strict recall for a
compressing arm.** Answer recall is unaffected — it checks text — so the
answer-column comparisons above stand.

## 31. The paper: compiled for the first time, and cut to 6 pages

### 31.1 Tectonic works; the README was wrong about why it didn't

`paper/README.md` claimed the install was impossible because Homebrew could not
reach `ghcr.io`. **False.** `ghcr.io` answers normally (401 to an
unauthenticated `/v2/`, which is healthy). The link was simply slow — 6–40 KB/s
— so the portable-Ruby fetch looked like a hang. `brew install tectonic`
completed in ~50 minutes. Tectonic 0.17.0 is now installed and runs BibTeX and
the rerun passes itself.

**If it looks stuck, measure the `.incomplete` file in
`~/Library/Caches/Homebrew/` before concluding anything.**

### 31.2 check.py passed a paper with three visible layout defects

The first actual compile found what a brace-counter cannot:

```
tab:scorers   54.7pt overfull  (~1.9cm into the gutter)
tab:endtask   35.8pt overfull
tab:policies  12.0pt overfull
```

Fixed by `\resizebox{\columnwidth}` on the two generated tables and tighter
`\tabcolsep` on the hand-written one. `check.py` remains useful and remains
**not a substitute for compiling**.

### 31.3 8 pages → 6, and what the old cut list got wrong

The prioritized cut list previously in `paper/README.md`, **applied in full,
removed zero pages.** Text reflowed into every gap it opened.

What moved the counter was vertical structure, not word count: removing the
full-width `figure*` took 8→7, and converting the seven-item contributions
`enumerate` into a paragraph took 7→6 — worth *seven words*, but a large amount
of list leading.

The useful diagnostic: compile with `\bibliography` stripped. Body alone was 6
pages against 7 for the full document, which located the overflow in the
19-entry bibliography and turned "cut two pages" into "free one column".

Removed: four of five figures (`fig:cost` and `fig:scorer` had **no prose
reference at all**; `fig:scaling` and `fig:frontier` duplicated tables that the
cut list protects), `tab:policies`, the roadmap paragraph, and prose compression
across Related Work, Metrics, Setup, Scorer analysis, Threats, Limitations,
Conclusion and the crossover subsection. Only `fig:endtask` survives.

Kept, as §29 required: `sec:accounting`, `tab:storage`, `tab:significance`,
`sec:endtask`, `tab:endtask`, `fig:endtask`. Every result, number and interval
is intact.

Final: **6 pages, 4,170 words, 7 tables, 1 figure, 19/19 citations resolved, 0
undefined references**, one 0.65pt overfull box (0.23mm). `main.pdf` committed.

### 31.4 What §30 changed in the paper

One limitation added, and it bounds the central claim:

> *The scorer is tuned to this corpus.* On a 94-item LongMemEval subsample,
> whose turns average 210 tokens against LoCoMo's 32, the heuristic's separation
> between evidence and non-evidence turns reversed in sign and scored eviction
> lost to FIFO. Read the $+8.67$ of Section~\ref{sec:selection} as what a policy
> recovers *given a scorer suited to the corpus*, not as a property of scored
> selection in general.

Future work in the conclusion retargeted: **a scorer that transfers across
corpora** is now the most urgent of the three, displacing the LongMemEval item
that this session closed.

No §30 table or figure entered the paper. n=62 on the answer metric, S=32,768
missing, and the §30.4 confound unfixed — the standing rule that a pilot-scale
run does not enter the paper applies to our own most interesting result.

## 32. State

* test suite **68 passed, 0 failed**
* paper compiles locally, 6 pages, `main.pdf` committed
* `memgate/data/longmemeval/` gitignored — `longmemeval_s_cleaned.json` is
  265 MB, over GitHub's per-file limit on its own
* abstractive still a **1-conversation** pilot (n=149, degenerate CIs — one
  cluster, so `ci_lo == ci_hi == delta`; its `significant` column is an
  artefact). Online still **2 conversations** (n=230).

### Next, in order

1. **Re-run the LongMemEval contrast with `split[0]=0`** (§30.4). Until that is
   done, "selection loses at matched retention" is confounded.
2. **Finish the sweep at S=32,768.** Run it alone; the OS killed it at 0.06 GB
   free with the session's other work resident.
3. **A scorer that transfers.** §30.3 makes this the project's live question,
   and it is more interesting than the three tracks §29.5 listed.
4. Abstractive and online to all ten conversations, or drop them from the paper's
   future work honestly.
5. The prose rewrite — abstract, introduction, threats, conclusion — is the
   authors'. `paper/README.md` explains why and in what order.

## 33. Committed and pushed

`f57f0ae` — *"LongMemEval: the headline does not replicate, and the scorer is
why"* — on branch `endtask-full-run`, 22 files, 1,851 insertions. Local and
remote hashes match.

```
.gitignore                  +10   SESSION_RECORD.md            +242
memgate/README.md           +22   memgate/memgate/abstractive.py  +217
memgate/memgate/online.py  +189   memgate/memgate/data.py        +114
memgate/run_abstractive.py +225   memgate/run_longmemeval.py     +188
memgate/run_online.py      +238   memgate/test_memgate.py         +64
paper/main.tex          reworked   paper/README.md               +107
paper/main.pdf            binary   results/longmemeval_S*.csv    4 files
```

### 33.1 What is deliberately not in the repo

* `memgate/data/longmemeval/` — `longmemeval_s_cleaned.json` is **265 MB**,
  over GitHub's per-file limit on its own, and `longmemeval_oracle.json` a
  further 15 MB. Both are downloaded artefacts, ignored on the same reasoning
  as `memgate/data/locomo/` and `memgate/models/`. Re-fetch from
  `xiaowu0162/LongMemEval`.
* `paper/main.log`, `paper/main.blg` — regenerated by every compile.
* `paper/main.pdf` **is** committed. It is the deliverable, and the reasoning
  that keeps `fig1`–`fig5` in the tree applies to it.

### 33.2 The remote moved

The push succeeded through a redirect, and GitHub reported:

```
remote: This repository moved. Please use the new location:
remote:   https://github.com/ruthme1ster/MemGate.git
```

`origin` still points at the old `ruthme1ster/ruthme1ster.git`. Redirects are
not forever:

```sh
git remote set-url origin https://github.com/ruthme1ster/MemGate.git
```

### 33.3 One machine constraint worth carrying forward

Three background jobs were OOM-killed this session — the S=32,768 sweep point
and two survival diagnostics — with swap at 5.8 GB of 7 GB from unrelated
desktop apps. `run_longmemeval.py` re-warms all 46,827 vectors per invocation
(~10 min) and then holds them alongside per-item stores, so a sweep costs
~20 min per budget and tolerates nothing else running.

The §30.3 scorer-separation result was obtained *after* the policy-level
diagnostic was killed twice, by scoring turns directly — no policy, no store,
no embeddings. **When a diagnostic keeps dying, ask whether the question can be
answered without replaying the haystack.** It usually can, and the cheaper
measurement is often the more direct one.

---

# Session 7 — 29 September 2026

## 34. The §30.4 confound, ruled out

§30.4 flagged that `MemGatePolicy.build_context` reserves `split[0]`=25% of the
context for Tier-1 recency before retrieval is consulted, while `RAGPolicy`
reserves nothing — so "P1-S vs RAG isolates which turns are forgotten" was not
strictly true. It was named as the first thing to fix before publishing any
LongMemEval number.

`run_lme_split.py` runs the identical comparison with the reservation removed.
94 items, S=23,000 (LoCoMo-matched retention), everything else held:

```
  P1-S split .25   strict   3.2%   answer  19.4%
  P1-S split 0     strict   2.1%   answer  19.4%
  RAG store-all    strict  21.3%   answer  40.3%

  P1-S split 0   vs P1-S split .25   answer   +0.00  [ +0.00,  +0.00]  n.s.
  P1-S split 0   vs RAG store-all    answer  -20.97  [-33.87,  -8.06]  significant
  P1-S split .25 vs RAG store-all    answer  -20.97  [-33.87,  -6.45]  significant
```

**The reservation is not load-bearing.** Removing it moves the answer metric by
exactly zero — the two arms score identically on all 62 answer-recoverable
questions. Selection loses to FIFO by 20.97 points either way.

So §30.3 stands unqualified: the failure is the scorer's transfer, not the
recency share and not the mechanism. Item 1 of §32's Next list is closed.

Strict recall differs slightly between the two (3.2% vs 2.1%, i.e. 3 of 94
against 2 of 94) — noise at that count, and §30.6 applies regardless.

`results/longmemeval_split_S23000.csv`.

## 35. Review 2 deck rebuilt

`docs/make_review2_deck.py` → 30 slides (was 28). Numbers are read from the
committed CSVs, as before; nothing is typed by hand.

**Two new slides**, placed after end-task accuracy:

* **18 — "We tested our own headline on a second benchmark — it failed."** The
  four-budget sweep table with clustered intervals, the +8.67 → −20.97 reversal
  at matched retention, and the scorer sign-flip (+0.0476 → −0.0346) as cause.
* **19 — "The obvious alternative explanation, ruled out."** The recency
  confound, why it should have mattered on LongMemEval specifically, and §34's
  +0.00 result.

**Updated:** the status slide (eleven experiments; LongMemEval and the paper
marked complete; abstractive and online demoted to "Pilot only" with the reason);
limitations (two added — the scorer is tuned to LoCoMo, and strict recall is
uninterpretable there for compressing arms); remaining work (reordered — a
scorer that transfers is now item 1); the conclusion (a sixth bullet for the
non-replication); deliverables and repo layout (68 tests, ~6,500 lines, 17
experiments, `paper/main.pdf`); and the timeline (end-task, LongMemEval and the
compiled paper filled in).

The deck now opens by conceding the headline does not transfer and closes on
"the more useful result is what doesn't work — including, twice now, our own
headline." That is a stronger Review 2 position than the September version,
which listed LongMemEval as not started.

## 36. State

* test suite **68 passed, 0 failed**
* paper: 6 pages, compiles, `paper/main.pdf` committed
* deck: 30 slides, rebuilt from CSVs
* §32 Next item 1 (the confound) **closed**; item 2 (S=32,768) still open

### Next

1. **S=32,768** — the last LongMemEval sweep point. ~20 min, must run alone.
2. **A scorer that transfers.** The project's live question, and what the final
   review should be about.
3. Abstractive to ten conversations (~4 h of generation), online to ten.
4. The prose rewrite — abstract, introduction, threats, conclusion — is the
   authors'.

## 37. Two of the three remaining gaps closed

### 37.1 S=32,768 — the sweep completed, and a claim of ours corrected

```
   store  retention   P1-S select  RAG store-all   selection - FIFO (answer)
    4,096      3.9%        14.5%           9.7%    +4.84 [ -3.23, +12.90]  n.s.
    8,192      7.9%        22.6%          14.5%    +8.06 [ -1.61, +17.74]  n.s.
   16,384     15.7%        21.0%          27.4%    -6.45 [-17.74,  +4.84]  n.s.
   23,000     22.1%        19.4%          40.3%   -20.97 [-33.87,  -8.06]  significant
   32,768     31.4%        30.6%          51.6%   -20.97 [-35.48,  -6.45]  significant
```

**§30 said P1-S "peaks at 8,192 and then flattens or declines". That was wrong**
— read off four points when the fifth reverses it. P1-S recovers to 30.6%; the
curve is 14.5 → 22.6 → 21.0 → 19.4 → 30.6, non-monotonic but rising. The dip at
16k–23k was noise at n=62 and was over-read.

What replaces it is stronger: **the deficit is −20.97 at both of the top two
budgets, significant at both.** Selection is not failing to use storage. It uses
storage consistently less well than forgetting oldest-first, once retention is
realistic. The §30.3 diagnosis is untouched.

Corrected in three places that carried the old claim: deck slide 18, its speaker
notes, and `REPORT.md` §3.9.

### 37.2 P4 online learning at full scale — the pilot was an artefact

```
  P0 recency     strict 12.6%   answer 25.6%
  P1 heuristic   strict 19.8%   answer 36.8%
  P4 online      strict 18.4%   answer 35.2%   1233 updates, alpha 0.76

  P4 vs P1   answer   -1.54  [ -4.63,  +0.79]  n.s.
  P0 vs P1   answer  -11.19  [-17.30,  -6.21]  significant
```

n = 1,527 / 715 answer-recoverable, ten clusters.

The two-conversation pilot reported **-12.16, significant**. At full scale it is
**-1.54, not significant**. P4 reaches parity with the hand-written heuristic
using only retrieval feedback — no labels, no future questions. §32's warning
that two clusters is "an interval in form only" is now demonstrated, not
asserted.

What it learned, which bears directly on §30.3:

```
ends_period  -0.529     is_question  +0.352
n_words      -0.372     has_month    +0.202
n_caps       -0.320     has_digit    -0.216
```

It learned to **disfavour long turns and sentence-final punctuation**. Correct on
LoCoMo, whose evidence turns are short factual lines. On LongMemEval, where every
turn is ~210-token prose ending in a period, those weights point the wrong way.
So P4 addresses §30.3's transfer failure **only if allowed to re-learn per
corpus** — which is the next experiment, not a result.

`REPORT.md` §3.10. Note that P4's parity is with P1 on LoCoMo; it has not been
run on LongMemEval.

### 37.3 Gap 3 in flight

`run_abstractive.py` across all ten conversations, ~3,700 generations against the
373 its one-conversation pilot used. Running under `nohup` so it outlives the
session's other work; log in the scratchpad. This closes the last of §29.5's
three tracks.

## 38. Gap 3 — abstractive compression at full scale

`run_abstractive.py` on all ten conversations. 4,879 generations, 383 cache
hits, 0 fallbacks, 3,892 s in the summariser arm.

```
  RAG store-all      strict 17.8%   answer 28.1%      0.5s
  P1-A extractive    strict 30.5%   answer 30.1%     76.3s
  P1-A abstractive   strict 32.3%   answer 34.1%   3892.3s
  P1-S select        strict 19.8%   answer 36.8%      2.1s

  abstractive - extractive   answer   +4.06  [+0.84,  +6.66]  significant
  select      - extractive   answer   +6.71  [+4.26,  +9.50]  significant
```

**Two findings, and they cut against each other.**

1. **A better compressor genuinely helps.** Rewriting beats word-selection by
   +4.06 answer points on real ten-cluster intervals. Part of §22/§23's negative
   result was about the *compressor*, not about compression. That is a
   correction to our own claim, found by our own experiment.
2. **Dropping still wins.** 36.8% against 34.1%. Even with a 1.5B model
   rewriting every evicted turn, keeping a scored subset whole beats compressing
   everything. The optimum stays at the vertex; §23 narrows rather than falls.

The cost asymmetry is the practical result: **3,892 s and 4,879 model calls to
finish 2.7 points behind a policy that takes 2.1 s and simply forgets.** §24.1's
crossover is not reached on the fidelity axis either.

This supersedes the one-conversation pilot recorded in §32, whose intervals were
degenerate (`ci_lo == ci_hi == delta`, one cluster) and whose `significant`
column was an artefact. `results/abstractive.csv` now carries real intervals.

## 39. All three scoped tracks closed — and each revised a claim

§29.5 scoped abstractive, LongMemEval and online for the final review. All three
are now measured at full scale, and **none of them simply confirmed what we
believed**:

| Track | What we expected | What it gave |
|---|---|---|
| LongMemEval (§30) | the +8.67 replicates | it reverses to −20.97; the scorer's evidence separation flips sign |
| Online (§37.2) | a significant loss, per the pilot | parity, −1.54 n.s.; the pilot was a two-cluster artefact |
| Abstractive (§38) | compression loses, full stop | rewriting is worth +4.06; dropping still wins |

### Propagated

`REPORT.md` §3.9/§3.10/§3.11 (and the §3.10/§3.9 ordering bug from the first
insert, fixed); `paper/main.tex` — the *"Extractive compression only"*
limitation replaced by the measured result, and future work reduced to the one
open question; the deck — status, limitations and remaining work; the speaker
notes — the "three scoped tracks" answer; `memgate/README.md` and
`paper/README.md`.

Paper still compiles at **6 pages**, 19/19 citations, 0 undefined references.

### What is actually left

1. **A scorer that transfers.** Every other track is closed. P4 online is the
   obvious first try — it reaches parity without labels, but the cues it learns
   (short turns, no sentence-final period) are the ones LongMemEval inverts, so
   it must be allowed to re-learn per corpus. Untested.
2. A larger summariser, to see whether the last 2.7 points to dropping close.
3. A second reader model, to separate the memory layer from this one.
4. The prose rewrite — abstract, introduction, threats, conclusion — is the
   authors'.

## 40. A larger training set for the learned scorer, and a shipped scorer

Full write-up: `docs/SCORER_TRANSFER.md`. In brief:

* REALTALK (10 real human chats, 8,944 turns, 660 questions) added beside
  LoCoMo (`data.load_realtalk`). LongMemEval could not be downloaded on the
  machine that ran this (huggingface.co blocked); the script accepts it.
* MiniLM loads from an ONNX export when the safetensors copy is absent
  (`utils._OnnxMiniLM`); `train_scorer.py` reproduces `learned_scorer.csv`
  with it (hand row exact, MiniLM row within one question).
* `train_transfer.py`, S=4096, hand+MiniLM, on PR #2's scorer: pooled training
  (all other 19 conversations) beats P1 on LoCoMo by **+14.55 [+10.40, +19.70]**
  answer recall and beats the old in-corpus protocol by +3.36 [+0.27, +6.52].
  On REALTALK every gain over P1 is n.s. (160 answerable questions).
  Cross-corpus transfer works REALTALK→LoCoMo (+9.09, SIG) but not
  LoCoMo→REALTALK (−4.38, n.s.). Hand features alone transfer worse than P1.
* Whole-word months on top of the tag fix lower recall, agreeing with PR #2.
* Boosted trees and a small MLP do not beat logistic regression (≤0.03 AUC,
  mixed sign); logistic regression stays.
* `export_scorer.py` fits the pooled model on all 20 conversations into
  `memgate/scorer_pooled_lr.json` (plain numbers, no pickle);
  `MEMGATE_SCORER=learned` makes `MemGatePolicy` use it. Library default
  stays P1 so every committed experiment keeps its meaning.

Item 1 of §39's list is now partly answered: the pooled scorer is the one that
transfers to a new conversation, but not yet shown on LongMemEval.

## 41. A 4× larger training set: BEAM, and a rebalanced shipped scorer

Full write-up: `docs/BEAM_RESULTS.md`. Viva Q&A: `docs/VIVA_PREP.md`. In brief:

* BEAM 100K (20 chats) and 500K (35 chats) added (`data.load_beam`), bringing
  the scorer's data to 75 conversations and 58,616 turns, 4× §40.
* Trained only on LoCoMo + REALTALK, the scorer ranks BEAM evidence below
  chance (AUC 0.372; P1 0.447). §3.9's LongMemEval sign flip replicates.
* With BEAM in the pool, at 20% retention (S = 26,000) answer recall on BEAM is
  76.5% vs P1's 35.3% (+41.18 [+20.51, +63.64], SIG; 34 answerable questions).
* Unweighted, BEAM (75% of turns) costs LoCoMo −3.22 [−6.50, −0.16] (SIG).
  `--balance` (equal weight per dataset family) removes that (−0.14, n.s.)
  and keeps the BEAM gain at S = 26,000 (+38.24, SIG). At S = 4096 (3% of a
  BEAM chat) the balanced gain is n.s.
* Shipped scorer refitted with `export_scorer.py --with-beam --balance`.
  Library default stays P1.
