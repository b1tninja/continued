# Local provider capacity: parallel sessions, parked conversations, and how many agents run at once

Status: research, 2026-11-13. Docs only: no code, no ROADMAP edit, no model call, no generation request to any server. Codebase references are to `main` at `d35c3bc1d`. Strata references are to its repository (https://github.com/Niko1221/Strata) at `c62d5e3a`, read locally. Upstream server facts were fetched on 2026-11-13. Companion to [`../parallel-agents.md`](../parallel-agents.md) section 7 and phase A7, [`caching-context-cost.md`](./caching-context-cost.md), [`session-forking-and-cache.md`](./session-forking-and-cache.md) (PR #830) and [`subagent-sessions-phase2.md`](./subagent-sessions-phase2.md) (PR #820); both links resolve once those PRs merge.

The owner's question: with a local provider such as Strata, can we tell how many conversations can be **parked** (kept warm in the server's prompt or KV cache) and how many agent sessions can **run** at once on that server? Can we then use those numbers to decide whether subagents are enabled, how many run at once (subagents, loop workers, parallel waves) and what each provider's session limit is?

## 1. Summary

1. **Yes, for the servers that matter here, and the two numbers are different.** "Running at once" is the server's decode slots: Strata `concurrency.serving`, llama.cpp `total_slots`, vLLM `max_num_seqs`, SGLang `max_running_requests`, Ollama `OLLAMA_NUM_PARALLEL`, LM Studio "Max Concurrent Predictions". "Parked" is how many conversations the server keeps warm while they are not running. Strata reports it directly (`conversation_cache.slots`, `budget_mib`, `parked`, `bytes`, `evictions` in `/metrics`). llama.cpp keeps idle slots in a host-RAM prompt cache (`--cache-ram`, 8192 MiB by default) but does not report its occupancy. vLLM and SGLang only report KV usage and a prefix hit rate, so "parked" there is an estimate.
2. **The owner's Strata serves one request at a time and parks up to 4 conversations.** Its config (`strata-nvfp4-nvfp4.json`) sets no `parallel`, `--conversation-cache-mib 24576` and `--conversation-cache-min-tokens 4096`. Its log says "up to 4 parked conversations". Across 3,231 parks in its log, a parked snapshot costs about **16 KB per token plus 0.6 GiB**: about 2.4 GiB at 120K tokens, 4.3 GiB at 250K and 8 GiB at 500K. So 24 GiB holds 4 conversations up to about 330K tokens each and 2 or 3 near the 524K window.
3. **On Strata, parking is the capacity that counts, not slots.** The owner's own measurement (3 agents, about 120K tokens each, requests sent at the same moment) took 6.2 s per round with one serving slot and the conversation cache, against 13.4 s with `"parallel": 3`. Batch slots also cost a lone agent 13 to 21% of its decode speed. Restoring a parked 400K conversation takes 0.9 to 1.5 s. Reading it again cold takes 75 to 90 s (about 5,000 tok/s). **Eviction, not queueing, is the expensive failure.**
4. **Our code already reads the slot count but not the parking capacity.** The GUI caps subagents and Loop wave workers at 3 (`core/subagents/scheduling.ts:7`) and also takes one of the server's slots per run (`gui/src/util/subagents/runSubagent.ts:278-307`, from `models/serverConcurrency` at `core/core.ts:560-565`). On a one-slot Strata that runs **whole subagent runs one after another**, so the parent sits idle and tool time is not overlapped. The CLI runs subagents one at a time unconditionally (`extensions/cli/src/subagent/executor.ts:147-199`). CLI Loop waves start every worker process at once and never ask the server (`extensions/cli/src/loop/loopWave.ts:331`). Nothing reads rate-limit headers, and nothing counts the parent's own conversation against the server's cache.
5. **Recommended first slice (P1): a cached capacity probe and a budget used by both hosts.** One `serverCapacity(apiBase)` call in core returns `{ serving, parkSlots, parkBudgetMiB, parked, queued, source }` from `/v1/status` and `/metrics` (Strata), `/props` and `/slots` (llama.cpp), and `/api/ps` (Ollama), cached for 60 s. A derived budget, **`agents = min(user setting, serving + parkSlots - 1)`** (the 1 is the parent), replaces "one subagent run at a time" with "requests queue at the server, conversations stay parked". The CLI wave and CLI subagents use the same budget. When the budget is 1, subagents still run, one after another, with a one-line reason. This needs no UI beyond that line, and it fixes the CLI wave thrash.

## 2. What Strata is and what it exposes

Strata is a local inference server for large MoE models on consumer GPUs, with its own C++/CUDA engine (`engine/strata.exe`) behind a Python HTTP front end (`serve/server.py`, about 9,600 lines). It speaks OpenAI Chat Completions, Anthropic Messages and OpenAI Responses (`docs/DETAILS.md:406-410`). It mirrors llama-server's names where it can (`/props`, `/slots`, `llamacpp:*` Prometheus names). On this machine it holds port 8080, as `bench/lab/README.md:143` notes, and our code already detects it by `GET /v1/status` returning `service: "strata"` (`core/llm/localServers.ts:516-533`).

**The server was not running during this research.** `GET http://127.0.0.1:8080/health` got "connection refused", so every field below is from Strata's source and its log file (`strata-nvfp4-nvfp4.log`, 17.9 MB, last written 2026-11-12). No live payload was captured. Capturing one is the first step of P1 (section 8).

### 2.1 Endpoints and fields relevant to capacity

| Endpoint | Fields | Source |
| --- | --- | --- |
| `GET /v1/status` | `service: "strata"`, `model`, `loaded`, `auto_load`, `context.native`, `cache_max_tokens`, **`concurrency.serving`** (batch slots, at least 1), `concurrency.requested`, **`activity.in_flight`** (running + queued), `last_timings`, `vram`, `machine.gpu`/`ram` | `serve/server.py:5047-5100` |
| `GET /metrics` (JSON, not Prometheus) | `engine` (model, `max_context`, engine INFO incl. `conversation_cache_mib`, `conversation_cache_slots`), `live` (`state` reading/generating/idle/unloaded, `queued`, `prompt_read`/`prompt_total`, `tok_s`; with batch slots also `parallel`, `running`, `slots[]`, `waiting`, `admitting`), `requests[]` (last 12, each with `prompt_tokens` and **`reused`**), `totals` (`prompt_tokens`, `reused`, ...), **`conversation_cache`** | `serve/server.py:4955-5012` |
| `metrics.conversation_cache` | **`enabled`, `budget_mib`, `slots`, `parked`, `bytes`, `evictions`, `parks`, `restores`, `last_event`, `last_tokens`, `last_at`**, `requests`, `requests_reused`, `reused_tokens`, `prompt_tokens`, `last_reused`, `last_prompt` | `conversation_cache_view`, `serve/server.py:860-870`; `parked`/`bytes`/`evictions` are parsed from the engine log by `ConvCacheLog`, `:790-845` |
| `GET /metrics/prometheus` | `llamacpp:requests_processing`, **`llamacpp:requests_deferred`** (queued), `llamacpp:prompt_tokens_cached_total`, `llamacpp:prompt_tokens_total`, throughput gauges, `strata:model_loaded` | `serve/server.py:5014-5045` |
| `GET /slots` | one entry per batch slot (or one for the whole engine): `id`, `n_ctx`, `is_processing`, `n_prompt_tokens` | `serve/server.py:7384-7401` |
| `GET /props` | llama.cpp-compatible; `total_slots` | `serve/server.py:7381-7383` |
| `GET /v1/telemetry` | `work.max_queue`, `queue_timeout_s`, `queue_timeouts`, `admission_limit`, `oldest_queue_s` | `serve/server.py:7123-7195` |
| `POST /slots/0?action=save\|restore` | the held conversation to or from a file, only with `--slot-save-path`; JSON from Strata's own page or a trusted origin only | `serve/server.py:4409-4430`, `:7434-7435`; `docs/DETAILS.md:728-737` |

### 2.2 How Strata parks a conversation

From `docs/DETAILS.md:684-726`:

- The live session plus up to 6 in-RAM checkpoints serve the conversation that ran last. Taking a checkpoint at a shared system prompt lets a new chat start after it.
- `--conversation-cache-mib N` / `--conversation-cache-slots N` "park conversations in a bounded host-RAM cache so alternating requests (controller and worker histories, sub-agents) reuse their prompts". Without the flag the budget is 40% of free RAM, at most 8192 MiB. "It preserves histories; it does not run requests at once."
- `--conversation-cache-min-tokens N` parks only conversations of at least N tokens, "so short side requests do not evict a long conversation".
- "Oldest parked entries are evicted first" (LRU). A new conversation that starts at a checkpoint inside a parked one "restores that prefix and leaves the parked conversation in place (the log says 'borrowed')". This is the subagent case: siblings with one system prompt share it.
- Per request, `"strata_checkpoint": false` keeps a one-shot request from parking or evicting anything. Our CLI can already send it through `contextManagement.requestBodyHints` (`extensions/cli/src/contextManagement.ts:13-23`).
- There is **no API to park, unpark or pin a conversation by name**. Parking is implicit, on the next request from another conversation. `strata_prefix` pins one document prefix per engine, which is a different use.

### 2.3 What the log shows on the owner's machine

| Measure | Value | Log evidence |
| --- | --- | --- |
| Park capacity | "up to 4 parked conversations" in every sizing line; budget 24576 MiB from the config | `conversation cache sized from the free RAM: ... for up to 4 parked conversations` |
| Snapshot size | least squares over 3,231 parks (25 to 422K tokens): **16.0 KB/token + 593 MiB** | `parked N tokens ...; snapshot_bytes=B` |
| Park time | median 169 ms; 0.3 to 1.2 s at 30K to 140K; one 37.9 s outlier at 383K (paging) | same lines |
| Restore time | 28 ms at 5K; 0.9 s at 388K (checkpoint); 1.5 s at 409K (live) | `restored N tokens (...) in T ms` |
| Cold read | 383K to 422K tokens in 75 to 89 s, **4,570 to 5,110 tok/s** | `prompt N tokens = 0 reused + N read in T ms` |
| Evictions | 4,986 park lines and 1,763 restores in this log; `evictions=` reached 42 in one run | `evictions=E` |
| RAM floor refusals | parks skipped when free RAM was under snapshot + 2560 MiB, and 21 starts with the cache **off** for lack of RAM (before the 128 GB kit) | `skip parking (physical RAM admission ...)`, `conversation cache off` |

The owner's earlier diagnosis of Cline on this server: 3 parallel subagents caused 177 agent switches in 214 requests, and with parking off every switch re-read about 250K tokens (about 45 s). With a 20 GiB cache, 99% of the prompt was reused and the first token came in 1.14 s. Batch slots lost in both the alternating and the simultaneous test. (Owner notes outside this repository, 2026-11-01.)

## 3. Capacity signals by server

| Server | Runs at once | Context per running conversation | Parked / warm conversations | Queue and pressure | Overload answer |
| --- | --- | --- | --- | --- | --- |
| **Strata** | `/v1/status` `concurrency.serving` (`"parallel": N`, default 1) | `context.native`; each batch slot gets the full `n_ctx` (`/slots`) | **`/metrics` `conversation_cache.slots`, `budget_mib`, `parked`, `bytes`, `evictions`** | `activity.in_flight`, `live.queued`, `llamacpp:requests_deferred`, `/v1/telemetry` `oldest_queue_s` | Unbounded queue by default. With `max_queue`: 429 `admission_full`, `Retry-After: 1`. With `queue_timeout_s`: 429 `queue_wait_timeout`. 503 while draining or GPU busy (`serve/server.py:7450-7471`, `:7550-7557`) |
| **llama.cpp `llama-server`** | `/props` `total_slots` (`-np, --parallel N`, default -1 = auto) | `/slots[].n_ctx`. With `--kv-unified` (default when slots are auto) the slots share one KV pool. The README does not say how `-c` is split, so read `n_ctx` per slot rather than dividing | Idle slots move to a host-RAM prompt cache (`--cache-ram`, default 8192 MiB; `--cache-idle-slots`), **not reported**. Explicit parking to disk: `POST /slots/{id}?action=save\|restore\|erase` with `--slot-save-path` | `/slots[].is_processing`; with `--metrics`: `llamacpp:requests_processing`, `llamacpp:requests_deferred`, `llamacpp:n_busy_slots_per_decode` | Queues. `GET /slots?fail_on_no_slot=1` answers 503 when no slot is free |
| **vLLM** | `--max-num-seqs` (not exposed over HTTP); actual `vllm:num_requests_running` | `/v1/models` `max_model_len` | Estimate only: `vllm:kv_cache_usage_perc`, `vllm:prefix_cache_queries`/`_hits` (tokens). The startup log line "GPU KV cache size: N tokens" / "Maximum concurrency for M tokens per request: Kx" is the capacity, but it is in the log only | `vllm:num_requests_waiting`, `vllm:num_preemptions` (evictions under pressure), `vllm:time_to_first_token_seconds` | Queues; preempts and recomputes when KV runs out |
| **SGLang** | `--max-running-requests`; `/server_info` (admin-gated when `--admin-api-key` is set) | `--context-length` | Radix (prefix) cache, estimate only: `sglang:token_usage`, `sglang:cache_hit_rate`, `sglang:num_used_tokens` (with `--enable-metrics`) | `sglang:num_running_reqs`, `sglang:num_queue_reqs`; `--max-queued-requests` | Queues; past `--max-queued-requests` it refuses |
| **TGI** | `--max-concurrent-requests` (default 128) | `--max-total-tokens` | Prefix caching not reported | Prometheus on its own port | Refuses past the limit ("refuse clients requests instead of having them wait"). **TGI is in maintenance mode**; the docs recommend vLLM, SGLang or llama.cpp |
| **Ollama** | `OLLAMA_NUM_PARALLEL` (default 1), not exposed over HTTP | `/api/ps` `context_length` per loaded model (the parallel count multiplies it: "2K context with 4 parallel requests ... becomes 8K") | One conversation per parallel slot while the model is loaded; `/api/ps` `expires_at` is the warm window (`keep_alive`) | none | `OLLAMA_MAX_QUEUE` (default 512), then **503** |
| **LM Studio** | "Max Concurrent Predictions" (0.4.0+, default 4, llama.cpp continuous batching; MLX from 0.4.2), set at model load, **not exposed in the REST docs** | `/api/v0/models` `max_context_length`, `loaded_context_length` | not reported | not reported | Queues |

Sources: llama.cpp `tools/server/README.md` (https://github.com/ggml-org/llama.cpp/blob/master/tools/server/README.md); vLLM metrics (https://docs.vllm.ai/en/latest/usage/metrics.html) and engine args (https://docs.vllm.ai/en/latest/configuration/engine_args.html); the "Maximum concurrency" log line from vLLM's forum (https://discuss.vllm.ai/t/some-questions-about-maximum-concurrency/1145), a secondary source; SGLang server arguments (https://docs.sglang.io/advanced_features/server_arguments.html) and production metrics (https://docs.sglang.io/references/production_metrics.html); TGI launcher (https://huggingface.co/docs/text-generation-inference/reference/launcher) and index (maintenance notice); Ollama FAQ (https://docs.ollama.com/faq) and `/api/ps` (https://docs.ollama.com/api/ps); LM Studio 0.4.0 (https://lmstudio.ai/blog/0.4.0), parallel requests (https://lmstudio.ai/docs/app/advanced/parallel-requests) and REST v0 (https://lmstudio.ai/docs/developer/rest/endpoints). Not verified: whether llama.cpp's `/metrics` has a KV usage gauge (the README's list does not show one), and whether vLLM exposes `max_num_seqs` anywhere over HTTP.

### 3.1 Cloud providers: the equivalent signal is the rate limit

| Provider | Signal | Notes |
| --- | --- | --- |
| Anthropic | `anthropic-ratelimit-{requests,tokens,input-tokens,output-tokens}-{limit,remaining,reset}`, `retry-after` on 429 | ITPM counts only uncached input (`cache_read_input_tokens` do not count). There is also a **ramp limit** (429 `ramp_limit_exceeded`) after a sharp increase, and "a burst of requests within a few seconds can also count". The spend-cap 429 has no `retry-after`. https://platform.claude.com/docs/en/api/rate-limits |
| OpenAI | `x-ratelimit-{limit,remaining,reset}-{requests,tokens}`, plus `-project-tokens` variants | https://developers.openai.com/api/docs/guides/rate-limits |
| Bedrock | Service Quotas per model (TPM, RPM), read by #837's optional `ListServiceQuotas` check; a 0 quota is a warning before the first request | No per-response headers; throttling is a `ThrottlingException` |

Concurrency is not a cloud limit. Tokens per minute are. Three agents each reading 200K of **cached** context cost almost no ITPM on Anthropic. Three agents each **writing** 200K (fresh subagents, cold caches) cost 600K ITPM in a burst and can trip the ramp limit. So the cloud budget is better expressed as "uncached input tokens per minute remaining", read from the last response's headers.

## 4. Turning signals into numbers

Let `S` = running slots, `P` = park slots, `B` = park budget in bytes, `T` = typical conversation size in tokens (the session's own `lastInputTokens`, `SessionPromptCache` at `core/index.d.ts:337`), `k` = bytes per parked token, `c` = fixed bytes per snapshot, `R` = cold prefill rate (tok/s).

- **Concurrent requests without queueing:** `S`.
- **Conversations kept warm:** `S + min(P, floor(B / (k*T + c)))`. Strata gives `P` and `B` directly. `k` and `c` can be learned from `bytes / parked` after a few parks, which is better than a constant: the owner's server measured `k` ≈ 16 KB and `c` ≈ 0.6 GiB, and other models and KV types (`--kv int8`) differ. For llama.cpp: `S` plus an unknown share of `--cache-ram`, so report "likely warm" only. For vLLM and SGLang: `(1 - kv_cache_usage_perc) * KV tokens / T` is an upper bound; prefix hits after the fact are the only proof.
- **Agents that can work without thrashing:** `S + P_eff - 1`, where `P_eff` is the warm count above and **the 1 is the foreground conversation**, which must stay warm. Above that, every switch evicts someone.
- **Cost of queueing:** the queued request waits for the running one's remaining decode. On a one-slot server with parking, three agents at 120K finish a round in about 6 s (section 2.3), so queueing is cheap when everyone stays parked.
- **Cost of eviction:** `T / R`. On the owner's server about 24 s at 120K, 50 s at 250K and 80 s at 400K, against about 1 s to restore. On a cloud provider it is the cache write: `missExtraUsd` (`gui/src/util/cacheSafeguards.ts:64`) and `formatRereadCost` (`gui/src/util/cacheNotices.ts:40`) already compute it.

## 5. Our code today

| Where | What it does | Adapts to the provider? |
| --- | --- | --- |
| `core/subagents/scheduling.ts:7` | `MAX_CONCURRENT_SUBAGENTS = 3`; the tool description tells the model "at most 3 at a time" (`core/tools/definitions/subagent.ts:31`) | No |
| `gui/src/util/subagents/registry.ts:17`, `:20-37` | One window-wide semaphore of 3; one semaphore per `apiBase` and limit (`subagentServerSlots`) | Yes, slots only |
| `gui/src/util/subagents/runSubagent.ts:278-307` | `acquireSubagentSlots`: the global slot, then one server slot held **for the whole run**, from `models/serverConcurrency` | Yes. On a one-slot server, runs are serialized whole |
| `core/core.ts:560-565`, `core/llm/localServers.ts:591-626` | `serverConcurrency`: Strata `concurrency.serving`, else llama.cpp `total_slots`; **two GETs per call, no cache** | Yes, slots only; nothing for vLLM, Ollama, LM Studio |
| `gui/src/util/subagents/runLoopItemSubagent.ts:279` | Loop wave workers take the same slots | Yes, as above |
| `core/util/loopMode.ts:904-905`, `:962-969` | `LOOP_MAX_PARALLEL = 3` items per wave; the wave is chosen without asking the server, then workers wait on the semaphore with their worktrees already created | No |
| `extensions/cli/src/subagent/executor.ts:147-199` | CLI subagents always one at a time (services swap), with Strata named as a reason | Fixed at 1 |
| `extensions/cli/src/loop/loopWave.ts:331` | `startWave` starts a worker **process** per item at once; nothing asks the server | **No**: three CLI workers on a one-slot Strata interleave and, past 4 parked, evict |
| `core/llm/localServers.ts:656-700`, `core/autocomplete/CompletionProvider.ts:233` | `serverBusyElsewhere`: Tab skips a request when every `/slots` entry `is_processing` | Yes (Tab only) |
| `gui/src/util/promptCache.ts:221-250`, `gui/src/util/localWarmWindow.ts:22` | Local cache treated as warm for a fixed 15 minutes (`LOCAL_CACHE_WARM_MS`); Ollama uses its `keep_alive` | Guess, not a reading |
| `extensions/cli/src/contextManagement.ts:13-23` | `requestBodyHints` can send `strata_checkpoint: false` on one-shot requests, by config only | Configured, not detected |
| `core/llm/utils/retryPolicy.ts:34`, `gui/src/util/transientFailure.ts:31-36` | 429/503/529 retried, then shown as "rate limited" or "overloaded" with a wait | Reacts, never prevents |
| rate-limit headers | No code reads `anthropic-ratelimit-*` or `x-ratelimit-*` (searched `core`, `gui/src`, `extensions/cli/src`, `packages/openai-adapters/src`) | No |

**How an overloaded local server surfaces today.** Strata and llama.cpp by default **queue** without limit, so overload looks like a slow first token, not an error. The GUI shows the prompt progress (`return_progress`, `core/llm/index.ts:1465`) once the request is admitted, but nothing while it waits. An eviction looks the same as a cold start: the "reading N tokens" progress, with no reason given. Errors only come with an explicit `max_queue` (Strata 429 `admission_full`) or `OLLAMA_MAX_QUEUE` (503). Both go through the retry policy and then the transient-failure banner, which says "rate limited" for a local server. That wording is wrong for a queue.

## 6. Design

### 6.1 Capacity probe (core)

`serverCapacity(model)` in `core/llm/localServers.ts`, replacing `serverConcurrency` (kept as a wrapper):

```ts
interface ServerCapacity {
  source: "strata" | "llamacpp" | "ollama" | "vllm" | "sglang" | "lmstudio" | "unknown";
  serving?: number;          // running at once
  parkSlots?: number;        // Strata conversation_cache.slots
  parkBudgetMiB?: number;    // Strata conversation_cache.budget_mib
  parked?: number; parkedBytes?: number; evictions?: number;
  queued?: number;           // in_flight - running, requests_deferred, num_requests_waiting
  bytesPerToken?: number;    // learned: parkedBytes / parked tokens over time
  at: number;                // when read
}
```

- **Which servers:** only the `apiBase` of a model that is selected for chat or used by a subagent or loop item, and only when `isLocalApiBase` (or a configured LAN host). Never a scan.
- **Requests:** Strata `GET /v1/status` (which identifies it) then `GET /metrics`; llama.cpp `GET /props` and `GET /slots`; Ollama `GET /api/ps`; vLLM and SGLang `GET /metrics` only if a cheap HEAD/GET shows Prometheus text. Timeout 2 s. API key sent as today.
- **Cache:** 60 s per `apiBase` for the static part (`serving`, `parkSlots`, budget), 2 s for the live part (`queued`, `parked`), the same pattern as `busyAnswers` (`localServers.ts:630-700`). Invalidate on a model or server restart (Strata `started` in `/v1/status`).
- **Setting:** under "Model information updates" (`readModelCatalogSettings`, `core/llm/modelCatalogStore.ts:261`). `off` turns the probe off and falls back to today's fixed limits. Local GETs are not a network disclosure, so `automatic` and `manual` both allow them.
- **Strata's model loads on first request:** `/v1/status` and `/metrics` answer while unloaded (`loaded: false`), and the probe must never `POST`. `conversation_slots()` reads the slot count from the engine's arguments before it starts (`serve/server.py:847-857`), so `parkSlots` is known even when the engine is unloaded. The budget can be `null` until the engine sizes it.

### 6.2 Concurrency budget

```
agents      = min(userMax, serving + warmParkable - 1)      // at least 1
warmParkable = parkSlots, reduced to floor(budget / (k*T + c)) when T is known
inFlight    = serving   // requests this client sends at once to that server
```

- **Hold a server slot per request, not per run.** Today a subagent holds its server slot for the whole run (`runSubagent.ts:293-297`), so on a one-slot Strata the second subagent waits for the first to finish entirely. With parking, several agents can be **live** while their **requests** queue one at a time at the server: the GPU stays busy while another agent runs tools. Change `acquireSubagentSlots` to take the agent slot (budget `agents`) per run and the server slot (`serving`) per model request. This is the same change the owner's simultaneous test measured (6.2 s per round).
- **When `warmParkable` is unknown** (llama.cpp, vLLM, Ollama): `agents = min(userMax, serving)`. That is today's behaviour, plus the per-request change only when `serving > 1`.
- **Waves:** `parallelWave` takes `agents` instead of `LOOP_MAX_PARALLEL` (`loopMode.ts:969`), so no worktree is created for a worker that would only wait. The CLI `startWave` gets the same number through the loop state, and its worker processes take a cross-process server slot. For a first slice, the CLI can cap the wave at `agents` and run the rest as the next wave.
- **The model's instructions:** the subagent tool description states the real number ("at most N at a time"). It is part of the tools block, so it changes the prompt-cache prefix. Compute it once per session and model, not per probe, as `subagent-sessions-phase2.md` R3(c) already warns for a similar change.

### 6.3 Budget of 1

When `agents = 1` (a one-slot server with parking off or `P <= 1`, or Ollama at `OLLAMA_NUM_PARALLEL=1`):

- Subagents **stay enabled** and run one after another. The tool description says "subagents run one at a time on this server". The card's queued row says "waiting: this server runs one conversation at a time and keeps no other warm; running now would make it read the parent's 180K tokens again (about 40 s)".
- Loop parallel waves are offered but run inline, with that reason (`inlineInsteadOfWave`, `loopMode.ts:995`).
- Disabling subagents is not recommended: a subagent's main value is keeping tool output out of the parent's context, and that holds even sequentially. The real cost is that the parent's cache is evicted by the subagent's prompt. That is solved by parking, not by disabling.

### 6.4 Adaptive back-off

Signals, cheapest first: our own count of requests in flight to that `apiBase`; `queued` from the 2 s probe; a first token slower than `max(10 s, 3 x median for this prompt size)`; a 429/503 from a local server; an eviction (Strata `evictions` grew while our request was waiting, or `reused` in the response's `prompt_tokens_details.cached_tokens` fell to near 0 for a conversation that was warm).

Rules: on a queue that grows beyond `serving` for 2 probes, or a 429/503, lower `agents` by one (minimum 1). After 5 minutes without either, raise it by one up to the budget. An eviction of **our** foreground conversation drops `agents` to `serving` for the rest of the session and shows one line ("Strata evicted this chat's cache while subagents ran; subagents now run one at a time"). The transient-failure text for a local server says "the server is busy" and not "rate limited".

### 6.5 Per-provider session limits (cloud)

- Read `anthropic-ratelimit-input-tokens-remaining`/`-reset` and `x-ratelimit-remaining-tokens`/`-reset-tokens` from each response in the adapters, and keep the last value per provider and model in core (no persistence).
- Before starting N fresh subagents (each a cold write of its prompt), check `N x estimated prompt tokens <= remaining x 0.8`. If not, start fewer and stagger the rest, which `PrefixGate` already does for siblings with one prefix (`core/subagents/scheduling.ts`, `PREFIX_WAIT_MS` at line 13).
- Bedrock: use #837's quota reading as the static limit. Without headers there is no "remaining", so only back off on `ThrottlingException`.
- A user setting "Max agents at once" per model (`models[].capabilities` or a session setting) caps everything. The default stays 3 for cloud models.

### 6.6 Parked-conversation estimate in the UI

In the context and cache popover (`gui/src/components/mainInput/ContextStatus.tsx:134`), for a local model with a probe:

- "Strata: 1 running, 3 of 4 parked (11.2 of 24 GiB). This chat is parked: resuming takes about 1 s; if evicted, about 50 s."
- llama.cpp / Ollama / vLLM: "N slots; warm conversations not reported. Assumed warm for 15 min" (today's guess, labelled as a guess).
- An agents-panel header line when a budget below the user's setting is in force: "Running 2 at once: Strata keeps 4 conversations warm and this chat is one of them."

## 7. Parked conversations in the session lifecycle

The owner's direction: parking is not a new kind of session. It describes **where a paused session's prefix lives on the server**, and it decorates the states we already have.

### 7.1 States we already have or are designing

| State | Where | What resumes it |
| --- | --- | --- |
| Turn stopped, failed or cut off by a reload | #831 (2.16.2): `resumeTurn` (`gui/src/redux/thunks/resumeTurn.ts:18-28`), `ResumeResponse.tsx` | Resume: keep a partial answer and ask the model to go on, or resend the message |
| Session idle between turns | the chat | the next message |
| Agents panel: Active / Done / Archived | #816 (`AgentsList.tsx`) | opening the session |
| Subagent run stopped, interrupted, completed or failed, with a transcript | `subagent-sessions-phase2.md` (#820) 4.3 | `resumeSubagentRun`, by the person or the parent model |
| Fork of a session at a point | `session-forking-and-cache.md` (#830) | a new session sharing the prefix |
| Selective compaction, with an undo window | #851 | Undo restores the pre-compaction history, whose prefix may still be warm |

### 7.2 The model: run state x cache state

A session (or subagent run) has a **run state**: `running`, `queued` (waiting for a server slot or the agents budget), or `paused` (anything not running: idle, stopped, failed, interrupted, done). A paused session also has a **cache state** for its last prefix on its model's server:

- `warm`: in a running slot, or the cloud TTL has not passed.
- `parked`: in the server's park cache (Strata), or in a llama.cpp slot file saved by Park. Cheap to resume.
- `cold`: known evicted (Strata `evictions` grew past it, a `reused` near 0 seen, TTL passed, the model unloaded or the server restarted). Resume reads the whole prompt again.
- `unknown`: no signal (vLLM, LM Studio, a reloaded window with no probe). Shown as "likely warm" only within the 15-minute guess.

```
                         send / Resume (#831) / resumeSubagentRun (#820)
                 +---------------------------------------------------------+
                 |                                                         |
                 v           slot free                                     |
  +--------+  budget/slot  +---------+  request ends   +----------------------------------+
  | queued | ------------> | running | --------------> | paused                           |
  +--------+               +---------+  stop/fail/     |                                  |
      ^                       |   ^     reload/done    |  warm --(other conv runs)--> parked
      |  budget full          |   |                    |   |  (Strata: implicit, LRU)    |  |
      +-----------------------+   |                    |   |  (llama.cpp: explicit Park) |  |
         (never the foreground)   |                    |   |                             |  |
                                  |                    |   +--(TTL passes / evicted /    |  |
                                  |                    |   |   unload / restart)--> cold <+  |
                                  |                    |   |                       ^      |  |
                                  |                    |   +--(no signal)--> unknown      |  |
                                  |                    |                                  |  |
                                  |                    |  parked --(Unpark/restore)--> warm  |
                                  |                    +----------------------------------+
                                  |                                    |
                                  +---- Resume: preview cost by cache state, then send ----+
                                        warm/parked: ~1 s or cache-read $
                                        cold: T/R s (local) or write $ (cloud)
```

Fork (#830) creates a new paused session whose cache state is inherited from the fork point. Selective compaction (#851) makes the session's next prefix cold from the first removed message onward, and Undo within the window returns to the old prefix's cache state (warm or parked if it has not been evicted yet).

### 7.3 Park and Unpark

| Provider | Park | Unpark | Badge confidence |
| --- | --- | --- | --- |
| Strata | **Implicit**: the server parks the previous conversation when another one runs; no API to request it. We cannot pin it either | Implicit on the next request (restore ~1 s) | High: `conversation_cache.parked` and `evictions`, plus `reused` on the next response |
| llama.cpp with `--slot-save-path` | **Explicit**: `POST /slots/{id}?action=save {filename}` writes the slot to disk | `action=restore` before the next request, into a free slot | High for the file; the restore is only valid for the same model and build |
| llama.cpp without it | Implicit (`--cache-ram`) | Implicit | Low: not reported, "likely warm" |
| Strata with `--slot-save-path` | Explicit, as llama.cpp, but **only from Strata's own page or a trusted origin** (`serve/server.py:7434`), so the extension must be listed in `trusted_origins` or send no Origin. One slot (0) only | `action=restore` | High |
| vLLM, SGLang | Not possible; prefix cache is automatic | Implicit | Low: "likely warm" while `kv_cache_usage_perc` is low and the prefix hit rate is high |
| Ollama | Not possible; one context per parallel slot while loaded | Implicit | Medium: warm only if the same model is still loaded (`/api/ps` `expires_at`) and no other conversation used that slot |
| Anthropic, Bedrock, OpenAI | Implicit: the TTL window is the park (5 min or 1 h) | Implicit | High within the TTL (the existing `promptCacheStatus`) |

**Keep-warm is not recommended.** On Anthropic a 1-token request that reads a 200K prefix to refresh the TTL costs a cache read of 200K tokens every 5 minutes: about $0.04 on Claude Opus 5.5, or about $0.48 an hour, to save one cold write of about $1.00 (both figures from `session-forking-and-cache.md` section 1). It pays only if the person resumes within about 2 hours, and we cannot know that. The 1-hour TTL, which Auto already escalates to (`cacheSafeguards.ts:243-249`), is the cheaper form. On a local server keep-warm is pointless: parking is free, and a keep-warm request would itself evict another conversation.

**Explicit Park in the UI** is offered only where it does something: llama.cpp (and Strata) with a slot save path. It appears as "Park on server" on a paused session's menu, and runs automatically when the person switches away from a session on such a server, if they opt in. Everywhere else the badge just reports the implicit state.

### 7.4 The scheduler and eviction

- **Running sessions count against `serving`; paused warm or parked sessions count against `parkSlots`/budget.** Our client only knows its own sessions. Other clients on the same server show up only in `parked` and `evictions` (section 9).
- When starting a new agent would exceed `serving + parkSlots - 1`, **queue it** (it is shown `queued` with "waiting: starting now would push <session> out of Strata's cache"). Strata evicts LRU, so the session most at risk is the least recently used paused session. That is never the foreground (it ran last), but it may be a paused subagent the person will resume.
- **Our own order, where we have a choice:** the foreground chat is never evicted by our scheduler. Paused subagent runs that are Done and not resumed in 5 minutes are the first to go. Stopped or interrupted runs (likely to be resumed) go after them. Archived sessions (#816) always count as cold and take no budget.
- **The person can override:** "Run now anyway" on a queued agent, with the preview "will make <session> read 180K tokens again next time (about 40 s)".

### 7.5 Resume

Resume keeps #831's and #820's semantics exactly. Two things are added:

1. **A cost and latency preview** on the Resume button and the session badge, from the cache state:
   - local warm or parked: "Resume (about 1 s)";
   - local cold: "Resume: reads 250K tokens again (about 50 s)" from `T / R`, with `R` learned from this server's `prompt_tokens`/time on cold reads (Strata's `last_timings`, llama.cpp `timings.prompt_per_second`);
   - cloud warm: unchanged; cloud cold: the existing `coldResume` text (`cacheSafeguards.ts:229`, `formatRereadCost`).
2. **An optional restore step** before sending, only where Park was explicit (a llama.cpp or Strata slot file): `action=restore`, then the normal send. If the restore fails (other model, other build, no free slot), the send goes ahead cold, and the badge says so.

## 8. Phased plan

| Phase | Scope | Size | Depends on | Done when |
| --- | --- | --- | --- | --- |
| **P1 (first slice)** | `serverCapacity` probe (Strata, llama.cpp, Ollama), 60 s cache, under "Model information updates"; `agents = min(userMax, serving + parkSlots - 1)`; GUI subagents hold a **server slot per request**, the agent slot per run; `parallelWave` and CLI `startWave` capped at `agents`; one-line reason when the budget is 1; the local 429/503 wording ("server is busy"). Capture one live `/v1/status` and `/metrics` payload from the owner's Strata as a test fixture | M | none | 3 GUI subagents on a one-slot, 4-park Strata interleave without eviction (`reused` > 90% on every turn after the first); 3 CLI wave workers on the same server do not start more than `agents`; `off` restores today's limits |
| P2 | Cache-state badge (`warm`/`parked`/`cold`/`unknown`) on the session, the agents panel rows (#816) and the context popover; parked estimate line; Resume preview (local seconds, cloud $) | M | P1, #816 | The badge matches Strata's `parked`/`evictions` in a scripted alternating run; Resume shows seconds for local and $ for cloud |
| P3 | Adaptive back-off: queue growth, slow first token, local 429/503, own-eviction detection from `reused` | S-M | P1 | A second client saturating the server lowers our `agents` within 2 probes and raises it 5 minutes after |
| P4 | Cloud: read `anthropic-ratelimit-*` / `x-ratelimit-*`; stagger fresh subagents when uncached ITPM would run out; Bedrock from #837 | M | P1 | No 429 in a 5-subagent burst at Start tier on a 200K prompt; headers absent means today's behaviour |
| P5 | Explicit Park/Unpark for llama.cpp `--slot-save-path` (and Strata if its origin check allows); restore step on Resume | M | P2 | A parked llama.cpp session resumes with `n_restored` = its prompt and a near-zero read |
| P6 | Subagent tool description states the real N, computed once per session and model | S | P1 | The prefix hash changes at most once per session |

## 9. Risks

| Risk | Effect | Mitigation |
| --- | --- | --- |
| **Signals missing** (vLLM `max_num_seqs`, LM Studio's concurrency, llama.cpp's `--cache-ram` occupancy, Ollama's `NUM_PARALLEL`) | Budget falls back to slots or the fixed 3 | `source` and confidence carried in `ServerCapacity`; "unknown" shown as such; user setting wins |
| **Signals misleading**: Strata's `parked`/`evictions` are parsed from the engine log (`ConvCacheLog`), reset at engine restart, and read only the last 1 MiB of new lines | Under-counts after a burst of log lines; counts reset | Treat `evictions` as a delta between probes; confirm with `reused` on our own next response |
| **Park capacity in slots is not the binding limit** at long contexts (4 slots but only 2 conversations of 500K fit in 24 GiB), and the RAM floor can refuse a park | Estimate too high | Use `budget / (k*T + c)` with learned `k`, `c`; `bytes` near `budget` caps the estimate |
| **Multiple clients on one server** (the owner runs Cline and Claude Code against the same Strata; the IDE and the CLI are two clients) | Our budget assumes we own the parks; another client's turns evict ours | Count `parked - ours` as foreign; a foreign eviction triggers P3's back-off; say "another client is using this server" when `in_flight` exceeds our own count |
| **Probe cost and privacy** | A GET every 2 s while agents run | Only while agents run on that server; 60 s otherwise; loopback only by default |
| **Batch slots look like capacity but are slower** on this hardware (section 2.3) | A user who turns on `"parallel": 3` gets a higher budget and slower agents | The budget uses `serving + parkSlots`, so parking already gives 3 agents on 1 slot; document the measurement next to the setting |
| **Prefix change from a dynamic N in the tool description** | One cache miss per change | P6: fixed per session |
| **`strata_checkpoint: false` not sent by the GUI** | GUI side requests (titles, compaction) can evict a parked agent below the min-tokens floor | Detect Strata and send it on one-shot requests in both hosts (an owner decision, OD-6) |

## 10. Owner decisions

| # | Decision | Recommendation |
| --- | --- | --- |
| OD-1 | Budget formula: `serving` only (today), or `serving + parkSlots - 1` | **`serving + parkSlots - 1`, capped by the user's setting.** The owner's measurement shows parking beats slots on this server |
| OD-2 | Server slot held per run (today) or per request | **Per request** when the server parks; per run when it does not (llama.cpp without a reported park, Ollama) |
| OD-3 | When the budget is 1: disable subagents, or run them one at a time | **Run one at a time with a stated reason.** Their value (a clean parent context) does not depend on parallelism |
| OD-4 | Probe under "Model information updates", or its own setting | **Under it**; `off` turns the probe off. No new setting |
| OD-5 | CLI waves: cap at `agents` now (P1), or a cross-process server slot later | **Cap now**, cross-process slots only if waves on local servers become common |
| OD-6 | Send `strata_checkpoint: false` on one-shot requests automatically when Strata is detected | **Yes**, in both hosts; today it needs config |
| OD-7 | Explicit Park/Unpark (P5) | **Build only for llama.cpp `--slot-save-path`**, opt-in. Strata parks by itself, and its slot endpoint is origin-gated |
| OD-8 | Keep-warm requests for cloud caches | **No.** Prefer the 1-hour TTL (Auto already escalates); show the cold-resume cost instead |
| OD-9 | Eviction order of our own paused sessions | **Done subagents first, then stopped/interrupted, never the foreground; archived count as cold** |
| OD-10 | Cloud: stagger subagents by the rate-limit headers (P4) | **Yes for Anthropic and OpenAI**; Bedrock uses #837's quotas and back-off only |
| OD-11 | Badge states shown to the person | **`warm`, `parked`, `cold`, and `unknown` labelled "likely warm" only within 15 min**; no badge for cloud sessions inside the TTL beyond today's cache indicator |

## 11. Not verified

- No live payload from the owner's Strata (it was not running). The field names are from `serve/server.py` at `c62d5e3a`. The running build may differ.
- llama.cpp: whether `/metrics` has a KV-usage gauge, and how `-c` is split across slots with `--kv-unified`. The README fetched does not say.
- vLLM: whether `max_num_seqs` and the KV token capacity are exposed over HTTP. Only the startup log line was found, through a forum source.
- LM Studio: whether "Max Concurrent Predictions" is readable over the REST API.
- The 6.2 s vs 13.4 s and 1.14 s figures are from the owner's notes (2026-11-01), not re-run here.
