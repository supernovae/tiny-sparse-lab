"""Local, read-only Streamlit dashboard for SparseLab run telemetry.

The app intentionally opens SQLite through ``dashboard.queries`` rather than the
writer-side ExperimentStore, so loading a dashboard can never migrate a run store.
"""

from __future__ import annotations

import argparse
import json
import sqlite3
from datetime import UTC, datetime
from importlib.resources import files
from pathlib import Path

import pandas as pd
import plotly.express as px
import streamlit as st

from sparselab.dashboard.queries import DashboardSnapshot, RunRecord, runs, snapshot
from sparselab.dashboard.research import learn_page, research_page
from sparselab.training.checkpoints import CheckpointManager, _safe_member
from sparselab.training.metric_registry import metric_spec

_HELP_PACKAGE = "sparselab.dashboard"
_PILOT_PURPOSES = frozenset({"smoke", "warmup"})
_MEMORY_NATIVE = {
    "memory/device_allocated_bytes",
    "memory/device_reserved_bytes",
    "memory/device_peak_allocated_bytes",
    "memory/device_peak_reserved_bytes",
    "memory/driver_allocated_bytes",
}
_MEMORY_MLX = {
    "memory/device_allocated_bytes",
    "memory/device_peak_allocated_bytes",
    "memory/device_cache_bytes",
}
_MEMORY_SAMPLED = {
    "memory/device_sampled_peak_bytes",
    "memory/process_rss_bytes",
    "memory/process_peak_rss_bytes",
    "memory/system_available_bytes",
}
_ESTIMATE_BUCKETS = (
    ("resident_weights_bytes", "resident weights"),
    ("runtime_buffers_bytes", "runtime buffers"),
    ("gradients_bytes", "gradients"),
    ("optimizer_bytes", "optimizer state"),
    ("activations_bytes", "retained activations"),
    ("attention_working_bytes", "attention working"),
    ("workspace_bytes", "temporary workspace"),
    ("headroom_bytes", "headroom"),
)


def arguments() -> argparse.Namespace:
    parser = argparse.ArgumentParser(add_help=False)
    parser.add_argument("--runs-dir", default="runs")
    parser.add_argument("--reports-dir", default="artifacts/research-reports")
    args, _ = parser.parse_known_args()
    return args


def metric_help(slug: str) -> str:
    try:
        resource = files(_HELP_PACKAGE).joinpath("help", f"{slug}.md")
        return resource.read_text(encoding="utf-8")
    except (FileNotFoundError, OSError):
        return "No packaged guide is available for this metric."


def _as_object(value: object) -> dict[str, object]:
    return value if isinstance(value, dict) else {}


def _nested(value: object, *keys: str) -> object | None:
    current = value
    for key in keys:
        if not isinstance(current, dict):
            return None
        current = current.get(key)
    return current


def _format_bytes(value: object) -> str:
    if not isinstance(value, (int, float)) or isinstance(value, bool):
        return "unavailable"
    units = ("B", "KiB", "MiB", "GiB", "TiB")
    number = float(value)
    for unit in units:
        if abs(number) < 1024 or unit == units[-1]:
            return f"{number:.2f} {unit}"
        number /= 1024
    return "unavailable"


def _observation_age(observed_at: datetime) -> str:
    seconds = max(0, int((datetime.now(UTC) - observed_at).total_seconds()))
    if seconds < 60:
        return f"{seconds}s"
    if seconds < 3600:
        return f"{seconds // 60}m"
    return f"{seconds // 3600}h"


def _recorded_age(value: object) -> str:
    if not isinstance(value, str):
        return "unavailable"
    try:
        observed_at = datetime.fromisoformat(value)
    except ValueError:
        return "unavailable"
    if observed_at.tzinfo is None:
        # ExperimentStore's SQLite datetime('now') values are UTC.
        observed_at = observed_at.replace(tzinfo=UTC)
    return _observation_age(observed_at.astimezone(UTC))


def _filtered_runs(view: DashboardSnapshot, include_pilots: bool) -> list[RunRecord]:
    return [
        record
        for record in view.runs
        if include_pilots or record.purpose not in _PILOT_PURPOSES
    ]


def selected(view: DashboardSnapshot) -> tuple[list[RunRecord], list[str]]:
    records = _filtered_runs(view, st.session_state.get("include_pilot_runs", False))
    ids = {record.run_id for record in records}
    selected_ids = [
        run_id for run_id in st.session_state.get("selected_runs", []) if run_id in ids
    ]
    return records, selected_ids


def _selection_controls(root: Path) -> None:
    """Entrypoint-owned widgets retain identity across Streamlit pages."""
    key = f"sidebar_records:{root.resolve()}"
    try:
        records = runs(root)
        st.session_state[key] = records
    except (OSError, sqlite3.Error, ValueError):
        records = st.session_state.get(key, [])
    include_pilots = st.sidebar.checkbox(
        "Include smoke and warmup pilots", value=False, key="include_pilot_runs"
    )
    ids = [
        record.run_id
        for record in records
        if include_pilots or record.purpose not in _PILOT_PURPOSES
    ]
    previous = st.session_state.get("selected_runs", ids[:1])
    st.session_state["selected_runs"] = [run_id for run_id in previous if run_id in ids]
    st.sidebar.multiselect("Runs", ids, key="selected_runs")


def _rows_for(
    rows: tuple[dict[str, object], ...], selected_ids: list[str]
) -> list[dict[str, object]]:
    wanted = set(selected_ids)
    return [row for row in rows if row["run_id"] in wanted]


def architecture(record: RunRecord) -> dict[str, str]:
    return {
        "attention": str(_nested(record.config, "attention", "kind") or "unavailable"),
        "dataset": str(_nested(record.config, "dataset", "source") or "unavailable"),
        "ffn": str(_nested(record.config, "model", "ffn") or "unavailable"),
        "memory": str(_nested(record.config, "model", "memory") or "unavailable"),
        "purpose": record.purpose or "unavailable",
    }


def _runtime(record: RunRecord, view: DashboardSnapshot) -> dict[str, object]:
    manifest = view.manifests.get(record.run_id, {})
    return _as_object(record.metadata.get("runtime")) or _as_object(
        manifest.get("runtime")
    )


def _requested_precision(record: RunRecord) -> object:
    return _nested(record.config, "runtime", "precision") or "unavailable"


def _effective_precision(record: RunRecord, runtime: dict[str, object]) -> object:
    return runtime.get("precision") or _requested_precision(record)


def _optimizer_semantics(record: RunRecord) -> str:
    optimizer = _nested(record.config, "optimizer", "name")
    if optimizer == "adafactor":
        return "Adafactor relative learning-rate cap; not numerically AdamW LR"
    if optimizer == "adamw":
        return "AdamW update learning rate"
    return "unavailable"


def _mlx_run_ids(view: DashboardSnapshot) -> set[str]:
    return {
        record.run_id
        for record in view.runs
        if _runtime(record, view).get("engine") == "mlx"
    }


def _estimate(record: RunRecord) -> dict[str, object]:
    return _as_object(record.metadata.get("memory_estimate"))


def _comparison_rows(
    records: list[RunRecord], view: DashboardSnapshot
) -> list[dict[str, object]]:
    rows: list[dict[str, object]] = []
    for record in records:
        runtime = _runtime(record, view)
        rows.append(
            {
                "run_id": record.run_id,
                "purpose": record.purpose or "unavailable",
                "engine": runtime.get("engine")
                or _nested(record.config, "runtime", "engine")
                or "unavailable",
                "backend": runtime.get("backend")
                or _nested(record.config, "runtime", "backend")
                or "unavailable",
                "requested_precision": _requested_precision(record),
                "effective_precision": _effective_precision(record, runtime),
                "optimizer": _nested(record.config, "optimizer", "name")
                or "unavailable",
                "optimizer_semantics": _optimizer_semantics(record),
                "sequence_length": _nested(record.config, "training", "seq_len")
                or "unavailable",
                "micro_batch": _nested(record.config, "training", "micro_batch_size")
                or "unavailable",
                "accumulation": _nested(
                    record.config, "training", "gradient_accumulation"
                )
                or "unavailable",
                "dataset": _nested(record.config, "dataset", "source") or "unavailable",
                "tokenizer": _nested(record.config, "tokenizer", "path")
                or "unavailable",
            }
        )
    return rows


def comparison(records: list[RunRecord], view: DashboardSnapshot) -> None:
    if len(records) < 2:
        return
    rows = _comparison_rows(records, view)
    changed = [
        key
        for key in rows[0]
        if key != "run_id" and len({str(row[key]) for row in rows}) > 1
    ]
    st.subheader("Comparison conditions")
    st.caption(
        "Comparisons are descriptive unless these recorded scientific and runtime conditions match. "
        "No values are interpolated or normalized."
    )
    st.dataframe(pd.DataFrame(rows), width="stretch", hide_index=True)
    if changed:
        st.warning("Different conditions: " + ", ".join(changed))
    else:
        st.success(
            "Displayed recorded conditions match; compare only observed budget points."
        )


def overview(view: DashboardSnapshot) -> None:
    st.header("Overview")
    records, selected_ids = selected(view)
    if not records:
        st.info("No eligible runs yet. Smoke and warmup pilots are hidden by default.")
        return
    st.dataframe(
        [
            {
                "run_id": item.run_id,
                "name": item.name,
                "status": item.status,
                "parent": item.parent_run_id or "unavailable",
                "updated_at": item.updated_at,
                **architecture(item),
            }
            for item in records
        ],
        width="stretch",
        hide_index=True,
    )
    comparison([record for record in records if record.run_id in selected_ids], view)
    selected_events = _rows_for(view.events, selected_ids)
    if selected_events:
        st.subheader("Events")
        st.dataframe(selected_events, width="stretch", hide_index=True)


def training(view: DashboardSnapshot) -> None:
    st.header("Training")
    records, selected_ids = selected(view)
    comparison([record for record in records if record.run_id in selected_ids], view)
    points = _rows_for(view.metrics, selected_ids)
    if not points:
        st.info("Select a run with recorded metrics.")
        return
    comparison_condition = st.selectbox(
        "Comparison condition",
        ("descriptive", "equal_tokens", "equal_steps", "equal_wall_time"),
        help="This labels the comparison claim; it does not interpolate observations.",
        key="training_comparison_condition",
    )
    st.caption(
        "Descriptive comparison only."
        if comparison_condition == "descriptive"
        else f"Showing observed points for `{comparison_condition}`; no controlled conclusion is inferred."
    )
    axis = st.radio(
        "X axis",
        ("step", "tokens_seen", "wall_time"),
        horizontal=True,
        key="training_axis",
    )
    names = sorted({str(point["name"]) for point in points})
    selected_names = st.multiselect(
        "Metrics", names, default=names, key="training_metrics"
    )
    filtered = [point for point in points if point["name"] in selected_names]
    if filtered:
        figure = px.line(
            filtered, x=axis, y="value", color="run_id", facet_row="name", markers=True
        ).update_yaxes(matches=None)
        figure.update_layout(height=max(350, 220 * len(selected_names)))
        st.plotly_chart(figure, width="stretch")
    for name in selected_names:
        spec = metric_spec(name)
        if spec is not None:
            with st.expander(f"What is {name}?"):
                st.markdown(metric_help(spec.help_slug))


def architecture_diagnostics(view: DashboardSnapshot) -> None:
    st.header("Architecture diagnostics")
    _, selected_ids = selected(view)
    points = _rows_for(view.metrics, selected_ids)
    for title, prefix in {
        "MoE": "moe/",
        "Engram": "engram/",
        "Attention": "attention/",
    }.items():
        subset = [point for point in points if str(point["name"]).startswith(prefix)]
        st.subheader(title)
        if not subset:
            st.info(f"No persisted {title} diagnostics for the selected runs.")
            continue
        st.plotly_chart(
            px.line(
                subset,
                x="step",
                y="value",
                color="run_id",
                facet_row="name",
                markers=True,
            )
            .update_yaxes(matches=None)
            .update_layout(
                height=max(350, 220 * len({point["name"] for point in subset}))
            ),
            width="stretch",
        )


def evaluation(view: DashboardSnapshot) -> None:
    st.header("Evaluation")
    _, selected_ids = selected(view)
    points = [
        point
        for point in _rows_for(view.metrics, selected_ids)
        if str(point["name"]).startswith("validation/")
    ]
    if not points:
        st.info("No persisted evaluation metrics are available for the selected runs.")
        return
    st.plotly_chart(
        px.line(
            points, x="step", y="value", color="run_id", facet_row="name", markers=True
        )
        .update_yaxes(matches=None)
        .update_layout(height=max(350, 220 * len({point["name"] for point in points}))),
        width="stretch",
    )


def runtime_view(view: DashboardSnapshot) -> None:
    st.header("Runtime")
    records, selected_ids = selected(view)
    rows = []
    for record in records:
        if record.run_id not in selected_ids:
            continue
        runtime = _runtime(record, view)
        rows.append(
            {
                "run_id": record.run_id,
                "worker": view.manifests.get(record.run_id, {}).get(
                    "worker_id", "unavailable"
                ),
                "engine": runtime.get("engine", "unavailable"),
                "backend": runtime.get("backend", "unavailable"),
                "device": runtime.get("device_name")
                or runtime.get("torch_device")
                or "unavailable",
                "physical_device_id": runtime.get("physical_device_id", "unavailable"),
                "os": runtime.get("os", "unavailable"),
                "requested_precision": _requested_precision(record),
                "effective_precision": _effective_precision(record, runtime),
                "optimizer": _nested(record.config, "optimizer", "name")
                or "unavailable",
                "optimizer_semantics": _optimizer_semantics(record),
                "declared_precisions": runtime.get(
                    "precision_capabilities", "unavailable"
                ),
                "tested_precisions": runtime.get("tested_precisions", "unavailable"),
                "tested_features": runtime.get("tested_features", "unavailable"),
                "validated_at": runtime.get("validated_at", "unavailable"),
                "framework": runtime.get("framework_version")
                or runtime.get("torch_version")
                or "unavailable",
                "system_total": _format_bytes(runtime.get("system_total_bytes")),
                "system_available": _format_bytes(
                    runtime.get("system_available_bytes")
                ),
                "device_total": _format_bytes(runtime.get("device_total_bytes")),
                "device_free": _format_bytes(runtime.get("device_free_bytes")),
                "device_recommended": _format_bytes(
                    runtime.get("device_recommended_bytes")
                ),
                "measurement_source": runtime.get("measurement_source", "unavailable"),
            }
        )
    if not rows:
        st.info(
            "Runtime metadata is unavailable for these legacy or not-yet-registered runs."
        )
        return
    st.dataframe(rows, width="stretch", hide_index=True)
    st.caption(
        "Unified-memory device capacity and system RAM are reported separately and are not added together."
    )
    with st.expander("Runtime and precision guide"):
        st.markdown(metric_help("runtime"))


def memory_view(view: DashboardSnapshot) -> None:
    st.header("Memory")
    records, selected_ids = selected(view)
    values = [
        point
        for point in _rows_for(view.metrics, selected_ids)
        if str(point["name"]).startswith("memory/")
    ]
    mlx_run_ids = _mlx_run_ids(view)
    mlx_native = [
        point
        for point in values
        if point["run_id"] in mlx_run_ids and point["name"] in _MEMORY_MLX
    ]
    native = [
        point
        for point in values
        if point["name"] in _MEMORY_NATIVE
        and not (point["run_id"] in mlx_run_ids and point["name"] in _MEMORY_MLX)
    ]
    sampled = [point for point in values if point["name"] in _MEMORY_SAMPLED]
    if native:
        st.subheader("Native allocator readings")
        st.plotly_chart(
            px.line(native, x="step", y="value", color="run_id", facet_row="name")
            .update_yaxes(matches=None)
            .update_layout(
                height=max(350, 220 * len({point["name"] for point in native}))
            ),
            width="stretch",
        )
    else:
        st.info(
            "Native allocator readings are unavailable for the selected non-MLX runs."
        )
    if mlx_native:
        st.subheader("MLX Metal memory")
        st.plotly_chart(
            px.line(mlx_native, x="step", y="value", color="run_id", facet_row="name")
            .update_yaxes(matches=None)
            .update_layout(
                height=max(350, 220 * len({point["name"] for point in mlx_native}))
            ),
            width="stretch",
        )
        st.caption(
            "MLX active, peak, and cache memory are Metal framework measurements. "
            "Cache memory is neither allocator-reserved nor driver-allocated memory."
        )
    else:
        st.info("MLX Metal memory is unavailable for the selected runs.")
    if sampled:
        st.subheader("Sampled and host readings")
        st.plotly_chart(
            px.line(sampled, x="step", y="value", color="run_id", facet_row="name")
            .update_yaxes(matches=None)
            .update_layout(
                height=max(350, 220 * len({point["name"] for point in sampled}))
            ),
            width="stretch",
        )
        st.caption(
            "Sampled device peaks are lower bounds; host RSS is not added to device capacity."
        )
    else:
        st.info("Sampled memory readings are unavailable for the selected runtime.")
    estimates = []
    for record in records:
        if record.run_id not in selected_ids:
            continue
        estimate = _estimate(record)
        if estimate:
            estimates.append(
                {
                    "run_id": record.run_id,
                    **{
                        label: _format_bytes(estimate.get(key))
                        for key, label in _ESTIMATE_BUCKETS
                    },
                    "result": estimate.get("result", "unavailable"),
                }
            )
    st.subheader("Disjoint estimated memory")
    if estimates:
        st.dataframe(estimates, width="stretch", hide_index=True)
    else:
        st.info("No persisted memory estimate is available for these runs.")
    with st.expander("Memory guide"):
        st.markdown(metric_help("memory"))


def _current_stages(
    rows: list[dict[str, object]], records: list[RunRecord]
) -> list[dict[str, object]]:
    latest: dict[str, dict[str, object]] = {}
    for row in rows:
        run_id = str(row["run_id"])
        if run_id not in latest or int(row["sequence"]) > int(
            latest[run_id]["sequence"]
        ):
            latest[run_id] = row
    return [
        {
            "run_id": record.run_id,
            "run_status": record.status,
            "current_stage": latest.get(record.run_id, {}).get("stage", "unavailable"),
            "stage_status": latest.get(record.run_id, {}).get("status", "unavailable"),
            "step": latest.get(record.run_id, {}).get("step", "unavailable"),
            "tokens_seen": latest.get(record.run_id, {}).get(
                "tokens_seen", "unavailable"
            ),
            "started_at": latest.get(record.run_id, {}).get(
                "started_at", "unavailable"
            ),
            "last_run_update": record.updated_at,
            "last_run_update_age": _recorded_age(record.updated_at),
        }
        for record in records
    ]


def stage_view(view: DashboardSnapshot) -> None:
    st.header("Stages")
    records, selected_ids = selected(view)
    selected_records = [record for record in records if record.run_id in selected_ids]
    rows = _rows_for(view.stages, selected_ids)
    current = _current_stages(rows, selected_records)
    st.subheader("Current stage")
    if current:
        st.dataframe(current, width="stretch", hide_index=True)
        st.caption(
            "A silent RUNNING row remains RUNNING; the dashboard never infers completion "
            "from its age or from the presence of a checkpoint."
        )
    else:
        st.info("Select a run to show its recorded stage status.")
    st.subheader("Append-only stage intervals")
    if rows:
        st.dataframe(rows, width="stretch", hide_index=True)
    else:
        st.info("No stage intervals are persisted for the selected runs.")


def _checkpoint_directory(root: Path, row: dict[str, object]) -> Path:
    run_id, relative = row["run_id"], row["relative_path"]
    if (
        not isinstance(run_id, str)
        or Path(run_id).name != run_id
        or not isinstance(relative, str)
        or Path(relative).name != relative
    ):
        raise ValueError("unsafe projected checkpoint path")
    run = _safe_member(root, run_id)
    checkpoints = _safe_member(run, "checkpoints") if run is not None else None
    directory = _safe_member(checkpoints, relative) if checkpoints is not None else None
    if directory is None:
        raise ValueError("unsafe projected checkpoint path")
    return directory


def checkpoint_view(view: DashboardSnapshot, root: Path) -> None:
    st.header("Checkpoints")
    records, selected_ids = selected(view)
    rows = _rows_for(view.checkpoints, selected_ids)
    st.caption(
        "Stored verification describes save time, not current disk integrity. "
        "Local verification is read-only and timestamped; recheck after files change."
    )
    key = f"checkpoint_verification:{root.resolve()}"
    verified = st.session_state.setdefault(key, {})
    if rows and st.button("Verify selected checkpoint files"):
        with st.spinner("Verifying local checkpoint files"):
            for row in rows:
                identity = (row["run_id"], row["checkpoint_id"], row["digest"])
                try:
                    directory = _checkpoint_directory(root, row)
                    result = CheckpointManager(directory.parent.parent).verify(
                        directory,
                        require_training_state=row["resume_level"] != "weights_only",
                    )
                    valid, errors = result.valid, list(result.errors)
                    if valid:
                        manifest = json.loads((directory / "manifest.json").read_text())
                        if manifest.get("sha256") != row["digest"]:
                            valid = False
                            errors.append(
                                {
                                    "field": "projection",
                                    "reason": "checkpoint digest mismatch",
                                }
                            )
                except (OSError, ValueError, TypeError) as error:
                    valid, errors = False, [{"field": "path", "reason": str(error)}]
                verified[identity] = {
                    "session_verification": "verified" if valid else "invalid",
                    "checked_at": datetime.now(UTC).isoformat(),
                    "verification_errors": json.dumps(errors) if errors else None,
                }
    rows = [
        {
            "run_id": row["run_id"],
            "step": row["step"],
            **verified.get(
                (row["run_id"], row["checkpoint_id"], row["digest"]),
                {
                    "session_verification": "not checked",
                    "checked_at": None,
                    "verification_errors": None,
                },
            ),
            **row,
        }
        for row in rows
    ]
    if rows:
        checked = sum(row["session_verification"] != "not checked" for row in rows)
        invalid = sum(row["session_verification"] == "invalid" for row in rows)
        st.caption(
            f"Local file checks: {checked}/{len(rows)} checked; "
            f"{checked - invalid} verified; {invalid} invalid."
        )
        if invalid:
            st.error(f"{invalid} checkpoint generation(s) failed local verification.")
        st.dataframe(rows, width="stretch", hide_index=True)
        local_best: list[dict[str, object]] = []
        for run_id in selected_ids:
            candidates = [
                row
                for row in rows
                if row["run_id"] == run_id
                and row["verification_status"] == "verified"
                and row["session_verification"] == "verified"
                and isinstance(row["validation_loss"], (int, float))
            ]
            if candidates:
                best = min(
                    candidates,
                    key=lambda row: (
                        float(row["validation_loss"]),
                        int(row["step"]),
                        str(row["checkpoint_id"]),
                    ),
                )
                local_best.append(
                    {
                        "run_id": run_id,
                        "local_best_checkpoint": best["checkpoint_id"],
                        "validation_loss": best["validation_loss"],
                        "available_locally": True,
                        "verified_locally_at": best["checked_at"],
                    }
                )
            else:
                local_best.append(
                    {
                        "run_id": run_id,
                        "local_best_checkpoint": None,
                        "validation_loss": None,
                        "available_locally": None,
                        "verified_locally_at": None,
                    }
                )
        st.subheader("Local best")
        st.caption(
            "Only generations verified in this session are eligible; blank means no verified candidate."
        )
        st.dataframe(local_best, width="stretch", hide_index=True)
    else:
        st.info(
            "No checkpoint projection is available for these legacy or not-yet-checkpointed runs."
        )
    parents = []
    metadata_by_run = {record.run_id: record.metadata for record in records}
    for run_id in selected_ids:
        manifest = view.manifests.get(run_id, {})
        parents.append(
            {
                "run_id": run_id,
                "continuation_kind": manifest.get("continuation_kind", "unavailable"),
                "parent_run_id": manifest.get("parent_run_id"),
                "parent_checkpoint_sha256": manifest.get("checkpoint_sha256")
                or manifest.get("parent_checkpoint_sha256")
                or _as_object(metadata_by_run.get(run_id)).get("checkpoint_sha256"),
            }
        )
    st.subheader("Parent checkpoint identity")
    st.dataframe(parents, width="stretch", hide_index=True)
    lineage = []
    for record in records:
        if record.run_id not in selected_ids:
            continue
        value = record.metadata.get("lineage_best")
        if isinstance(value, dict):
            lineage.append(
                {
                    "run_id": record.run_id,
                    **value,
                    "availability": "ancestor metadata; local generation may be unavailable",
                }
            )
    st.subheader("Ancestor lineage best")
    if lineage:
        st.dataframe(lineage, width="stretch", hide_index=True)
    else:
        st.info("No ancestor lineage-best metadata is recorded.")
    with st.expander("Checkpoint guide"):
        st.markdown(metric_help("checkpoints"))


def learn() -> None:
    learn_page()
    st.subheader("Runtime guides")
    guides = {
        "Runtime and precision": "runtime",
        "Training memory": "memory",
        "Activation recomputation": "recomputation",
        "Optimizer and learning rate": "learning-rate",
        "Gradient accumulation": "accumulation",
        "Disk checkpoints and lineage": "checkpoints",
        "Activation offload": "offload",
        "Independent workers boundary": "independent-workers",
    }
    search = (
        st.text_input("Search runtime guides", key="learn_guide_search").strip().lower()
    )
    for title, slug in guides.items():
        body = metric_help(slug)
        if search and search not in title.lower() and search not in body.lower():
            continue
        with st.expander(title, expanded=bool(search)):
            st.markdown(body)


def _read_snapshot(
    root: Path,
) -> tuple[DashboardSnapshot | None, datetime | None, str | None]:
    key = f"dashboard_snapshot:{root.resolve()}"
    try:
        fresh = snapshot(root)
    except (OSError, sqlite3.Error, ValueError) as error:
        previous = st.session_state.get(key)
        if previous is None:
            return None, None, str(error)
        view, observed_at = previous
        return view, observed_at, str(error)
    observed_at = datetime.now(UTC)
    st.session_state[key] = (fresh, observed_at)
    return fresh, observed_at, None


@st.fragment(run_every=2)
def render(root: Path, page: str) -> None:
    if st.button("Refresh now", key="dashboard_refresh"):
        st.rerun()
    view, observed_at, error = _read_snapshot(root)
    if view is None:
        st.error(f"Dashboard could not read the run store: {error}")
        return
    assert observed_at is not None
    if error:
        st.error(f"Showing stale data ({_observation_age(observed_at)} old): {error}")
    else:
        st.caption(
            f"Last observed {_observation_age(observed_at)} ago. Refreshes every 2 seconds."
        )
    _selection_controls(root)
    pages = {
        "overview": overview,
        "training": training,
        "evaluation": evaluation,
        "architecture": architecture_diagnostics,
        "runtime": runtime_view,
        "memory": memory_view,
        "checkpoints": lambda value: checkpoint_view(value, root),
        "stages": stage_view,
    }
    pages[page](view)


def _run_page(root: Path, page: str) -> None:
    """Keep run views unavailable until a read-only projection exists."""
    key = f"dashboard_snapshot:{root.resolve()}"
    if not (root / "experiments.sqlite3").is_file() and key not in st.session_state:
        st.info("No runs yet. Run `sparselab train CONFIG --run-id NAME`.")
        return
    render(root, page)


def main() -> None:
    st.set_page_config(page_title="SparseLab", layout="wide")
    st.title("Tiny Sparse Lab")
    args = arguments()
    root = Path(args.runs_dir)
    reports_dir = Path(args.reports_dir)
    page = st.navigation(
        [
            st.Page(lambda: learn(), title="Learn", url_path="learn", default=True),
            st.Page(
                lambda: research_page(reports_dir),
                title="Research",
                url_path="research",
            ),
            st.Page(
                lambda: _run_page(root, "overview"),
                title="Overview",
                url_path="overview",
            ),
            st.Page(
                lambda: _run_page(root, "training"),
                title="Training",
                url_path="training",
            ),
            st.Page(
                lambda: _run_page(root, "evaluation"),
                title="Evaluation",
                url_path="evaluation",
            ),
            st.Page(
                lambda: _run_page(root, "architecture"),
                title="Architecture",
                url_path="architecture",
            ),
            st.Page(
                lambda: _run_page(root, "runtime"),
                title="Runtime",
                url_path="runtime",
            ),
            st.Page(
                lambda: _run_page(root, "memory"),
                title="Memory",
                url_path="memory",
            ),
            st.Page(
                lambda: _run_page(root, "checkpoints"),
                title="Checkpoints",
                url_path="checkpoints",
            ),
            st.Page(
                lambda: _run_page(root, "stages"),
                title="Stages",
                url_path="stages",
            ),
        ]
    )
    page.run()


if __name__ == "__main__":
    main()
