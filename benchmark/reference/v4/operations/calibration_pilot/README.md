# V4 Calibration Pilot

The default release target is
`benchmark-vabench-release-v4/release/benchmarkv4-r53`, paired with the pinned
EVAS 0.8.7 public runtime. Tools that support
historical inspection require the frozen r44 path explicitly; the active
direct-EVAS runner never falls back to it.
Use `--sample-families N --seed S` for reproducible random complete-family
campaigns, or pass an explicit `--selection` manifest when reproducing a
historical pilot. `CALIBRATION_FAMILIES.json` is retained only as historical
selection evidence.

The pilot is used only to freeze real skill snapshots, the agent wall-time cap,
provider per-turn output cap, safety limits, runner behavior, repetition count,
and telemetry. Skill text must remain task-agnostic and is not inlined into the
task prompt. G1/G3 expose the `veriloga` language skill, G4 exposes the
`vabench-feedback` public-EVAS diagnosis skill, and G5 exposes both. Neither
skill may contain a selected family ID, title, equation, threshold, stimulus
constant, checker rule, or mutation hint.

Because model outcomes from these families influence experimental settings,
their 30 forms are excluded from the primary post-calibration result. The
primary denominator is therefore 390 families and 1,170 scored forms. The
complete 400-family result may be reported only as a clearly labeled secondary
or sensitivity analysis.

The selection does not modify task assets, existing EVAS/Spectre evidence, or
the sealed 1,200-task release. A later campaign manifest must reference this
file by SHA-256 and record the frozen parameters produced by the pilot.

## Build The Campaign

The calibrated primary episode limit is wall-clock time. Its only authoritative
value and timeout-finalization behavior live in
`benchmark-vabench-release-v4/EXPERIMENT_POLICY.json`; campaign builders and
runners do not accept an override. The current policy gives every mode one
30-minute episode. Setup, model requests, tool calls, and judges use separate
infrastructure ceilings. The provider token value is
`per_turn_max_tokens`: a per-model-call safety cap passed as `max_tokens`, not a
cumulative G0-G5 stopping budget. Provider completion, hidden reasoning, visible
completion, and feedback-delivered text are recorded as telemetry and must be
reported separately from functional score.

If a model/provider rejects the next turn because the conversation exceeds its
native context window, the runner records `context_window_exceeded` separately.
If a single call stops at the provider output cap, the runner records
`termination_reason=model_output_limit`; it does not treat accumulated tokens as
the experimental ability budget. If wall time expires, the latest valid
workspace artifact is still eligible for judging, and otherwise the cell is
reported as `agent_timeout`.

```bash
python3 benchmark-vabench-release-v4/operations/calibration_pilot/build_campaign.py \
  --sample-families 10 \
  --seed 20260715 \
  --model qwen3.5-flash \
  --per-turn-max-tokens 65536 \
  --repetitions 1 \
  --output /tmp/v4-api-pilot-campaign.json
```

This produces 180 cells: ten families, three forms, and six modes. Use
`--repetitions` only after the single-episode smoke is sound.

Each model event records the requested per-turn maximum, provider-reported
completion, reasoning and visible tokens, and `finish_reason`. Hosted-model
aliases and provider timestamps must also be retained in external run metadata.

## Reuse A Completed Pilot

Completed episodes may be mechanically reused only when the model, prompt hash,
release hash, selection hash, endpoint hash, decoding settings, wall-time
policy, per-turn token cap, tools, and candidate files are unchanged. Prepare a
derived runtime containing only mechanically eligible episodes:

```bash
python3 benchmark-vabench-release-v4/operations/calibration_pilot/prepare_budget_reuse.py \
  --source-output /tmp/v4-calibration-4096 \
  --source-campaign /tmp/v4-calibration-4096.json \
  --target-campaign /tmp/v4-calibration-65536.json \
  --output /tmp/v4-calibration-65536
```

`REUSE_MANIFEST.json` records every accepted or rejected cell, source-result
hashes, candidate hashes, and rejection reasons. Reuse requires the same
provider, model, endpoint hash, temperature, streaming mode, prompt, EVAS
executable identity, wall-time policy, per-turn token cap, and release. A submitted
file is not by itself reusable: any episode whose model turn hit the provider
output limit must be rerun because an agent may have written an intermediate
file before truncation.
Run the full target campaign with `--resume`; reused cells are skipped and all
rejected cells start fresh.

## Dry Run

Install the pinned agent scaffold and build the upstream shared environment
before executing G2--G5:

```bash
uv sync --extra agentic --group dev
benchmark-vabench-release-v4/public-agent-runtime/build.sh
benchmark-vabench-release-v4/public-agent-runtime/verify.sh
```

`auto` selects Docker. Formal results require the matched images built from the
repository's top-level `environment/`: `vabench-agent-runtime:0.8.7` and
`vabench-agent-runtime:0.8.7-no-evas`. Other sandbox backends remain
legacy/test sensitivity paths and are not paper-valid. Record the Git commit,
image references, and observed image IDs by experimental arm with every
campaign.

G2--G5 use `mini-swe-agent==2.4.5` with its `DefaultAgent` controller and one
`bash` tool. The benchmark runner still owns campaign construction, runtime
export, credentials, wall-time enforcement, telemetry, trusted replay, and
final scoring; it does not implement a second model-control loop. Mini-SWE
step, cost, and consecutive-format-error limits are disabled. Accumulated
tokens are recorded but never terminate an episode.

Mini-SWE fixes the model--tool interaction scaffold; upstream vaBench's shared
Docker image fixes where those commands execute. This adapter does not fork or
modify mini-SWE-agent. It creates one container per task, forwards mini-SWE's
Bash calls through `docker exec`, and destroys the container at episode end.

Dry-run exports isolated runtime packages without contacting a model:

```bash
python3 benchmark-vabench-release-v4/operations/calibration_pilot/run_campaign.py \
  --campaign /tmp/v4-calibration-campaign.json \
  --output /tmp/v4-calibration-dryrun \
  --dry-run --limit 18
```

The mini-SWE shell starts at `/workspace` in the shared container and exposes
`public/task/` read-only, `public/submission/` writable, and `work/` writable.
Skill-enabled modes additionally expose `public/skills/<id>/` read-only with a
hash-bound `SKILL.md` package and `public/skills/SNAPSHOT_MANIFEST.json`; G2 has
no skill directory. All agentic modes receive the same minimal EVAS contract: a
pinned, real `evas` executable is discoverable in `PATH`, `evas --help` works,
and the task-local `evas_runtime.json` gives the public command.

The main-table executable-feedback profile adds `Agent-No-EVAS`, which keeps
the G2 mini-SWE controller, Bash workspace, wall-time policy, task prompt base,
and submission gate but uses the paired no-EVAS image. Its effective prompt
states that EVAS is unavailable, `evas_runtime.json` is removed, and neither
the `evas` command nor Python module is installed. This is an availability
control, not evidence that an Agentic episode causally used feedback.

G1 is still a direct artifact-envelope mode, but may use provider-side
`list_skills` and `read_skill` tools before the final answer. These tools read
only `public/skills`, reject path escape and symlinks, cache repeated reads, and
record skill lookup events. G0 receives no tools.

The old `prompt_assets/form_skills/` and `prompt_assets/evas_guides/` files are
retained only to reproduce sealed pre-r50 releases. The r50 materializer does
not copy or render them; all new comparisons use the real package/mode matrix
above.

The model invokes the image's fixed EVAS directly through ordinary bash,
including pipes, redirection, and compound commands, and inspects logs and
`tran.csv` under `/tmp/vabench-visible/evas-output` itself. The adapter does not
expose a waveform-specific helper or experiment arm, and does not run a
feedback broker, checker, gold comparison, or property diagnosis.
`vabench-submit` is likewise a real,
discoverable shell command that requests runner validation of the final
artifact set.

The shell wrapper records each actual `evas` process invocation independently
of the surrounding bash spelling, so pipes, redirections, and compound commands
do not disappear from telemetry. Campaign results expose the raw invocation
records, skill availability/hash metadata, bash commands that reference
`public/skills`, and a `v4-direct-evas-usage-v2` summary. Each invocation records
the deterministic `candidate_tree_sha256` computed immediately before EVAS
starts over only the task-declared candidate artifact paths; missing artifacts
have a stable state marker. The summary retains succeeded, failed, timed out,
and interrupted counts and adds unique candidate hashes, per-hash call counts,
modified-rerun count, and unchanged-repeat count. These records describe
candidate versions at tool invocation, not causal feedback use; an EVAS nonzero
exit is not promoted to a hidden-checker or behavioral verdict.

An explicit `vabench-submit` ends the episode early and records
`submission_mode=explicit`. It is not a score-eligibility gate: when wall time
expires with a complete declared artifact set, the runner snapshots that final
workspace as `status=workspace_ready` and
`submission_mode=workspace_at_deadline`, then sends the snapshot to the same
trusted judge. `termination_reason=agent_timeout` remains visible, so artifact
correctness and the agent's ability to recognize completion are reported
separately.

Evaluator, gold, and trusted-replay assets remain outside the model-visible
container. A production G2--G5 run requires the shared Docker environment;
`none` is allowed only for unit tests and dry runs. Docker denies network
access and mounts only the current task, submission, and work directories.
Each command has a 64 MiB per-file limit. The runner permits at most 64 MiB in
submission and 512 MiB in work, and captures at most 1 MiB of command output in
host memory. Model observations receive a 12 KiB head/tail summary when output
is larger; telemetry records the original, captured, and truncated byte counts.
Quota violations are reported as `agent_resource_exhausted`, not as benchmark
behavior failures or hidden-test zeroes.
Before trusted
replay starts, the runner also rejects submission symlinks and candidate source
includes that can escape the declared artifact set.

G0/G1 parse exact artifact blocks into the submission directory. In the
mini-SWE path, the model controls direct EVAS invocations over the public
runtime package. DUT/bugfix tasks expose their visible deck. For r52 testbench
tasks, the public runtime exposes only the reference DUT; the five scored
faults remain evaluator-only and are used only during trusted replay.
The legacy native scaffold retains its restricted `run_evas` tool only as a
sensitivity path and is not the default G2--G5 agent.

Direct responses must use the exact artifact envelope contract. The live runner
rejects filename-only markers, input-artifact markers, Markdown fences,
duplicate or out-of-order blocks, undeclared paths, and non-whitespace text
outside the blocks. It preserves the extracted body bytes and records the raw
response hash, parser version, diagnostics, and artifact hashes. A format
failure remains `invalid_submission` and is not passed to a judge.

`audit_direct_protocol.py` can classify deterministic recoverability in stored
historical responses. `reparse_direct.py` may materialize those recovered files
under `evidence/recovered_direct_submission` for diagnosis, but it does not
change the episode status or make the result score-eligible. Recovery therefore
stays separate from the benchmark execution path.

## Provider Credentials

Credentials are loaded from an environment variable or a repository-external
file and are never included in prompts or result JSON. Credential-file paths
and injected operator commands are redacted from wrapper metadata:

```bash
export DEEPSEEK_API_KEY='...'
python3 benchmark-vabench-release-v4/runners/run_benchmarkv4_campaign.py \
  --task-id v4-001 \
  --mode G0 \
  --model deepseek-v4-flash \
  --base-url https://api.deepseek.com/v1 \
  --api-key-env DEEPSEEK_API_KEY \
  --evas-command "$(pwd)/.venv/bin/evas" \
  --output-root /tmp/benchmarkv4-api-smoke
```

Executable campaigns require `--evas-command`; there is no PATH-derived
default. Before the first model request, the wrapper resolves it to an absolute
command and records the executable SHA-256, complete `--version` output
(including version, ABI, and revision), and version-output SHA-256 in
`campaign.json`. The cell runner rechecks that identity before loading provider
credentials. Dry runs may omit EVAS because they execute neither model nor
evaluator.

The provider adapter uses the OpenAI-compatible chat-completions protocol.
Changing providers requires only `--base-url`, the campaign model ID, and
`--api-key-env` or `--api-key-file`.

## Evaluator Adapters

`--final-judge-command` injects the benchmark-controlled trusted replay. It
receives these environment variables:

- `VABENCH_RUNTIME_DIR`
- `VABENCH_PUBLIC_DIR`
- `VABENCH_SUBMISSION_DIR`
- `VABENCH_EVALUATOR_DIR`

The final judge adapter runs once after submission and must use the
release-pinned strict EVAS evaluator. It may additionally dispatch Spectre as
a non-blocking parity audit. Neither its command string nor evaluator directory
is sent to the model. A formal pilot must configure the EVAS final adapter; a
provider-only smoke may omit it only to test API transport and artifact
handling.

### Result protocol

Every completed G0-G5 cell now writes an `experiment_result` object in
`evidence/campaign_result.json` conforming to
`schemas/vabench-experiment-result.schema.json`. The record preserves the exact
last assistant message and its hash, snapshots every declared final artifact
under `evidence/final_submission/`, and records per-file and tree hashes. This
snapshot is the scored submission; later edits to `public/submission` do not
change it. Trusted replay receives the snapshot path in both
`VABENCH_SUBMISSION_DIR` and `VABENCH_FINAL_SUBMISSION_DIR`, and its record binds
the replay to the snapshot tree hash.

The final judge is a trusted replay, not another model-feedback turn. Before it
runs, the runner hashes the exported evaluator tree and records the already
pinned EVAS identity. The adapter
must write JSON to `VABENCH_TRUSTED_REPLAY_RESULT` with one of these statuses:

```json
{
  "status": "behavior_failure",
  "diagnostics": ["slew_limit violated in corner-fast"],
  "failure_taxonomy": {
    "schema_version": "vabench-failure-taxonomy-v1",
    "primary_class": "property",
    "secondary_classes": ["functional"],
    "stage": "property_check",
    "responsibility": "candidate",
    "retryable": false,
    "case_ids": ["corner-fast"],
    "property_ids": ["slew_limit"],
    "mutation_ids": []
  }
}
```

Allowed terminal replay statuses are `passed`, `compile_failure`,
`runtime_failure`, `behavior_failure`, and `infrastructure_failure`. A legacy
adapter returning zero without JSON is accepted as `passed` with a compatibility
diagnostic. A nonzero return without JSON is an infrastructure failure because
the runner cannot safely infer its failure stage.

Experiment-result schema v2 adds a required `failure_taxonomy` object to both
the replay and terminal episode record without changing `status`, `outcome`, or
binary-score semantics. Canonical primary classes are `invalid`, `compile`,
`runtime`, `functional`, `mutation_survival`, `property`, `timeout`,
`resource_exhaustion`, `behavior_unspecified`, and `infrastructure`; passing
and not-yet-scored records use `null`. The runner derives unambiguous classes
from artifact gates, execution state, and coarse replay status. A
`behavior_failure` adapter should provide `functional`, `mutation_survival`, or
`property` plus any applicable `case_ids`, `property_ids`, and `mutation_ids`.
For compatibility, an adapter that omits `failure_taxonomy` remains scoreable
as `behavior_unspecified`. An invalid or status-incompatible supplied taxonomy
marks the replay as `infrastructure_failure` instead of silently corrupting
analysis labels; the raw adapter JSON is retained.

`score_campaign.py` copies the normalized object into each analysis row and
flattens `failure_class`, `failure_stage`, `failure_responsibility`, and
`failure_retryable`. Score-report schema v2 aggregates `failure_classes`,
`secondary_failure_classes`, `failure_stages`, `failure_responsibilities`,
`failure_retryability`, failed case/property/mutation ID counts, and
per-form/per-mode/per-arm `failure_breakdown`.

Model execution is separate from replay execution. `agent_timeout` without a
complete artifact and `no_submission` have `score_eligible: false` and
`score: null`; neither is reported as a hidden-test or behavior zero. A complete
workspace produced before the wall-time boundary may still enter trusted replay.
Trusted replay timeouts are
`runtime_failure`, while launch and malformed-result failures remain
`infrastructure_failure`.

Operational failures are also recorded on an orthogonal `incidents` axis.
Each incident identifies its phase, component, category, responsibility, and
retryability. This separates provider request timeouts, sandbox/preflight
failures, runner failures, and direct EVAS command failures without replacing
the final artifact/checker outcome. In particular, a failed exploratory EVAS
call can coexist with a later passing final submission.

The historical `feedback_adapter.py` remains only to reproduce old experiments.
It reads evaluator assets and must never be configured as an active G2-G5 model
tool. The legacy native sensitivity scaffold retains `run_evas`; current
mini-SWE runs invoke the pinned `evas` executable directly and receive only its
raw public simulation output, never a checker or score oracle.

Generated campaign manifests, runtime workspaces, API responses, simulator
outputs, and credentials belong outside the repository. Only runner source,
tests, schemas, and compact aggregate reports should enter a PR.

## Score A Completed Campaign

Run a judge adapter over every complete submission and aggregate model, form,
mode, token, tool, and outcome records:

```bash
python3 benchmark-vabench-release-v4/operations/calibration_pilot/score_campaign.py \
  --campaign-output /tmp/v4-calibration-smoke \
  --judge-kind final_trusted_replay \
  --judge-command \
    "python3 /path/to/trusted_replay_adapter.py"
```

`score_campaign.py` resolves campaign/output paths and existing judge-command
script paths to absolutes before invoking adapters, so the command is safe to
run from either the workspace root or `behavioral-veriloga-eval/`.

`feedback_evas` reports are always marked `provisional_feedback_only`; they
are useful for pilot tuning but are not benchmark scores. A paper-facing run
must use `--judge-kind final_trusted_replay` with the sealed, pinned strict
EVAS adapter. `--judge-kind final_spectre` is retained only for optional parity
audits and does not gate a score claim. Missing or invalid submissions remain
explicit denominator failures and are never silently dropped.

Historical pilot runs produced before submission-path normalization can be
repaired without another model call when every required candidate is found
under one unique common extra directory and no competing target copy exists:

```bash
python3 benchmark-vabench-release-v4/operations/calibration_pilot/repair_submission_layout.py \
  --campaign-output /tmp/v4-calibration-smoke
```

The repair is path-only, preserves artifact hashes, and records the stripped
prefix and each promotion. It rejects partial bundles, symlinks, and ambiguous
or competing prefixes. Recovered candidates remain
`submission_protocol_compliant=false`, and the formal scorer treats them as not
submitted.

Long agentic episodes checkpoint the public conversation, cumulative provider
output tokens, tool events, and current submission after every model and tool action.
`--resume` continues the same episode after an infrastructure interruption;
it does not reset the wall-time episode budget, create another sample, or grant another
pass@k opportunity.

Independent cells may run concurrently with `--workers N`. Each worker writes
only its own cell runtime; keep `--workers 1` when diagnosing provider rate
limits or simulator resource contention.
