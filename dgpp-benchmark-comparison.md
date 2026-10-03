# DGPP vs DGX Spark forum deployments — informal comparison baseline

DGPP figures updated 2026-09-16 from HawkBearPig/dgpp `docs/benchmarks.md`, `docs/measurements.md` and `CHANGELOG.md` (master). The forum snapshot remains the one compiled 2026-09-14. DGPP entries use the newest applicable production-path measurement; superseded internal baselines are omitted. Forum numbers are as posted by their authors.

## 1. Decode, single stream (tok/s)

| Model / world | DGPP (published) | Forum comparable (topic) | Read |
|---|---|---|---|
| GLM-5.3-Flash w4 FP8 | T=1 33.4 · MTP greedy 42–49 | 28–43 sustained, ~37 avg, 50+ spikes — native FP8, 1M ctx (381543) | DGPP median at/above forum band |
| GLM-5.3-Flash w4 NVFP4 hybrid | T=1 38.1 · MTP 50–59 (17.1–19.9 ms/tok) | 35.2 (32–39), TP=3 NVFP4 (381534) | DGPP ahead; 3-node vs 4-node caveat |
| GLM-5.3-Flash w2 | T=1 21.9 · MTP 23–33 | MTP-5 19.6–30.3 (381433) · DFlash2 21.8 (381429) · EXL3 27–32 (382486) · EXL3+DFlash2 33–74 c1 (Entrpi, via 382486) | Overlapping bands; forum extreme-quant lanes win on peaks |
| GLM-5.3-Flash w1 | not offered | 64 structured / 25 prose — EXL3 2.05bpw + DFlash2 K7 (382140) | No DGPP lane |
| Qwen3.8-Flash-Next w4 | T=1 46.5 · MTP d1 63–78 | 31.0 MTP-2 NVFP4 (381897) · 40.5 med / 54.2 peak TP4 NVFP4 (382476) | DGPP ~1.2–2.5×; DGPP FP8 vs forum NVFP4 |
| Qwen3.8-Flash-Next w2 | T=1 30.8 · MTP 42–50 | NVFP4 SPEED 53.7 med / 63.7 peak (382476) · SGLang FP8 36–41 (382435) | DGPP above the SGLang FP8 band; forum NVFP4 lane ahead |
| Qwen3.8-Flash-Next w1 | T=1 32.3 · MTP 43–50 (FP8 dense) | 32.5 med / 43.8 peak (382476) · 43 coding (381859) · MiaAI 37 (382446) · INT4-AutoRound 53.8–71, strict-c1 51 vs 36 (382733) | DGPP overlaps the NVFP4 lane; INT4-AR lane leads |
| GLM-5.3 full 754B w4 int4/int8 | T=1 19.5 · MTP d1 25–29 | c1 12.1 @ 200K ctx, TP4 vLLM (381755) | DGPP ~2.1–2.4× single-stream |
| DeepSeek-V4.1-Flash w4 MXFP4 | current recipe-client C1 49.64 aggregate / 54.8 per-stream scope | 77.2 peak c1 (counting) · 52 code · 47 math · 39 reasoning · 23 prose; 72 warm code (382897) | DGPP current aggregate sits in the forum's category band; forum headline is a peak |
| GLM-4.7 w4 NVFP4 | T=1 20.4 · MTP d1 30–33 | SGLang NEXTN MTP 24.4 c1 (366325) · TP2 17.5 @ 64K (375690) | DGPP ahead |
| DeepSeek-V4.1-Flash 8× Spark | not offered | 92.7 coding single / 256 @ 6 streams (382725) | Forum only |

## 2. Aggregate decode under concurrency (tok/s)

| Model / world | DGPP (published) | Forum comparable (topic) | Read |
|---|---|---|---|
| GLM-5.3-Flash w4 hybrid | 94–104 @ c=4 | ~40–50 @ c=4–5 (381543) | DGPP ~2× at equal concurrency |
| GLM-5.3-Flash w2 | 39–47 @ c=4 | 67.6 @ 12-way (382120) · 74–77 @ c=6 (382486) | Forum wins at c≥6; DGPP caps at 4 slots |
| Qwen w4 | 142–167 @ c=4 | 46 @ x2 · 53 @ x4 · 97 @ x8 · 157 @ x16 (381897) · 262 @ 6 TP4 (382476) | DGPP wins at c=4 (2.7–3.2× vs x4); forum wins at c≥6 |
| Qwen w2 | 69–83 @ c=4 | 88–98.5 @ 4 streams, SGLang FP8 (382435) · 309 @ 6 SPEED (382476) | SGLang c=4 lane ahead of DGPP |
| GLM-5.3 full w4 | 42–47 @ c=4 | 33.1 @ c4 · 46.0 @ c6 (381755) | DGPP leads at c=4; forum C6 overlaps DGPP's C4 |
| DeepSeek-V4.1 w4 | 108.49 @ C6 | 214 @ 6 (382897) · 131.9 @ 6 (tonyd2wild repo bench) | Forum ~1.2–2× at c=6 |
| GLM-4.7 w4 | 63–69 @ c=4 | 81.1 @ c=8, SGLang (366325) | Forum figure uses twice the concurrency |

## 3. Prefill (tok/s)

| DGPP (published) | Forum comparable (topic) |
|---|---|
| Qwen FP8 TP2 service: ~1,525–1,577 at 2K–32K after the Sept-15 QSA kernel; DSV41: 1,383 on its 2,950-token cold prompt; full GLM int4/int8: ~94–337 at 2K–32K; GLM-Flash hybrid remains 93.8 s at 32K | Qwen TP2 2,784 @ 28K · TP4 2,450 (382476) · GLM TP=3 1,800 (381534) · EXL3 kit 1,408 @ 240K (Reederey87 kit, via flowtivity Sep 13) · llama.cpp 4-node DSv4-0731 2,582–3,031 (381005) |

Read: the forum Qwen figures remain about 1.5–1.8× above DGPP's current Qwen TP2 service result. DGPP now offers opt-in budgeted prefill continuation to bound decode pauses; the shipped Qwen template keeps monolithic admission for maximum cold-prefill throughput.

## 4. Context / capacity

| DGPP (published) | Forum comparable |
|---|---|
| GLM-5.3-Flash hybrid 786K validated (fp8 latent cache, w4) · full GLM-5.3 208K fp8 · DSV41 128K | 1M ctx served on multiple lanes (381543, 382897 300K/1M proven, 382446 MiaAI 1M) · KV pools to 4.7M tokens (382486) |

## 5. Quality / determinism

DGPP publishes task-level quality with every throughput table: HumanEval 94.5–96.3%, GSM8K 97–100% of denominators, schema extraction 100/100, plus MTP==greedy transcript identity and cross-rank op-stream md5 identity as pass/fail gates. The forum's only task-quality datapoint is tsarihan's SWE-bench Pro enterprise-40 (382697): Qwen 36–38, GLM 36, DSv4 33 (needs thinking=true + temp 1.0, else 22/40). Suites do not overlap — not comparable; treat DGPP's quality gate as an extra control the forum numbers don't have.

## 6. Engine architecture map

The diagram below is generated from the repo source (rev 904f76c) with archify — interactive HTML (pan/zoom, theme, trace, export): [`~/dgpp-architecture.html`](../../dgpp-architecture.html) (spec `fc2d17fc05037599`, artifact `b8a35fa51583bdf7`, `visual-check` pass).

```html
<iframe src="../../dgpp-architecture.html" style="width:100%;height:720px;border:0;border-radius:8px"></iframe>
```

If the embed does not render in your viewer, open the file directly. Node copy matches the source tree:

- **Request path:** API clients → HTTP frontend (`serve/http_server`, OpenAI-compatible) → generation service (`serve/generation_service`, vision frontend) → scheduler (`sched/scheduler` + `sched/prefix_cache`) → graph engine (`engine/graph_engine`, MTP speculative decode).
- **Prefill economics (rev 904f76c):** resumable prefill with a **256 tok/tick busy budget** (`resolve_prefill_policy` auto) — admission-gated at 4 slots / queue 8, not chunking-gated.
- **Verify schedule** (`engine/verify_schedule`): confidence-scheduled verify depth implemented but **OFF in every shipped template** — dormant knob #1 for a test window.
- **Model lanes:** GLM lane (`models/glm`, NVFP4/FP8 hybrid — stalled since Sep 22) and Qwen lane (`models/qwen`, `mimo`, `dsv41` — active, packed int4 work lands here) share the CUDA kernel library (`kernels/`) and the checkpoint loader (`loaders/`).
- **TP2 fabric:** first-party collective bus (`net/collective_bus`, verbs/RDMA over RoCE, no NCCL) to the rank-1 node (`dgpp-serve --rank 1` on dgx2).

## Caveats — where this is not like-for-like

1. **Method.** DGPP: 3-run medians, fixed 5-class prompt set, client-side aggregates, determinism-gated. Forum: single runs, self-chosen prompts, and headline numbers are often peaks. Peak-vs-median on the same stack spans ~1.5–2× (e.g. 382476's own median-vs-peak rows).
2. **Prompt class.** Forum "prose" vs "structured/code" spans ~3× on one build (DSV41: 23 prose vs 52 code / 77 counting-peak, 382897). Compare per class only; DGPP publishes all five classes.
3. **Quantization.** DGPP serves FP8 / NVFP4-FP8 hybrid / MXFP4-FP8; forum lanes include EXL3 2.05–4bpw, INT4-AutoRound, NVFP4. Lower bits + deeper drafts trade quality for tok/s; acceptance and quality are mostly unpublished outside tsarihan's SWE run.
4. **Speculative decoding.** DGPP uses the checkpoint's own MTP at depth 1–2 with transactional verify; forum lanes use DFlash2 K7, MTP-5, DSpark d4–5. Deeper drafts inflate structured-prompt numbers.
5. **Concurrency caps.** Shipped Qwen and GLM-Flash templates cap at 4 slots; DSV41 ships six and full GLM eight. Qwen also has an opt-in eight-slot path. Forum runs go to 6–16 streams, so aggregate comparisons still depend on occupancy policy.
6. **Serving path.** The current DGPP prefill entries above use cold service measurements where available. Warm direct-engine ritual figures remain useful for kernel analysis but are not used for the Qwen comparison.
7. **Run health.** GB10 clock-gating is real: tonyd615's DSV41 went 5 → 41 → 77 tok/s after un-latching two GPUs stuck below 1 GHz (power-cycle fix, 382897). Some forum bests are post-fix numbers.
8. **Context length.** Decode step time grows with context (DGPP Flash: 41 ms @ 2K → 42–43 ms @ 32K). Forum numbers are often taken at 200K–1M ctx, DGPP's class tables at short ctx.
9. **No third-party DGPP measurements exist.** A Discourse search for "dgpp" returns zero hits (2026-09-14): every forum number is vLLM/SGLang/llama.cpp. The baseline is informal by construction — same hardware class and models, different engines and measurement conventions.

## Sources

- Repo: github.com/HawkBearPig/dgpp — docs/benchmarks.md, docs/measurements.md, CHANGELOG.md (master, updated 2026-09-16)
- Forum topics: 381543, 381534, 381433, 381429, 382486, 382140, 381897, 382476, 382435, 382446, 381859, 382733, 381755, 382897, 366325, 375690, 382725, 381005, 382697, 381228
- Blogs: flowtivity.ai DeepSWE benchmark (Aug 31) and dual-Spark GLM vs DSV4.1 (Sep 13, incl. Reederey87 EXL3 kit numbers)
- Raw sweep data: per-thread tok/s matches in /tmp/forum_mining.json
