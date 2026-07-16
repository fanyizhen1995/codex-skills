---
source_id: sglang-github-closed-issues-prs
title: '[Feature][RFC] SPECTRE: Parallel Speculative Decoding with a Multi-Tenant
  Remote Drafter'
canonical_url: https://github.com/sgl-project/sglang/issues/22044
captured_at: '2026-07-12T23:38:53.048873+00:00'
content_hash: a26b54751b49a302ed91746683006ebae264e92f029ca6d68efc95d8c9ebe51b
---
# [Feature][RFC] SPECTRE: Parallel Speculative Decoding with a Multi-Tenant Remote Drafter

URL: https://github.com/sgl-project/sglang/issues/22044
State: closed
Labels: inactive
Closed at: 2026-07-12T00:35:42Z
Merged at: 

### Checklist

- [x] If this is not a feature request but a general question, please start a discussion at https://github.com/sgl-project/sglang/discussions. Otherwise, it will be closed.
- [x] Please use English. Otherwise, it will be closed.

### Motivation

We propose SPECTRE (Parallel **Spec**ulative Decoding with a Multi-**T**enant **Re**mote Drafter), a novel system architecture for Speculative Decoding in SGLang , inspired by recent parallel speculative-decoding efforts such as [Pearl](https://arxiv.org/abs/2408.11850) and [SSD](https://arxiv.org/abs/2603.03251). By decoupling the tightly-bound Drafter and Verifier into independent, asynchronously communicating SGLang services (via ZMQ), SPECTRE resolves the high sequential latency and poor resource utilization of traditional implementations through two core features:

**Cross-Round Parallel Overlap**: Breaking the strict, synchronous "draft-then-verify" loop that leads to low GPU utilization, SPECTRE employs optimistic concurrency control. Assuming high draft acceptance, the Drafter generates tokens for round k+1 concurrently while the Verifier validates round k. This completely overlaps the forward passes of both models and effectively hides drafting latency.

**Drafter Dual-Mode Coexistence**: Instead of dedicating an underutilized GPU solely to the Drafter, SPECTRE treats it as a multi-tenant service. It processes internal draft requests from the Verifier alongside its own standalone user traffic within the same continuous forward batch. This maximizes GPU utilization and drastically lowers the serving cost for production environments.

**paper link**: (https://arxiv.org/pdf/2605.08151)

## Architecture Overview

To break free from this co-located synchronous trap, SPECTRE shifts speculative decoding into a **distributed, asynchronously coordinated pipeline**.

SPECTRE keeps both sides operationally familiar:

- The **Verifier** is a standard SGLang HTTP server that handles user requests and performs token verification with the large model. It acts as the authoritative serving endpoint.
- The **Drafter** is also a standard SGLang HTTP server. However, operating in **Dual-Mode**, it accepts remote draft-generation requests from the Verifier *in addition* to serving its own standalone traffic. Both traffic streams are mixed into the same GPU batch.
- The two sides communicate over **ZMQ**, with messages serialized as `SpectreRequest` objects through a C++ pybind11 transport layer.

![Image](https://github.com/user-attachments/assets/36f76fc6-df8d-431e-a47c-4c46ee6a8220)

As shown in the image above, SPECTRE can achieve overlap between the verifier and drafter computation results. Furthermore, drafter can simultaneously support the computation of both verifier requests and normal requests.


---

## Implementation Footprint

SPECTRE is implemented against SGLang `0.5.10rc0`. Most new code is isolated under `python/sglang/srt/speculative/spectre/`, with only a small set of integration points in the existing serving stack.

```text
python/sglang/srt/speculative/spectre/
|
|- spectre_protocol.py              # SpectreRequest, SpectreAction, SpecType
|- spectre_communication.py         # SpectreConfig, SpectreZMQCommunicator
|
|- verifier/
|  |- spectre_target_scheduler_mixin.py   # SpectreTargetSchedulerMixin, DraftCircuitBreaker
|  `- spectre_worker.py                   # SpectreWorker
|
|- drafter/
|  |- spectre_draft_scheduler_mixin.py    # SpectreDraftSchedulerMixin
|  |- spectre_state_manager.py            # SpectreDraftState, SpectreDraftStateManager
|  `- spectre_kv_rollbacker.py            # SpectreKVRollbacker
|
`- cpp_zmq/
   |- src/
   |  |- spectre_zmq.cpp
   |  `- spectre_zmq_serialization.cpp
   `- setup.py
```

### Main integration points in the existing codebase

```text
srt/server_args.py
    spectre_* CLI arguments and ServerArgs fields

srt/speculative/spec_info.py
    SPECTRE detection, worker import, and routing to the SPECTRE event loop

srt/managers/scheduler.py
    scheduler mixin integration, init_spectre_communication(),
    event_loop_normal_spectre_draft/target(), and state reset on flush

srt/model_executor/cuda_graph_runner.py
    spectre_ntpb_options for CUDA graph batch-size variants
```

The C++ ZMQ extension is built once before launch:

```bash
bash python/sglang/srt/speculative/spectre/cpp_zmq/scripts/build_cpp_zmq.sh
```

---


## Protocol Design

All communication uses a `SpectreRequest` dataclass serialized through msgpack via the C++ ZMQ layer.

### Key fields


| Field              | Type            | Description                                                                                  |
| ------------------ | --------------- | -------------------------------------------------------------------------------------------- |
| `request_id`       | `str`           | SGLang request ID (`req.rid`)                                                                |
| `spec_cnt`         | `int`           | Per-request speculative round counter used to correlate messages and discard stale responses |
| `action`           | `SpectreAction` | `DRAFT`, `FINISH`, `ABORT`, or `REJECT`                                                      |
| `spec_type`        | `SpecType`      | `DRAFT_REQUEST` or `DRAFT_RESPONSE`                                                          |
| `draft_token_ids`  | `List[int]`     | Draft tokens proposed by the Drafter                                                         |
| `input_ids`        | `List[int]`     | Full prompt token IDs, sent on `spec_cnt == 0`                                               |
| `output_ids`       | `List[int]`     | Tokens generated so far                                                                      |
| `num_draft_tokens` | `int`           | Number of draft tokens requested by the Verifier                                             |


### Action semantics


| `SpectreAction` | Direction                                   | Meaning                                             |
| --------------- | ------------------------------------------- | --------------------------------------------------- |
| `DRAFT`         | Verifier -> Drafter and Drafter -> Verifier | Normal draft request / response                     |
| `FINISH`        | Verifier -> Drafter                         | Request completed normally; Drafter cleans up state |
| `ABORT`         | Verifier -> Drafter                         | Request aborted; Drafter cleans up state            |
| `REJECT`        | Drafter -> Verifier                         | Drafter is overloaded; Verifier should back off     |


---

## Transport Layer

### ZMQ transport selection

`SpectreConfig` chooses the transport automatically based on `--spectre-zmq-addr`:


| `zmq-addr` value         | Transport | Rationale                                                             |
| ------------------------ | --------- | --------------------------------------------------------------------- |
| `127.0.0.1` or `0.0.0.0` | **IPC**   | Avoids unnecessary network stack overhead for same-machine deployment |
| Any other IP             | **TCP**   | Enables cross-machine communication                                   |


### Socket roles

The current design uses:

- **Verifier**: binds a **Router** socket
- **Drafter**: connects with a **Dealer** socket

This choice keeps the Verifier in a coordination role and makes it possible to extend toward one-to-many topologies, where a single Verifier can talk to multiple Drafter instances.

That matters because SPECTRE is intended to scale outward cleanly. The transport is not just point-to-point glue; it is the foundation for a future multi-drafter deployment model.

### C++ transport layer

SPECTRE uses a C++ pybind11 extension for ZMQ plus msgpack serialization. This keeps message handling predictable and efficient in the serving path, avoiding Python-level control flow overhead for every transport operation. The communication layer is kept thin, explicit, and production-friendly — it is not an additional infrastructure dependency but a narrow binding on top of well-established primitives.

---

## Scheduling, Fault Tolerance, and State Management

### Circuit breaker on the Verifier

The Verifier maintains a `DraftCircuitBreaker` so that Drafter failures do not stall user-visible generation.


| State       | Behavior                                                                                                              |
| ----------- | --------------------------------------------------------------------------------------------------------------------- |
| `CLOSED`    | Normal operation. Draft requests are sent every round.                                                                |
| `OPEN`      | Too many consecutive timeouts. The Verifier falls back to single-token decoding for `SPECTRE_COOLDOWN_ROUNDS` rounds. |
| `HALF_OPEN` | Cooldown expired. One probe request is sent. Success returns to `CLOSED`; failure reopens the breaker.                |


This gives SPECTRE a critical operational property: when remote drafting is unhealthy, the system degrades to standard autoregressive decoding instead of amplifying latency or deadlocking progress. SPECTRE accelerates the happy path without holding the serving stack hostage to the remote path.

### Drafter scheduling modes

Because draft tokens are highly time-sensitive, the Drafter exposes two scheduling strategies.

**Mixed mode** (default):

- Draft requests are merged into the Drafter's normal running batch.
- This maximizes overall GPU utilization.
- It works well when Drafter load is light or moderate.
- It offers no strong isolation, so under heavy load the Verifier may see occasional timeouts.

**Draft-Priority mode** (`--spectre-draft-priority`):

- The Drafter runs a dedicated draft batch for up to `--spectre-max-draft-priority-steps` steps before serving normal requests each iteration.
- This bounds draft latency more tightly.
- It protects Verifier throughput when the Drafter is busy.
- The trade-off is slightly higher tail latency for the Drafter's ordinary user traffic.

This mode split reflects an actual serving trade-off rather than hiding it: SPECTRE can optimize for utilization or for speculative responsiveness, depending on deployment goals.

---

## User-Facing API

### CLI arguments

#### Shared arguments


| Argument                   | Type  | Default | Description                                                           |
| -------------------------- | ----- | ------- | --------------------------------------------------------------------- |
| `--spectre-role`           | `str` | `None`  | `target` for the Verifier or `draft` for the Drafter                  |
| `--spectre-zmq-addr`       | `str` | `None`  | ZMQ address. `127.0.0.1` selects IPC automatically; other IPs use TCP |
| `--spectre-zmq-port`       | `str` | `None`  | ZMQ port used by both sides                                           |
| `--spectre-max-batch-size` | `int` | `32`    | Overload threshold for sending `REJECT`                               |


#### Verifier-side arguments


| Argument                         | Type    | Default | Description                                                                                 |
| -------------------------------- | ------- | ------- | ------------------------------------------------------------------------------------------- |
| `--speculative-algorithm`        | `str`   | `None`  | Must be `SPECTRE`                                                                           |
| `--speculative-num-steps`        | `int`   | `None`  | Draft tree depth                                                                            |
| `--speculative-num-draft-tokens` | `int`   | `None`  | Total draft tokens verified per round                                                       |
| `--spectre-reject-interval`      | `int`   | `500`   | Decode rounds to skip after a `REJECT` before retrying                                      |
| `--spectre-no-draft-ratio`       | `float` | `0.5`   | Fraction of requests without drafts that triggers batch fallback to autoregressive decoding |
| `--spectre-retry-fail-ratio`     | `float` | `0.5`   | Fraction of pre-verify failures required to trigger inline retry                            |
| `--spectre-retry-min-count`      | `int`   | `4`     | Minimum failed-request count required before retry logic activates                          |


#### Drafter-side arguments


| Argument                             | Type  | Default | Description                                                 |
| ------------------------------------ | ----- | ------- | ----------------------------------------------------------- |
| `--spectre-draft-priority`           | flag  | `False` | Enable draft-priority scheduling                            |
| `--spectre-max-draft-priority-steps` | `int` | `0`     | Maximum dedicated draft steps per iteration; `0` means auto |


### Environment variables


| Variable                        | Side     | Default | Description                                                     |
| ------------------------------- | -------- | ------- | --------------------------------------------------------------- |
| `SPECTRE_RECV_TIMEOUT_MS`       | Verifier | `200`   | Max time to wait for draft tokens on receive                    |
| `SPECTRE_FAILURE_THRESHOLD`     | Verifier | `30`    | Consecutive timeout rounds before opening the circuit breaker   |
| `SPECTRE_COOLDOWN_ROUNDS`       | Verifier | `100`   | Rounds to stay in `OPEN` before probing again                   |
| `SGLANG_DRAFT_CLEANUP_INTERVAL` | Drafter  | `500`   | Forward cycles between stale-state cleanup sweeps               |
| `SPECTRE_DEBUG`                 | Both     | `0`     | `1` enables info-level ZMQ logs; `2` enables per-message timing |


### Launch example

#### Step 1: Start the Drafter

```bash
python -m sglang.launch_server \
  --model-path /path/to/small-model \
  --tp 1 \
  --host 0.0.0.0 \
  --port 3008 \
  --spectre-role draft \
  --spectre-zmq-port 30090 \
  --spectre-draft-priority \
  --spectre-max-draft-priority-steps 5 \
  --spectre-max-batch-size 320 \
  --disable-overlap-schedule
```

#### Step 2: Start the Verifier

```bash
python -m sglang.launch_server \
  --model-path /path/to/large-model \
  --tp 1 \
  --host 0.0.0.0 \
  --port 30000 \
  --speculative-algorithm SPECTRE \
  --spectre-role target \
  --speculative-num-steps 3 \
  --speculative-eagle-topk 1 \
  --speculative-num-draft-tokens 4 \
  --spectre-zmq-addr 127.0.0.1 \
  --spectre-zmq-port 30090 \
  --spectre-max-batch-size 160 \
  --attention-backend fa3
```

For same-machine deployment, `127.0.0.1` selects IPC automatically. For cross-machine deployment, replace it with the Drafter's reachable IP and the transport switches to TCP.

---

## Performance

We compared Autodecode, Eagle3, StandAlone, and Pearl with Spectre on SGLang, and all showed certain performance gains.

<img width="4531" height="2666" alt="Image" src="https://github.com/user-attachments/assets/0ad977a9-c569-49c7-9e59-f02f088317ae" />

---

To reproduce our results：
### Dedicated traffic  
```bash
python3 -m sglang.bench_serving \
--backend sglang \
--dataset-name random \
--random-input-len 4000 \
--random-output-len 1000 \
--random-range-ratio 1 \
--request-rate 8 \
--max-concurrency 32 \
--num-prompts 128 \
```
Target model: `Qwen3-32B`  
Draft model: `Qwen3-0.6B`  
Eagle3 model: `Zhi-Create-Qwen3-32B-Eagle3`

| | Autodecode | Eagle3 | Standalone | Spectre |
|--|---------:|--------:|-----------:|----------:|
| Output token throughput (tok/s) | 715.97 | 925.88 | 992.00 | **1258.82** |
| Speedup | 1.00x | 1.29x | 1.38x | **1.76x** |


StandAlone:

<img width="816" height="1064" alt="Image" src="https://github.com/user-attachments/assets/e05a764d-8079-4061-81ac-02a556a792ff" />

Spectre:

<img width="800" height="1074" alt="Image" src="https://github.com/user-attachments/assets/dd4b201d-5384-4239-a918-85ecd27df4aa" />

### Mixed traffic in drafter

We sent bench serving to Verifier and Drafter(with Draft-Priority mode) respectively.

Verifier:
```bash
python3 -m sglang.bench_serving \
--backend sglang \
--dataset-name random \
--random-input-len 4000 \
--random-output-len 1000 \
--random-range-ratio 1 \
--request-rate 8 \
--max-concurrency 32 \
--num-prompts 128 \
```
Drafter:
```bash
python3 -m sglang.bench_serving \
--backend sglang \
--dataset-name random \
--random-input-len 1000 \
--random-output-len 1000 \
--random-range-ratio 1 \
--request-rate 32 \
--max-concurrency 8 \
--num-prompts 1000 \
```
|                                 | Autodecode | Eagle3 | Standalone | Spectre-verifier | 
| ------------------------------- | ---------- | ------- | ---------- | ---------------- | 
| Output token throughput (tok/s) | 715.97     | 925.88  | 992.00     | **1244.71**      |
| Speedup                         | 1.00x      | 1.29x   | 1.38x      | **1.74x**        |

|                                 | Origin-drafter | Spectre-drafter |
| ------------------------------- | ---------------|---------------  |
| Output token throughput (tok/s) |  3291.44       | 2869.87         |
| Speedup                         |  1.00x         | **0.87x**       |

The numbers support a system-level win (Verifier throughput up) at the cost of lower peak Drafter throughput—worth it if the goal is serving efficiency and end-user latency/throughput, not maximizing the draft worker’s standalone score.

---

## Reference
[PEARL: Parallel Speculative Decoding with Adaptive Draft Length](https://arxiv.org/abs/2408.11850)
[Speculative Speculative Decoding](https://arxiv.org/abs/2603.03251)

---

## Team
@feng397  @xq25478 @GoGoldenx @zhangfeiyu5610 
We welcome all interested developers to join us.

### Related resources

_No response_
