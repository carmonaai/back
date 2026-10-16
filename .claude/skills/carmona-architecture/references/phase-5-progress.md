# Phase 5 progress (admission + fairness)

Working log started 2026-10-03. Plan: [inference-plan.md](inference-plan.md) §3 step 6, §7 (admission, fairness, capacity), §11 row 5. Rules: `phase-5` branches only (`inference-service`, `back`); commit and push when green; PRs at the end; never merge without the user's go-ahead.

## Checklist

- [x] inference-service: Valkey rate buckets (Lua: requests, input tokens, output tokens per minute, per organization and model), settle with real counts at the end
- [x] inference-service: in-flight caps in memory (tier share of the model's slots, per-organization cap), permit held with `usingWhen`
- [x] rate-limit headers (`x-ratelimit-limit/remaining-requests|tokens`), `retry-after` + `retry-after-ms` on 429
- [x] IT: request bucket → 429 with headers; output charged after the request; tier share, org cap, other enterprise org still admitted (12 tests green)
- [x] compose: inference-service gets Valkey
- [x] smoke: rate-limit header present; trial over its share → 429 `model_busy` fast while an enterprise org is served (CPU and GPU green)
- [x] bench on the GPU through the gateway, one key per tier (`docker/bench.sh`): trial 429 < 100 ms, enterprise goodput ≥ 95%, no TTFT timeouts
- [x] Docs: plan progress/deviations, skills, templates
- [x] Commit + push, PRs

## Design decisions (keep consistent when resuming)

- **Order**: parse (400s never count) → buckets in Valkey → caps in memory → engine. Buckets come first so the caps are taken synchronously right before the engine call (no async gap that could leak a permit). A request refused by a cap still counted against the buckets, as OpenAI counts unsuccessful requests.
- **Buckets** `rl:{org:model}:requests|input|output` (one hash slot), one Lua script (`buckets.lua`, Valkey `TIME`): linear refill to the limit over a minute; admission needs ≥ 1 in each; requests −1 and input −(body bytes ÷ 4) at admission; at the end, input ± (real − estimate) and output −real. Buckets may go negative; a key expires when it would be full again. Valkey down or slow (500 ms timeout) → buckets skipped with a WARN, caps still apply.
- **Caps** per model (deployment) in memory: trial `max(1, C/2)`, standard `max(1, 0.85·C)`, enterprise `C + q` on the model's in-flight count, then `max-in-flight` per organization and model. One `synchronized` map (ponytail: per-model locks if it shows in a profile). Released by `Flux/Mono.usingWhen` on complete, error or cancel; a refused request never reaches usage-service.
- **Limits** per tier (`carmona.inference.tiers`), applied per organization and model; prototype values: trial 20 rpm / 20k input tpm / 10k output tpm / 2 in flight; standard 300 / 200k / 50k / 4; enterprise 3000 / 2M / 500k / 16. No "model class" axis yet (two models).
- **Slots**: llama.cpp C = 2 (`-np 2`), q = 2; vLLM C = 4, q = 2 (phase 3: q ≤ ~2 keeps TTFT p95 near 2 s). vLLM `--max-num-queued-reqs 8` stays as the engine-side backstop.
- **429 shape**: OpenAI error, type `rate_limit_error`, code `rate_limit_exceeded` (buckets, org cap) or `model_busy` (tier share); headers `retry-after` (s), `retry-after-ms`; 1 s for caps.
- **Tiers are staff-set** (no API): smoke and bench set `organizations.organization.tier` with psql before the key's first use (the gateway caches the key's tier for 60 s).

## Notes

- Smoke flake found and fixed: "Write a very long story." sometimes ends after ~50 tokens on Qwen3-0.6B, so a "long" background stream wasn't in flight; both long streams now count to 1000 at temperature 0 (runs > 10 s every time).
- First GPU smoke right after `up --wait` failed with curl exit 56 on the first request (gateway just restarted); the rerun passed.
- Bench 2026-10-03 (`docker/bench.sh`, 60 s, all three tiers at once through the gateway, 128-token streams), two runs after a vLLM restart:

  | tier | load | answered | refused | latency |
  |---|---|---|---|---|
  | enterprise | 4 workers back to back | 82–83, all | 0 | goodput 98%, TTFT p95 253–351 ms, TPOT p95 22 ms, ~176 output tok/s |
  | standard | 4 workers, 0.5 s pause | 1–2 | 445–465 `model_busy` | 429 p95 7 ms, max 84 ms |
  | trial | 12 workers (3×C), 1.5 s pause | 0–1 | ~38 `model_busy`, ~438 `rate_limit_exceeded` | 429 p95 9–16 ms, max 62–91 ms |

  No TTFT timeouts. Enterprise's two misses per run are at the start: a trial and a standard request got in before enterprise filled the 4 slots, so two enterprise requests waited 2.8 s (vLLM's priority orders the queue but never evicts a running request). After that, standard and trial are shed. With enterprise using all of C, standard gets nothing: that is the reserved-capacity design (plan §7); fairness inside and across tiers beyond that is later work (VTC/DRR on Kubernetes).
- The first bench run (right after vLLM came back) had slow 429s (p95 770 ms, max 2.4 s); the next two had none over 91 ms. Watch the 100 ms mark: it has little margin on the laptop.
- Leftover from the run that ran the VM out of memory: one synthetic "Bench" account with three organizations in the local DB (never cleaned up because the script died). Synthetic data only.
- `vllm bench serve` twice in parallel (enterprise + standard) next to vLLM, llama.cpp and nine JVMs ran the Docker Desktop VM out of memory (host 0.8 GB free, Docker API 500, WSL unresponsive). The bench now uses curl workers in the llama container for all three tiers (TTFT = time to first byte, TPOT from the usage chunk).
