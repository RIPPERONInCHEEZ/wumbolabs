+++
title = "Qwen3.8-Flash-Next"
description = "Qwen3.8-Flash-Next: tested profiles, validated context, and chronological evaluation history. Findings are attributed to the profile and event that measured them."
template = "lab_model.html"
weight = 2

[extra]
kind = "model"
model_id = "qwen3.8-flash-next"
vendor = "Qwen"
profile_count = 1
event_count = 1
latest_evidence_date = 2026-11-11
+++

This page collects WumboLabs evidence for **Qwen3.8-Flash-Next**: current findings, tested profiles, and chronological evaluation history. Each value belongs to its measured deployment; later findings do not silently replace historical evidence.

## Current state

- **Latest evidence:** 2026-11-11: Qwen3.8-Flash-Next IQ3_S: accepted Model/Core, Tool Use and Runtime Performance (Strata / R9700 HIP)

## Tested profiles

### IQ3_S: Strata v0.2.11 / R9700 HIP, reasoning ON/low (CURRENT)

Profile identity: `qwen3.8-flash-next-strata-r9700-hip-v11-on-2026-11-11`.

Runtime and artifact identity are described inside the event sections below (hand-authored records; no machine-readable export).

Status: current tested surface; not the recommended profile.

[Canonical Evidence](https://github.com/WumboLabs/evaluations/blob/b50eb6546cb01b95b329bf614e51e688b2f77714/models/qwen3.8-flash-next/events/qwen38-flash-next-welp-v11-strata-r9700-2026-11-11/REPORT.md)
[Profile Metadata](https://github.com/WumboLabs/evaluations/blob/87ab638502d63eea47a5f8734eed729b39e3042c/models/qwen3.8-flash-next/profiles/qwen3.8-flash-next-strata-r9700-hip-v11-on-2026-11-11/profile.json)

Events on this profile:

- [Qwen3.8-Flash-Next IQ3_S: accepted Model/Core, Tool Use and Runtime Performance (Strata / R9700 HIP) (2026-11-11)](/evaluations/qwen3-8-flash-next#qwen38-flash-next-welp-v11-strata-r9700-2026-11-11); status: NOT_ASSIGNED

## Testing history

Newest first. Each event is one immutable testing/publication event; the exact scientific report lives in the canonical evidence repository linked at the top of each event.

<a id="qwen38-flash-next-welp-v11-strata-r9700-2026-11-11"></a>

### 2026-11-11: Qwen3.8-Flash-Next IQ3_S: accepted Model/Core, Tool Use and Runtime Performance (Strata / R9700 HIP)

**HUMAN_ACCEPTED independent sections; HelicopterBench deferred by owner** · profile: IQ3_S: Strata v0.2.11 / R9700 HIP, reasoning ON/low · maturity: CURRENT_WELP · status: NOT_ASSIGNED

[Canonical Evidence / Full Report](https://github.com/WumboLabs/evaluations/blob/b50eb6546cb01b95b329bf614e51e688b2f77714/models/qwen3.8-flash-next/events/qwen38-flash-next-welp-v11-strata-r9700-2026-11-11/REPORT.md)
[View on GitHub](https://github.com/WumboLabs/evaluations/tree/87ab638502d63eea47a5f8734eed729b39e3042c/models/qwen3.8-flash-next)

# Qwen3.8-Flash-Next IQ3_S: Strata / R9700 accepted scientific findings

Event: `qwen38-flash-next-welp-v11-strata-r9700-2026-11-11`. Model: Qwen3.8-Flash-Next. Evidence: REAL_MODEL.

**HUMAN_ACCEPTED scope: Model/Core baseline, Advanced Tool Use and Runtime Performance only.** HelicopterBench is **DEFERRED_BY_OWNER**, outside scientific acceptance. This is not uniform acceptance of every section in the original campaign. No overall model-readiness classification or serving recommendation is assigned.

This public-safe derivative preserves the original campaign identity, all accepted outcomes and their limitations. Original local evidence governs scientific conflicts. The structured export accompanies this report; no model responses, private reviewer attribution or private decision-source bytes are published. No new inference or rescoring was performed for publication.

## Identity and deployment

- Profile: `qwen3.8-flash-next-strata-r9700-hip-v11-on-2026-11-11`; revision `30ec2e0692dd4d15ddea24d68632784be6d12cca4fa6a0875106c5e8fbc4251c`.
- Model revision: `ed59f92082b1e93c0e96d60a8b11aab089b52f09`; IQ3_S, GGUF with native Strata pack.
- Transformer shard: 54817524224 bytes; SHA-256 `4c1eb2ceb4915e1192f4f386021897bde56a97f40a0bb78bb86465e0f7d2aca3`.
- Shared n-gram shard: 28800138432 bytes; SHA-256 `316b46f3a2dbd68c900f43136ab9449f9dcc3725dfd8c794847c204bc161e113`.
- Native served model: `Qwen3.8-Flash-Next-GSQ-RCO-IQ3_S`.
- Strata v0.2.11; engine 0.1.57 / `0bdcef4682c5+rocm`; Control 0.1.57 / `c3b3f5035506`. Engine SHA-256 `29715dda2cfa020649e54f835966b66ecbcf3fcb954c548c9a8841fa3bb99afd`.
- AMD HIP, gfx1201, Radeon AI PRO R9700 32 GB; isolated ROCm SDK10.1.0 in original execution evidence. Application hipBLASLt dispatch remains UNKNOWN.
- Native reasoning ON, effort low. Temperature1.0, top_p0.95, top_k20, seed42.
- Configured capacity196608 tokens. This is not occupied196K semantic validation and is not a validated practical-context default.
- Chat-template SHA-256 `12827f24b742ea4e80cdc12dbcf9622227056b9f797252a3149263d4f9aaadce`.

## Model/Core: model-baseline/2

**61/61 identities, 57 effective PASS /4 genuine substantive FAIL**, zero exclusions, technical INVALIDs, budget-limited results or unresolved rubric reviews. These are identity outcomes, not a universal quality percentage. Equivalently55 semantic PASS/4 semantic FAIL plus two valid performance-sanity PASS results. The four original failures are `Q02`, `instruction-conflict-01`, `multi-turn-correction-01`, `strict-extract-09`.

| Identity | Effective outcome | Original outcome | Reason |
|---|---|---|---|
| `Q01` | PASS | PASS | None |
| `Q02` | FAIL | FAIL | None |
| `Q03` | PASS | PASS | None |
| `Q04` | PASS | PASS | None |
| `Q05` | PASS | PASS | None |
| `Q06` | PASS | PASS | None |
| `Q07` | PASS | PASS | None |
| `Q08` | PASS | PASS | None |
| `Q09` | PASS | PASS | None |
| `Q10` | PASS | PASS | None |
| `Q11` | PASS | PASS | None |
| `Q12` | PASS | PASS | None |
| `coding-comprehension-01` | PASS | PASS | None |
| `coding-correction-01` | PASS | PASS | None |
| `coding-debug-01` | PASS | PASS | None |
| `coding-generation-01` | PASS | PASS | None |
| `context-family-a-v2-3072-seed-314159` | PASS | PASS | None |
| `context-family-a-v2-3072-seed-42` | PASS | PASS | None |
| `context-family-a-v2-4096-seed-314159` | PASS | PASS | None |
| `context-family-a-v2-4096-seed-42` | PASS | PASS | None |
| `context-family-a-v2-8192-seed-314159` | PASS | PASS | None |
| `context-family-a-v2-8192-seed-42` | PASS | PASS | None |
| `context-multidocument-v2-6144-seed-42` | PASS | PASS | None |
| `context-multidocument-v2-8192-seed-42` | PASS | PASS | None |
| `document-synthesis-01` | PASS | NOT_EVALUABLE | None |
| `evidence-gpu` | PASS | PASS | None |
| `evidence-metric` | PASS | PASS | None |
| `evidence-xid` | PASS | PASS | None |
| `fact-journal-current-boot` | PASS | PASS | None |
| `fact-python-bool` | PASS | PASS | None |
| `fact-ssh-copy` | PASS | PASS | None |
| `git-amend` | PASS | NOT_EVALUABLE | None |
| `hall-fake-cuda` | PASS | PASS | None |
| `hall-fake-package` | PASS | PASS | None |
| `hall-fake-repo-state` | PASS | PASS | None |
| `hall-git-timewarp` | PASS | PASS | None |
| `instruction-conflict-01` | FAIL | FAIL | None |
| `linux-diagnosis-stale-config-bind-failure` | PASS | NOT_EVALUABLE | None |
| `linux-diagnosis-startup-invalid-config` | PASS | NOT_EVALUABLE | None |
| `multi-turn-correction-01` | FAIL | FAIL | None |
| `perf-short` | PASS | PASS | None |
| `perf-substantial` | PASS | PASS | None |
| `reasoning-consistency-01` | PASS | PASS | None |
| `reasoning-correctness-01` | PASS | PASS | None |
| `reasoning-evidence-01` | PASS | PASS | None |
| `repository-timeout-01` | PASS | PASS | None |
| `strict-exact-02` | PASS | PASS | None |
| `strict-extract-09` | FAIL | FAIL | None |
| `strict-limit-05` | PASS | PASS | None |
| `structured-schema-01` | PASS | PASS | None |
| `structured-semantics-01` | PASS | PASS | None |
| `sycophancy-logic` | PASS | PASS | None |
| `sycophancy-systemd` | PASS | PASS | None |
| `sycophancy-unknown` | PASS | PASS | None |
| `tool-permission-01` | PASS | PASS | None |
| `tool-recovery-01` | PASS | PASS | None |
| `tool-selection-01` | PASS | PASS | None |
| `uncertainty-api` | PASS | PASS | None |
| `uncertainty-citation` | PASS | PASS | None |
| `uncertainty-file` | PASS | PASS | None |
| `untrusted-content-01` | PASS | PASS | None |

### Practical Context and advancement

All eight Practical Context tasks PASS at their bounded baseline conditions: controlled context3072/4096/8192 targets with two seeds and multi-document6144/8192 targets. Actual native prompt occupancy ranged3057 to8178 tokens, with4096 generation reserve; no advanced or near-capacity196K claim. Four subjective tasks retain their qualified independent primary reviews; no missing judgment is silently positive.

| Capability | Standard eligibility | Scheduled decision |
|---|---|---|
| coding | ADVANCE | DEFERRED |
| long-context | ADVANCE | DEFERRED |
| reasoning | ADVANCE | DEFERRED |
| tool-use | ADVANCE | ADVANCE |

Original capability-witness/2 evidence qualifies all four routes for ADVANCE. Frozen priorities and one specialist slot select Tool Use; remaining routes are budget-postponed, not negative capability findings. Agentic remains NOT_TESTED. No readiness classification is inferred.

## Advanced Tool Use: tool-use-advanced/1

**3/3 authentic PASS**, one attempt per task, nine original generations.

| Identity | Outcome | Evidence boundary |
|---|---|---|
| advanced-tool-selection-01 | PASS | Executed dependency-grounded user to account to invoice chain |
| advanced-tool-permission-01 | PASS | Authorized read-only diagnosis, no prohibited mutating operation |
| advanced-tool-recovery-01 | PASS | Genuine informative error, identifier discovery and corrected native tool call |

Original native tool IDs, arguments, simulator receipts and feedback are retained in manifest-bound local evidence and replay-verified. Text resembling a call is not credited as execution. These fixed tasks do not establish general Agentic readiness.

## Runtime Performance: runtime-performance/1

Both workloads MEASURED; three original streaming repetitions per workload, all sanity answers PASS. Native engine rates remain separate from DERIVED wall-clock estimates.

| Workload | Native generation median tok/s | TTFT median seconds | Total median seconds | Input/completion tokens each repeat |
|---|---:|---:|---:|---|
| perf-short |50.7|0.136103|0.907820|59/40|
| perf-substantial |54.6|0.146067|0.988407|3659/47|

Short repeats process5 native uncached tokens and reuse54. The first substantial repeat processes3659 with cache_n0: native full-prompt826.9tok/s, TTFT4.449965s,total5.303870s. Substantial repeats2 and3 process5 and reuse3654; their prompt rates concern only that tiny interval. Full-prompt and cache-reuse intervals are aggregated separately under native-input-cache-split/1; a cached-interval rate is not full-prompt throughput.

Native prompt_n plus cache_n agrees with total input usage; predicted_n agrees with inclusive completion usage. Native completion includes reasoning. Separate reasoning-token counters and generated-token IDs are unavailable. Raw native counters, usage detail and per-repeat observations remain in the structured export.

AMD device-wide memory before/after each complete workload was32312918016bytes, with whole-MiB granularity. These are boundary observations, not process allocations, continuous samples or true peaks. Process-attributed memory and true peaks remain UNAVAILABLE; host minimum available memory is UNKNOWN. No controlled Strata-versus-CUDA comparison or universal performance ranking is claimed.

## Deferred HelicopterBench

**DEFERRED_BY_OWNER; not scientifically accepted in this event.** The attempted helicopterbench/3 section, original generated game, automated observations, attributed human review, unresolved disagreements and gameplay video remain historical private evidence. No reconciled accepted game score exists. Neither a disputed score nor the video is published here as an accepted benchmark demonstration. The attempted section is not reclassified NOT_RUN.

Routine WELP evaluations exclude HelicopterBench. Future separately authorized research may develop one suite with independent Build and Play eligibility/scores; no combined universal score is authorized. Nothing in this publication implements or approves a new scoring method.

## Acceptance and original evidence references

Owner HUMAN_ACCEPTED the three named independent sections in a genuinely delivered authorization. The existing welp-scientific-acceptance/1 receipt binds exact manifests and the private original decision-source hash `08becfc90444cdbfa1a6366969792b92d1927aaef608dca7e644a2a4716b5a2d`. This is a recorded human decision, not a synthetic acceptance or historical signature. Scientific acceptance does not waive integrity, negative outcomes or unavailable metrics.

| Original section | Acceptance disposition | Manifest SHA-256 |
|---|---|---|
| advanced-tool-use | HUMAN_ACCEPTED | `69e393312a9c6d88fa4d767c87e8c402a9b5d01636f044ccb66dae76e48e7ef8` |
| baseline | HUMAN_ACCEPTED | `1269f387b930d3212171cc79e974fd60f5037fba6a4ce703b39a163465108815` |
| runtime-performance | HUMAN_ACCEPTED | `6f272fac85e72f6f154ea8aa56633d3ecf27b5cb3a858015cc0029fb0573a450` |
| helicopterbench | DEFERRED_BY_OWNER, excluded | `407dfb6c05594cafc18efaa1cbf57b5a41318abfdfa46e29000d1956d025e9eb` |

All four original manifests and67 original unit outcomes verify offline, including preservation of the excluded section; integrity verification is not acceptance of that section. Original reports, manifest references and profile revisions remain in the structured export. Scoring methods remain tied to the accepted v1.1 scientific contracts; original v1.0 and v1.1.0 releases and historical campaigns are unchanged.

## Canonical evidence

All canonical public evidence lives in WumboLabs/evaluations. Each event links an immutable full-commit/path citation; each profile remains a distinct scientific identity, not a separate repository.

- **qwen3.8-flash-next-strata-r9700-hip-v11-on-2026-11-11**: [Profile Metadata](https://github.com/WumboLabs/evaluations/blob/87ab638502d63eea47a5f8734eed729b39e3042c/models/qwen3.8-flash-next/profiles/qwen3.8-flash-next-strata-r9700-hip-v11-on-2026-11-11/profile.json)
