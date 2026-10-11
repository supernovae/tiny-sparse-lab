# Fast test feedback

From the repository root, install the locked development environment once:

```sh
uv sync --locked --extra cpu --dev
```

Run the tests nearest the files you changed first. Examples:

```sh
# Corpus acquisition, normalization, generation, exports, and provenance
uv run --locked --extra cpu pytest -q tests/test_corpus_acquisition.py tests/test_corpus_pipeline.py tests/test_corpus_generators.py tests/test_corpus_exports.py tests/test_corpus_provenance.py
# Dataset/config/tokenizer/packing integration
uv run --locked --extra cpu pytest -q tests/test_config.py tests/test_datasets.py tests/test_conversations.py tests/test_local_chat.py tests/test_tokenizer.py tests/test_packing_manifest.py
# Surface changes
uv run --locked --extra cpu pytest -q tests/test_surface_overlay.py tests/test_surface_review.py tests/test_surface_triage_import.py
# Hub credentials (without a public endpoint)
uv run --locked --extra cpu pytest -q tests/test_hf_auth.py
```

Pushes to `main` and all PRs run two Linux jobs: `safe` (Ruff, research lint
and an explicit zero-model selection) and `lab-loop` (tiny CPU training plus
probe, reference, explorer and dashboard regressions). The automatic `safe`
selection itself fits no tokenizer and initializes no model; the separate
`lab-loop` job does model work. See the [workflow](../.github/workflows/ci.yml)
for exact nodes and budgets.

Manual `workflow_dispatch` with `safe` selects both jobs too. Additional
`integration-linux`, `platform-macos` and `release-candidate` choices need a
separately reviewed allocation. Do not dispatch them for prose changes. For
documentation, check links, anchors, parser arguments and configuration schemas
without calling command handlers. Ordinary PR success does not certify all
training paths, accelerator behavior or macOS behavior.

For an explicit local full-suite run, use two workers, distributing whole test
files so module-scoped fixtures remain together. Pytest's `tmp_path` and
`tmp_path_factory` keep artifacts in worker-specific directories. Do not share
a mutable work directory between independently launched suites.

```sh
uv run --locked --extra cpu pytest -q -n 2 --dist loadfile -m 'not mps and not mlx and not cuda and not rocm and not xpu and not network'
uv run --locked --extra cpu ruff check .
uv run --locked --extra cpu ruff format --check .
```

## Fast and full suites

The fast suite skips tests marked `slow`. It is the default local check before
a push. The full suite is the release gate.

```sh
# Fast: about 2,900 tests; a few minutes with 4 workers on an 8-vCPU box
uv run --locked --extra cpu pytest -q -n 4 -m 'not slow and not mps and not mlx and not cuda and not rocm and not xpu and not network'
# Full: about 3,200 tests; about 18 min with 4 workers on the same box
uv run --locked --extra cpu pytest -q -n 4 -m 'not mps and not mlx and not cuda and not rocm and not xpu and not network'
# Only the slow tests
uv run --locked --extra cpu pytest -q -n 4 -m slow
```

`tests/conftest.py` applies the `slow` marker to the base node ids listed in
[`tests/slow_tests.txt`](../tests/slow_tests.txt), so every parametrized case
of a listed test follows. The slow tests are fewer than a tenth of the suite
but take more than 90% of its test time: end-to-end campaign, corpus and
lifecycle runs, tiny training, and native subprocess monitors.
`tests/test_slow_list.py` fails when an entry no longer names a real test.

In CI, the automatic `safe` and `lab-loop` jobs are unchanged. The manual
`workflow_dispatch` choice `fast` runs the fast suite on Linux, and
`release-candidate` still runs everything.

### Profiling and the slow list

Profile a full run, then list any test whose call time is at least 1 s:

```sh
uv run --locked --extra cpu pytest -q -n 4 -p no:randomly --durations=50 \
  --junitxml=/tmp/suite.xml -o junit_duration_report=call
```

Add new slow tests to `tests/slow_tests.txt` in sorted order. A test whose
fixture setup is heavy, rather than its call, belongs there too.

### Known failures

[`tests/known_failures.txt`](../tests/known_failures.txt) lists tests that
fail for a root cause tracked in an open issue. The conftest skips each one
with its reason and issue number, so `-rs` shows exactly what is not running.
Delete an entry in the PR that fixes its issue.

### Host RAM in tests

Host-work planning (`sparselab.host_capacity`) refuses work when measured
available RAM minus a reserve cannot fit one worker. Under xdist, or on a box
shared with other jobs, that made unrelated tests fail with "inadequate
measured RAM after reserve". Every SparseLab reader of host RAM, including
reserves computed from total RAM, goes through
`host_capacity.measure_memory()`. An autouse fixture in `tests/conftest.py`
pins it to a fixed host (64 GiB total, 48 GiB available), whatever the
physical machine. Tests that
monkeypatch `psutil.virtual_memory` themselves still see their own values,
which is how `tests/test_host_capacity.py` covers the reserve logic.

## CPU worker limits and stall diagnosis

The root test `conftest.py` sets `OMP_NUM_THREADS`, `MKL_NUM_THREADS`,
`OPENBLAS_NUM_THREADS`, and `VECLIB_MAXIMUM_THREADS` to `1` during pytest
startup. This matches the CI environment and happens before collection and
xdist worker creation, so workers and subprocesses they launch inherit one
thread per CPU library. If a pytest plugin imported Torch before the
conftest, the conftest also caps Torch's intra-op pool without importing Torch
for Torch-free tests. Like CI, it leaves the inter-op pool unchanged. These limits
apply only to test processes; they do not change lab runtime defaults.

Campaign status projection verifies each completed dependency-DAG stage once
per traversal, including shared upstream nodes. Later projections and checks
before dispatch verify again; no completed-stage cache survives the traversal.
This is not generic snapshot proof reuse across projections or commands.

Verifier authority walks deduplicate module scheduling and file discovery only
within one closure walk. Each later authority lookup still reads and hashes the
verifier source bytes. Proof lookup diagnostics use the same authority that was
compared with the receipt, rather than walking the closure again for telemetry.

The CPU gate includes native Campaign integrations with real worker startup,
staging, training, checkpoint transfer, continuation, and evaluation. These can
take several minutes. A whole-command deadline must allow all separately
bounded runs and the subsequent verification; a faulthandler stack report is
not a test failure or a run deadline.

For a suspected CPU stall, retain the normal two-worker layout and ask
pytest's built-in faulthandler plugin for thread stacks after a bounded interval:

```sh
uv run --locked --extra cpu pytest -vv -n 2 --dist loadfile \
  -o faulthandler_timeout=120 \
  -m 'not mps and not mlx and not cuda and not rocm and not xpu and not network'
```

`faulthandler_timeout` reports stacks; it does not skip, kill, or otherwise
turn a slow test into a passing result. Use the reported test name to rerun it
serially with the same option when isolating the blockage.

On an Apple Silicon machine with the optional MLX runtime installed (`uv sync --locked --dev --extra cpu --extra mlx`), run hardware tests in **one serial process**, after CPU workers finish:

```sh
uv run --locked --extra cpu --extra mlx pytest -q -m 'mlx and not mps and not network'
# Opt-in MPS tests when the device is available; the current CI gate excludes these.
uv run --locked --extra cpu pytest -q -m 'mps and not network'
```

Never use `-n` for MLX/MPS or run another accelerator test/training process against the same device at the same time. Network-marked tests require explicit separate opt-in.

## Why the gate is structured this way

The full CPU jobs on Linux and macOS retain their tests, hardware exclusions,
and existing 30-minute safety limits, but are manual-only while their long
native integrations are paused as automatic build gates. The automatic `safe` and `lab-loop` jobs have 12- and 20-minute limits. The manual hosted
CPU jobs use up to four workers with work-stealing; the local command above
uses whole-file scheduling for fixture reuse.

The [historical CI run 36380519748](https://github.com/supernovae/tiny-sparse-lab/actions/runs/36380519748)
measured 331 seconds for Linux's serial CPU step and 407 seconds for macOS's
serial CPU step. Those measurements are not a bound for today's larger suite.
Locked uv downloads are cached through `setup-uv`. Accelerator and network
checks remain separate explicit opt-ins.
