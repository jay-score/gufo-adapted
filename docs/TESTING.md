# Testing

Run the smallest check that covers the change. Correctness and model-owned
quality limits pass before performance results count. Production targets
Linux gfx1151. CMake/CTest work with either system dependencies or `nix develop`.

## Commands

```sh
# Formatting on the editing host, using CI's pinned formatter
nix shell --inputs-from . nixpkgs#clang-tools -c python3 tools/ci/check-format.py
# Add --fix to apply formatting.

# Documentation changes
nix build .#checks.x86_64-linux.docs

# Hosted CPU/repository checks
nix build .#checks.x86_64-linux.pr

# Focused test (replace the target and expression)
nix develop -c cmake --preset gpu-test
nix develop -c cmake --build --preset gpu-test --target minimax_h3_sampling_test
nix develop -c ctest --preset gpu-full -R '^minimax_h3_sampling_test$' --output-on-failure

# Host memory/undefined-behavior diagnostics
nix develop -c cmake --preset cpu-sanitizer
nix develop -c cmake --build --preset cpu-sanitizer
nix develop -c ctest --preset cpu-sanitizer --output-on-failure
```

Preset definitions, build options and repository mechanics are in
[development](DEVELOPMENT.md). Formatting and the Python
documentation/dependency checks run on the editing host without building Gufo;
their entrypoints are in `tools/ci/`.

Selection by preset: `gpu-fast` excludes `slow` and `external-model` tests,
`deepseek-gpu` and `qwen-gpu-kernel-oracle` select model/device suites, and
`gpu-full` covers the complete hardware tree. External-model tests require
their documented local artifacts. A skip due to an absent model or device is
not a quality pass.

## Hosted versus local checks

GitHub runs formatting, documentation, dependency-inventory and server-command
checks plus `cmake/Checks.cmake`: parsing, GGUF safety, sampling, templates,
server/cache/scheduler behavior, model configuration and small audio/video API
contracts. It builds only those test executables and the CPU CLI. It does not
build ROCm, download weights, run full H3 oracles or compile whole-tree clang-tidy.
The workflow cancels superseded runs and has a 25-minute limit.

```sh
# Same hosted C++/CLI selection locally
cmake --preset cpu-test
cmake --build --preset pr --parallel 4

# Full CPU suite, or explicit non-hosted tools
nix build .#checks.x86_64-linux.tests
nix build .#checks.x86_64-linux.static-analysis
nix build .#checks.x86_64-linux.h3-manifest
nix build .#checks.x86_64-linux.h3-quality
nix build .#checks.x86_64-linux.h3-ml-quality
```

Full CPU builds need Python NumPy for the offline tool tests. GPU model oracles
need the documented local weights; use focused targets and CTest labels before
running the complete tree. H3 development normally needs an analytic primitive,
one transformer block or one denoiser forward. Full video generation and LPIPS
are release/quality qualification, not routine PR work. `nix flake check` runs
all declared checks and is deliberately not the hosted CI command.

## Match validation to the change

| Change | Relevant checks |
| --- | --- |
| Documentation | local links, anchors, JSON examples |
| Loader/container/tokenizer | independent fixtures, malformed/truncated input, exact token IDs |
| Kernel or quantizer | analytic oracle, affected layer/model boundaries, declared quality limits |
| Attention or state layout | long-context boundaries, snapshot/restore, fresh-versus-reused state |
| Sampling/speculation | distributions, proposal/rejection/residual draws, seeded replay, EOS commit |
| Scheduler/server | direct-versus-HTTP behavior, independent batched requests, multi-turn reuse, cancellation, failure and shutdown |
| Performance | affected quality gates followed by one comparable release measurement |

Broaden testing when a change crosses shared ownership boundaries or a failure
reveals an unresolved risk. Full model sweeps, media generation, and repeated
timing runs are not the default development loop.

For a bounded real-model tool/parser check, run
[tool_parser_agent_check.py](../tests/tools/tool_parser_agent_check.py) against
an isolated text server with a 4096-token context, thinking disabled and matched
model/sampling/speculative settings:

```powershell
python tests/tools/tool_parser_agent_check.py --url http://127.0.0.1:18080 --out build/tool-parser-check
```

It exercises both APIs with literal markers, disabled tools, typed wildcard
arguments, multiline edits, Unicode history, repeated requests and required
call interruption/resume. A six-turn read/edit/verify/finish loop operates only
on its fixture file under the output directory. Exact requests/responses,
latency, usage and independently checked contents are retained. Model copying
failures remain failures; deterministic API fixtures establish parser contracts
independently. Compare baseline/candidate controls with identical cache histories
before interpreting timings; a single run does not qualify a performance gain.

For controlled whitespace/edit diagnostics, run
[tool_whitespace_diagnose.py](../tests/tools/tool_whitespace_diagnose.py) against
the same isolated server:

```powershell
python tests/tools/tool_whitespace_diagnose.py --url http://127.0.0.1:18080 --out build/tool-whitespace --case raw --case plain_raw --case plain_recovery_json --case escaped_recovery_json
```

The original `raw` case remains a control. Other cases change the replacement
text, JSON-encode read results, describe exact replacement semantics, or make
verification and correction explicit. Escaped cases encode literal angle
brackets in the JSON example inside the prompt; they do not change the expected
file bytes. Recovery cases allow corrective edits within the same six-turn cap.
All cases independently check the file; failures still exit 1. Select `--api`
to bound a run to one API. See the [diagnosis record](plans/tool-calling-followup.md)
for retained results and the separate Flash termination investigation.

Model-owned procedures and outstanding qualification gaps live with the model:

- [DeepSeek V4 Flash](models/deepseek-v4-flash/QUALITY.md)
- [Qwen3.8 27B](models/qwen3.8-27b/QUALITY.md)
- [Qwen3.8 Flash-Next](models/qwen3.8-flash-next/QUALITY.md)
- [MiniMax H3](models/minimax-h3/QUALITY.md)
- [Qwen3-TTS](models/qwen3-tts/QUALITY.md)
- [Qwen3-ASR](models/qwen3-asr/QUALITY.md)

## Independent references and artifacts

Prefer hand-checkable analytic fixtures or the source checkpoint in a pinned
official runtime. A promoted Gufo build is a regression reference; agreement
with it alone does not establish upstream correctness. Record checkpoint
storage type separately from compute and accumulation precision.

Unchanged-arithmetic refactors retain exact boundaries. Reassociated kernels
need declared numerical limits and model-level checks. Quantization is
evaluated against a full-quality teacher with distribution, perplexity, and
capability gates. Do not loosen tolerances or silently replace goldens to
admit a change.

Golden artifacts record immutable model and oracle revisions, file hashes,
tokenizer/template identity, prompt/token-stream hashes, dtypes, parameters,
and schema version. Large tensor/logit dumps stay outside Git. Keep small
independent fixtures and concise results needed to reproduce qualification;
see [benchmark artifact retention](BENCHMARKS.md).

## Matched-token and layer comparisons

HIP builds register `kernel_resources_test`, a GPU-independent check of the
compiled gfx1151 prefill kernels affected by clang-23 scratch regressions. It
reads ELF or Windows PE offload payloads, requires the production template
variants and rejects scratch or spilled registers. The focused contract covers
Qwen blocked Q8/K-quant GEMMs (including fused Q8 and wave64) and Flash-Next's
blocked Q8 and routed-F16 GEMMs; it is not an all-model scratch budget.
`kernel_resources_parser_test` also runs in the bounded CPU PR suite.

```sh
ctest --test-dir build/gpu-test -R '^kernel_resources_test$' --output-on-failure --no-tests=error
python tools/ci/check-kernel-resources.py build/release/gufo --report
```

On Windows use `gufo.exe` and pass `--bundler` with the matching compiler's
`clang-offload-bundler.exe` when compressed bundles require external extraction.
CTest selects that compiler-adjacent tool automatically. For Qwen27B numerical
comparison across short and throughput prefill dispatch, the explicit
`qwen27b_target_test MODEL --capture-prefill-logits OUTPUT` diagnostic records
complete logits after 8/9/64/95/96/129/2048-token prefixes and their continuations.
Compare baseline and candidate with identical artifacts and build settings.

Flash-Next's `qwen38_flash_next_session_test --model FIRST.gguf --mtp-model
MTP.gguf --capture-prefill-logits OUTPUT` similarly records complete logits in
AR and MTP modes after 96/1023/1024/2048/4096/32768-token prefixes of fixed
prose/code fixtures and eight continuations. The 1024+ cases exercise paired Q4_K/Q5_K
expert prefill when those weights are loaded. This explicit diagnostic bypasses
the separate teacher-forcing capture's eight-row limit by recording the frontier
after each normal prefill. Its summary reports continuation NLL/perplexity; use
identical harness source, model artifacts, toolchain and settings for both builds.

Code changes that could affect inference correctness require relevant logit
regression checks before completion, including changes to kernels, model loading,
tokenization, prefill/decode, sampling, caching or speculative state. Record the
baseline and candidate revisions and executable hashes, model/sidecar identities,
corpus hash, toolchain, runtime settings, exact commands and results. Match these
inputs across runs. Require exact full-logit equality for unchanged arithmetic;
use declared model-owned numerical limits for intentional arithmetic changes.
Never treat a missing model, skipped check or uninvestigated mismatch as a pass.

For Flash-Next, `gufo bench --logit-eval corpus.txt --logit-schedules "1:1:2,4,8"`
with the appropriate model and MTP options reports perplexity for repeated decode
and mixed verification widths. Set `--logit-out` separately for baseline and
candidate, then use `python tools/bench/logit-eval.py LEFT.bin.sha256
RIGHT.bin.sha256` to compare complete raw-logit hashes for corresponding schedules.
See the [Windows logit check](WINDOWS.md#windows-validated-switches) for limits.
Perplexity alone can hide individual mismatches. Parser/API-only changes still
require deterministic contract tests; teacher-forced logits do not exercise tool
parsing, sampling draws, rejection or draft-head arithmetic.

For Flash-Next draft-head regression checks, build the explicit
`qwen38_flash_next_gpu_probe` and use `--model FIRST.gguf --mtp-model MTP.gguf
--batch 2048 --context 4096 --mtp-hashes`. This emits complete finite stage and
vocabulary-row hashes at eight fixed text/image-ID states, then checks isolated
batching and ragged catch-up. Compare the hash lines from matched baseline and
candidate builds. `--mtp-audit` separately retains the independent scalar oracle
and its numerical limits; hash equality does not establish oracle parity. The
two modes cannot be combined.

Run affected state, sampling, rejection/rollback and snapshot checks separately
from the logit comparisons.

Tokenize once and feed the same predetermined history to teacher and
candidate. Compare full next-token distributions at each position before
appending the next evaluation token. Free-running text diverges after one
different choice and cannot isolate numerical or quantization error.

Relevant metrics include non-finite counts, normalized-logit error, KL,
teacher-token NLL/perplexity, top-1 agreement, and top-k overlap. See
[benchmark quality methodology](BENCHMARKS.md#quality-method-matched-token-per-position).
For a discrepancy, capture the earliest changed embedding, normalization,
attention/recurrent state, routed expert, layer output, or LM-head boundary.
Preserve the failing input and add a focused reproducer before fixing it.

Pin sampling controls, seeds, cache history, and batching when testing replay.
Run longer multi-turn cases when session reuse or EOS handling changes.
Do not average away numerical mismatches or classify device failures as passes.

For a running text server with at least an 8,192-token context, check advancing
conversation reuse, unchanged retries and uncached answer controls explicitly:

```sh
python tests/tools/cache_growth_test.py --url http://127.0.0.1:8080/v1 \
  --model gufo --out build/cache-growth.json
```

This real-model check covers dropped reasoning, replayed reasoning and reasoning
disabled. It sends requests to the selected server and is not part of CPU CI.

Check edited and rewound histories separately on the same loaded server:

```sh
python tests/tools/cache_edits_test.py --url http://127.0.0.1:8080/v1 \
  --model gufo --out build/cache-edits.json
```

This checks editing the latest user message, shortening an older tool result,
and changing an earlier user message while dropping later turns. Each shape
must reuse at least half its prompt, preserve exact unchanged retries, and match
an uncached output control with reasoning disabled. It writes results even on
failure; detailed checkpoint diagnostics remain in the server log.

## Performance evidence

Compare identical model artifacts, prompt/output counts, context depths,
batching, sampling, and cache state. Measure request latency and aggregate
throughput separately. Run baseline and candidate close together; add
repetitions only when noise or a suspected regression requires them.
Record hardware/software identities and the exact timed scope. Use
[profiling tools](PERFORMANCE.md) to explain a gain before retaining it.
