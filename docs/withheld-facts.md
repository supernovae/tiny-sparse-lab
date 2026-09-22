# Withheld-fact diagnostic

Milestones 0.6–0.9 provide an offline deterministic fixture, an immutable split manifest, an offline verifier, and a compact verified audit for testing fact-identity data separation before transfer experiments. `split_facts(seed)` creates six training facts and two held-out facts. The split is by complete `(subject, relation)` identity; held-out values are absent from training documents. Evaluation cases expose a prompt and expected value, with the expected value excluded from the prompt.

This is not a training source, benchmark score, or evidence of byte-memory transfer. It deliberately does not add held-out facts to backbone training, memory-adapter supervision, or router objectives. Its purpose is to make accidental leakage detectable before a future trained diagnostic is designed.

```python
from sparselab.data.withheld_facts import evaluation_cases, training_documents

train = training_documents(seed=0)
held_out = evaluation_cases(seed=0)
```

Before running a diagnostic, write and retain a manifest:

```sh
uv run sparselab facts manifest --seed 0 --output artifacts/withheld-facts-seed-0.json
```

Verify a retained artifact before using or citing it:

```sh
uv run sparselab facts verify artifacts/withheld-facts-seed-0.json
```

For automation, emit a compact verified audit:

```sh
uv run sparselab facts audit artifacts/withheld-facts-seed-0.json
```

The JSON report states the fixture seed, manifest digest, statement/case counts, and whether held-out values occur in the training statements. It is fixture evidence only; it contains neither model outputs nor an experimental score.

Verification recomputes its digest and requires every field to match the current fixture for the recorded seed. A self-consistent substituted split is rejected, not merely a damaged JSON file.

The manifest records the ordered training statements, held-out prompt/expected-value cases, seed, format version, and a SHA-256 digest of its canonical payload. Re-running with the same seed accepts byte-identical evidence; a different seed cannot overwrite the existing manifest. It contains no model outputs, training examples, or score.

Record the verified manifest alongside any future experiment result. It proves the fixture split only; data-provenance evidence is still required to prove a training pipeline obeyed that boundary.
