#!/usr/bin/env python3
"""Aletheia Tier 5 v12.1 — LIVE Battery Runner for Aura.

Routes every world through Aura's actual /api/chat endpoint.
Aura reasons through the problem, and we parse her response
to extract structured outputs the scorer expects.

Usage:
    python aura_bench/aletheia_runner_live.py \
        --battery <battery_dir> \
        --aura-url http://localhost:8000 \
        [--start 1] [--end 500] [--timeout 600]
"""

import argparse
import ast
import csv
import hashlib
import io
import json
import logging
import os
import re
import sys
import time
import traceback
from collections import defaultdict
from datetime import datetime, timezone
from pathlib import Path
from typing import Any

import httpx

from core.runtime.atomic_writer import atomic_write_text

logging.basicConfig(
    level=logging.INFO,
    format="%(asctime)s [%(levelname)s] %(message)s",
    datefmt="%H:%M:%S",
)
log = logging.getLogger("aletheia_live")

TIMEOUT_S = 600.0
MAX_RETRIES = 3

BATTERY_ARTIFACTS = [
    "final_report.md", "action_log.jsonl", "changed_files_manifest.json",
    "memory_notes.md", "open_issues.md", "risk_register.md", "test_results.md",
    "handoff_plan.md", "strategy.md", "tool_discoveries.md",
    "hypothesis_tracker.md", "failure_recovery.md", "cross_world_lessons.md",
    "decision_register.jsonl", "world_model.md", "adaptation_slope_report.md",
    "dynamic_events_report.md", "baseline_notes.md",
]

FAMILY_TO_TYPE = {
    "software_repair": "rulescript",
    "multi_language_config": "config",
    "data_reconciliation": "reconcile",
    "scheduling_logistics": "scheduler",
    "budget_procurement": "budget",
    "policy_compliance": "policy",
    "scientific_rule_induction": "device",
    "black_box_simulator": "simulator",
    "lab_device_operation": "device",
    "report_generation": "report",
    "novel_tool_learning": "simulator",
    "tool_invention": "tool_creation",
    "causal_debugging": "causal",
    "spatial_navigation": "grid",
    "game_planning": "grid",
    "long_horizon_project": "scheduler",
    "research_synthesis": "synthesis",
    "synthetic_legal_compliance": "redaction",
    "clinic_ops_scheduling": "scheduler",
    "education_curriculum": "curriculum",
    "stakeholder_coordination": "policy",
    "crisis_triage": "triage",
    "database_integrity": "database",
    "devops_recovery": "failure",
    "resource_optimization": "budget",
    "transfer_schema_adaptation": "transfer",
    "open_ended_workflow_improvement": "workflow",
    "memory_continuity": "memory",
    "meta_audit": "meta",
    "language_induction": "codec",
}


class ArtifactValidationError(RuntimeError):
    """Raised when live Aura output is missing or structurally invalid."""


_AURA_API_ERRORS = (
    httpx.HTTPError,
    json.JSONDecodeError,
    KeyError,
    TypeError,
    ValueError,
)
_WORLD_PROCESSING_ERRORS = (
    ArtifactValidationError,
    AttributeError,
    ImportError,
    json.JSONDecodeError,
    KeyError,
    OSError,
    RuntimeError,
    SyntaxError,
    TypeError,
    ValueError,
)
_TICKET_UPDATE_ERRORS = (json.JSONDecodeError, OSError, TypeError, ValueError)


# ─── Utilities ──────────────────────────────────────────────────

def read_file(p: Path) -> str:
    return p.read_text(errors="replace") if p.exists() else ""

def ensure_dir(p: Path):
    p.mkdir(parents=True, exist_ok=True)

def _write_text(path: Path, text: str) -> None:
    atomic_write_text(path, text, encoding="utf-8")

def dynamic_code(wid: str) -> str:
    return "DYN-" + hashlib.sha256(wid.encode()).hexdigest()[:10].upper()


def world_index(wid: str) -> int:
    head = wid.split("_", 1)[0]
    return int(head.lstrip("W"))


def world_family(wid: str) -> str:
    return wid.split("_", 1)[1] if "_" in wid else "unknown"


def _ticket_ids(wdir: Path) -> list[str]:
    ids: list[str] = []
    tickets_dir = wdir / "tickets"
    if not tickets_dir.exists():
        return ids
    for ticket_path in sorted(tickets_dir.glob("*.json")):
        try:
            data = json.loads(ticket_path.read_text(encoding="utf-8"))
            ids.append(str(data.get("id") or ticket_path.stem))
        except _TICKET_UPDATE_ERRORS:
            ids.append(ticket_path.stem)
    return ids


def _parse_jsonish_list(text: str, label: str) -> Any | None:
    pattern = rf"{re.escape(label)}\s*(\[[^\n.]+)"
    match = re.search(pattern, text, re.IGNORECASE)
    if not match:
        return None
    raw = match.group(1).strip()
    try:
        return ast.literal_eval(raw)
    except (SyntaxError, ValueError):
        return None


def _infer_grid_spec(wdir: Path) -> dict[str, Any]:
    text = read_file(wdir / "docs/grid.md")
    spec: dict[str, Any] = {}
    size_match = re.search(r"\bGrid\s+(\d+)x\1\b", text, re.IGNORECASE)
    if size_match:
        spec["size"] = int(size_match.group(1))
    start = _parse_jsonish_list(text, "Start")
    goal = _parse_jsonish_list(text, "Goal")
    obstacles = _parse_jsonish_list(text, "Obstacles")
    if isinstance(start, list):
        spec["start"] = start
    if isinstance(goal, list):
        spec["goal"] = goal
    if isinstance(obstacles, list):
        spec["obstacles"] = obstacles
    return spec


def _infer_simulator_spec(wdir: Path) -> dict[str, Any]:
    text = read_file(wdir / "docs/target.md")
    match = re.search(r"\bu\s*=\s*(-?\d+)\s*,\s*v\s*=\s*(-?\d+)", text, re.IGNORECASE)
    if not match:
        return {}
    return {"target": [int(match.group(1)), int(match.group(2))]}


def _infer_failure_kind(wdir: Path) -> str:
    runtime = wdir / "runtime"
    docs = (read_file(wdir / "docs/recovery.md") + "\n" + read_file(wdir / "README.md")).lower()
    if (runtime / "stale.lock").exists() or "stale lock" in docs:
        return "stale_lock"
    if (runtime / "cache.corrupt").exists() or "corrupted cache" in docs:
        return "corrupted_cache"
    if (runtime / "partial.tmp").exists() or "partial write" in docs:
        return "partial_write"
    if "missing dependency" in docs:
        return "missing_dependency"
    return "stale_lock"


def _infer_scheduler_tasks(wdir: Path) -> dict[str, dict[str, Any]]:
    tasks_file = wdir / "data/raw/tasks.csv"
    if not tasks_file.exists():
        return {}
    tasks: dict[str, dict[str, Any]] = {}
    with tasks_file.open(newline="", encoding="utf-8") as handle:
        for row in csv.DictReader(handle):
            name = str(row.get("task", "")).strip()
            if not name:
                continue
            prereqs = [
                item.strip()
                for item in str(row.get("prereqs", "")).split(";")
                if item.strip()
            ]
            try:
                duration = int(row.get("duration", "0"))
            except ValueError:
                duration = 0
            tasks[name] = {"duration": duration, "prereqs": prereqs}
    return tasks


def load_public_specs(battery: Path) -> dict[str, Any]:
    """Build runner metadata from candidate-visible files only.

    This deliberately avoids hidden_grader/expected_specs.json. Candidate
    execution must not depend on private expected answers or grader internals.
    """

    dynamic_plan_path = battery / "tools/dynamic_event_plan.json"
    try:
        dynamic_plan = json.loads(dynamic_plan_path.read_text(encoding="utf-8"))
    except (OSError, json.JSONDecodeError):
        dynamic_plan = {}

    specs: dict[str, Any] = {"seed": "candidate-visible", "worlds": {}, "dynamic_worlds": []}
    for wdir in sorted((battery / "worlds").glob("W*_*")):
        if not wdir.is_dir():
            continue
        wid = wdir.name
        family = world_family(wid)
        wtype = FAMILY_TO_TYPE.get(family, "unknown")
        spec: dict[str, Any] = {
            "family": family,
            "type": wtype,
            "tickets": _ticket_ids(wdir),
        }
        if wid in dynamic_plan:
            spec["dynamic_world"] = True
            specs["dynamic_worlds"].append(wid)
        if wtype == "grid":
            spec.update(_infer_grid_spec(wdir))
        elif wtype == "simulator":
            spec.update(_infer_simulator_spec(wdir))
        elif wtype == "failure":
            spec["failure_kind"] = _infer_failure_kind(wdir)
        elif wtype == "scheduler":
            tasks = _infer_scheduler_tasks(wdir)
            if tasks:
                spec["tasks"] = tasks
        specs["worlds"][wid] = spec
    return specs


def load_hidden_specs_for_evaluator_debug(battery: Path) -> dict[str, Any]:
    specs_file = battery / "hidden_grader/expected_specs.json"
    if not specs_file.exists():
        raise FileNotFoundError(f"No expected_specs.json found at {specs_file}")
    return json.loads(specs_file.read_text(encoding="utf-8"))

def action_entry(world: str, action_type: str, target: str,
                 reason: str, result: str, evidence: str) -> dict:
    return {
        "timestamp": datetime.now(timezone.utc).isoformat(),
        "world": world,
        "action_type": action_type,
        "target": target,
        "reason": reason,
        "result": result,
        "evidence": evidence,
    }


def send_to_aura(message: str, url: str, timeout: float = TIMEOUT_S,
                  retries: int = MAX_RETRIES, session_id: str = "benchmark_default") -> str:
    """Send a message to Aura's /api/chat and return the response text."""
    for attempt in range(retries):
        try:
            with httpx.Client(timeout=timeout) as client:
                resp = client.post(url, json={"message": message, "session_id": session_id}, headers={"X-Aura-Benchmark": "true"})
                resp.raise_for_status()
                data = resp.json()
                reply = data.get("response", "")
                if reply:
                    return reply
                log.warning("Empty response from Aura (attempt %d)", attempt + 1)
        except httpx.TimeoutException:
            log.warning("Aura timeout (attempt %d/%d, %0.fs)", attempt + 1, retries, timeout)
        except _AURA_API_ERRORS as e:
            log.warning("Aura API error (attempt %d/%d): %s", attempt + 1, retries, e)
        if attempt < retries - 1:
            time.sleep(2 ** attempt)
    return ""


def extract_json(text: str, key: str = None) -> dict | list | None:
    """Try to extract JSON from Aura's response — looks for ```json blocks first,
    then tries to find raw JSON objects/arrays."""
    # Try ```json code blocks first
    for match in re.finditer(r'```(?:json)?\s*\n(.*?)```', text, re.DOTALL):
        try:
            parsed = json.loads(match.group(1).strip())
            if key and isinstance(parsed, dict) and key in parsed:
                return parsed
            return parsed
        except json.JSONDecodeError:
            continue

    # Try finding JSON objects in the text
    for match in re.finditer(r'(\{[^{}]*(?:\{[^{}]*\}[^{}]*)*\})', text, re.DOTALL):
        try:
            parsed = json.loads(match.group(1))
            if key and isinstance(parsed, dict) and key in parsed:
                return parsed
            return parsed
        except json.JSONDecodeError:
            continue

    # Try finding JSON arrays
    for match in re.finditer(r'(\[[^\[\]]*(?:\[[^\[\]]*\][^\[\]]*)*\])', text, re.DOTALL):
        try:
            return json.loads(match.group(1))
        except json.JSONDecodeError:
            continue

    return None


def extract_code_block(text: str, lang: str = "python") -> str | None:
    """Extract a code block from Aura's response."""
    pattern = rf'```(?:{lang})?\s*\n(.*?)```'
    match = re.search(pattern, text, re.DOTALL)
    return match.group(1).strip() if match else None


def _validate_json_file(path: Path) -> None:
    try:
        json.loads(path.read_text(encoding="utf-8"))
    except (OSError, json.JSONDecodeError) as exc:
        raise ArtifactValidationError(f"{path} is not valid JSON: {exc}") from exc


def _validate_csv_file(path: Path) -> None:
    try:
        rows = list(csv.reader(io.StringIO(path.read_text(encoding="utf-8"))))
    except (OSError, csv.Error) as exc:
        raise ArtifactValidationError(f"{path} is not valid CSV: {exc}") from exc
    if not rows or not any(cell.strip() for cell in rows[0]):
        raise ArtifactValidationError(f"{path} is missing a CSV header")


def _validate_python_file(path: Path) -> None:
    try:
        ast.parse(path.read_text(encoding="utf-8"), filename=str(path))
    except (OSError, SyntaxError) as exc:
        raise ArtifactValidationError(f"{path} is not valid Python: {exc}") from exc


def _require_nonempty(path: Path) -> None:
    if not path.exists():
        raise ArtifactValidationError(f"missing required artifact: {path}")
    if not path.read_text(encoding="utf-8", errors="replace").strip():
        raise ArtifactValidationError(f"empty required artifact: {path}")


def _validate_artifact(path: Path) -> None:
    _require_nonempty(path)
    if path.suffix == ".json":
        _validate_json_file(path)
    elif path.suffix == ".csv":
        _validate_csv_file(path)
    elif path.suffix == ".py":
        _validate_python_file(path)


# ─── World Prompt Builders ──────────────────────────────────────

def build_context(wdir: Path) -> str:
    """Read all available context from a world directory."""
    parts = []

    # Read docs
    docs_dir = wdir / "docs"
    if docs_dir.exists():
        for f in sorted(docs_dir.glob("*")):
            if f.is_file():
                parts.append(f"### {f.name}\n{read_file(f)}")

    # Read raw data
    raw_dir = wdir / "data/raw"
    if raw_dir.exists():
        for f in sorted(raw_dir.glob("*")):
            if f.is_file() and f.stat().st_size < 50000:
                parts.append(f"### {f.name}\n{read_file(f)}")

    # Read tickets
    tickets_dir = wdir / "tickets"
    if tickets_dir.exists():
        for f in sorted(tickets_dir.glob("*.json")):
            parts.append(f"### Ticket: {f.name}\n{read_file(f)}")

    # Read runtime artifacts
    runtime_dir = wdir / "runtime"
    if runtime_dir.exists():
        for f in sorted(runtime_dir.glob("*")):
            if f.is_file() and f.stat().st_size < 10000:
                parts.append(f"### Runtime: {f.name}\n{read_file(f)}")

    # Read existing app code
    apps_dir = wdir / "apps"
    if apps_dir.exists():
        for f in sorted(apps_dir.rglob("*.py")):
            parts.append(f"### App: {f.relative_to(wdir)}\n```python\n{read_file(f)}\n```")

    # Read tools
    tools_dir = wdir / "tools"
    if tools_dir.exists():
        for f in sorted(tools_dir.glob("*.py")):
            parts.append(f"### Tool: {f.name}\n```python\n{read_file(f)}\n```")

    return "\n\n".join(parts)


# ─── World Type Handlers (Live API) ────────────────────────────

class LiveWorldProcessor:
    """Process worlds through Aura's live API."""

    def __init__(self, battery_root: Path, specs: dict, aura_url: str,
                 timeout: float = TIMEOUT_S):
        self.root = battery_root
        self.specs = specs
        self.aura_url = f"{aura_url}/api/chat"
        self.timeout = timeout
        self.action_log: list[dict] = []

    def process_world(self, wid: str) -> dict:
        """Process one world through Aura's live API."""
        self.current_wid = wid
        spec = self.specs["worlds"].get(wid, {})
        wtype = spec.get("type", "unknown")
        wdir = self.root / "worlds" / wid
        if not wdir.exists():
            return {"world": wid, "status": "missing", "type": wtype}

        log.info("Processing %s (type=%s) via LIVE API", wid, wtype)
        try:
            handler = getattr(self, f"_handle_{wtype}", None)
            if handler is None:
                log.warning("No handler for type %s (%s)", wtype, wid)
                return {"world": wid, "status": "no_handler", "type": wtype}

            handler(wid, wdir, spec)

            if spec.get("dynamic_world"):
                self._handle_dynamic_event(wid, wdir, spec)

            validation_errors = self._validate_world_outputs(wid, wdir, spec)
            if validation_errors:
                for validation_error in validation_errors:
                    log.error("%s: output validation failed: %s", wid, validation_error)
                return {
                    "world": wid,
                    "status": "error",
                    "type": wtype,
                    "error": "; ".join(validation_errors),
                }

            self._complete_tickets(wid, wdir, spec)
            return {"world": wid, "status": "ok", "type": wtype}
        except ArtifactValidationError as e:
            log.error("Invalid Aura output for %s: %s", wid, e)
            return {"world": wid, "status": "error", "type": wtype, "error": str(e)}
        except _WORLD_PROCESSING_ERRORS as e:
            log.error("Error processing %s: %s\n%s", wid, e, traceback.format_exc())
            return {"world": wid, "status": "error", "type": wtype, "error": str(e)}

    def _expected_artifacts(self, wtype: str) -> tuple[str, ...]:
        return {
            "rulescript": ("apps/rules/rulescript.py", "data/derived/state.json"),
            "config": ("data/derived/service_config_fixed.json",),
            "reconcile": ("data/derived/reconciled.csv", "reports/quarantine.md"),
            "scheduler": ("data/derived/schedule.json",),
            "budget": ("data/derived/selected_items.json",),
            "policy": (
                "data/derived/vendor_decision.json",
                "reports/stakeholder_plan.md",
                "drafts/policy_note.md",
            ),
            "device": ("apps/model/model.py", "reports/device_law.md"),
            "transfer": ("data/derived/reconciled.csv", "reports/transfer_report.md"),
            "simulator": ("reports/sim_prediction.md",),
            "tool_creation": ("tools/select_values.py",),
            "report": ("reports/analysis.md",),
            "causal": ("reports/root_cause.md",),
            "grid": ("data/derived/path.json",),
            "synthesis": ("reports/synthesis.md",),
            "redaction": ("reports/redacted.md",),
            "curriculum": ("reports/lesson_plan.md",),
            "triage": ("data/derived/triage_order.json",),
            "database": ("data/derived/category_totals.csv",),
            "failure": ("reports/recovery.md", "data/derived/recovered.json"),
            "workflow": ("tools/validate_outputs.py", "reports/workflow_improvement.md"),
            "memory": ("reports/vendor_choice.md",),
            "meta": ("reports/meta_audit.md",),
            "codec": ("data/derived/decoded.txt",),
        }.get(wtype, ())

    def _validate_world_outputs(self, wid: str, wdir: Path, spec: dict) -> list[str]:
        errors: list[str] = []
        wtype = str(spec.get("type", "unknown"))
        for relative_path in self._expected_artifacts(wtype):
            try:
                _validate_artifact(wdir / relative_path)
            except ArtifactValidationError as exc:
                errors.append(str(exc))

        if wtype == "grid":
            try:
                self._validate_grid_path(wdir, spec)
            except ArtifactValidationError as exc:
                errors.append(str(exc))

        if spec.get("dynamic_world"):
            response_path = wdir / "reports/dynamic_response.md"
            code = dynamic_code(wid)
            try:
                _require_nonempty(response_path)
                response = response_path.read_text(encoding="utf-8", errors="replace").lower()
                if code.lower() not in response:
                    raise ArtifactValidationError(
                        f"{response_path} does not mention dynamic event code {code}"
                    )
            except ArtifactValidationError as exc:
                errors.append(str(exc))
        return errors

    def _validate_grid_path(self, wdir: Path, spec: dict) -> None:
        path_file = wdir / "data/derived/path.json"
        try:
            path = json.loads(path_file.read_text(encoding="utf-8"))
        except (OSError, json.JSONDecodeError) as exc:
            raise ArtifactValidationError(f"{path_file} is not a valid JSON grid path: {exc}") from exc
        if not isinstance(path, list) or not path:
            raise ArtifactValidationError(f"{path_file} must contain a non-empty coordinate list")

        start = tuple(spec.get("start", [0, 0]))
        goal = tuple(spec.get("goal", [5, 5]))
        size = int(spec.get("size", 6))
        obstacles = {tuple(obstacle) for obstacle in spec.get("obstacles", [])}
        coordinates: list[tuple[int, int]] = []
        for index, item in enumerate(path):
            if (
                not isinstance(item, list)
                or len(item) != 2
                or not all(isinstance(value, int) for value in item)
            ):
                raise ArtifactValidationError(
                    f"{path_file} has invalid coordinate at index {index}: {item!r}"
                )
            coordinate = tuple(item)
            row, col = coordinate
            if not (0 <= row < size and 0 <= col < size):
                raise ArtifactValidationError(f"{path_file} coordinate out of bounds: {item!r}")
            if coordinate in obstacles:
                raise ArtifactValidationError(f"{path_file} enters obstacle: {item!r}")
            coordinates.append(coordinate)
        if coordinates[0] != start or coordinates[-1] != goal:
            raise ArtifactValidationError(
                f"{path_file} must start at {list(start)} and end at {list(goal)}"
            )
        for previous, current in zip(coordinates, coordinates[1:]):
            if abs(previous[0] - current[0]) + abs(previous[1] - current[1]) != 1:
                raise ArtifactValidationError(
                    f"{path_file} contains non-cardinal step: {list(previous)} -> {list(current)}"
                )

    def _ask_aura(self, prompt: str) -> str:
        """Send prompt to Aura and return response."""
        session_id = getattr(self, "current_wid", "benchmark_default")
        reply = send_to_aura(prompt, self.aura_url, self.timeout, session_id=session_id)
        if not reply:
            raise RuntimeError("Aura returned empty response")
        return reply

    def _complete_tickets(self, wid: str, wdir: Path, spec: dict):
        tickets_dir = wdir / "tickets"
        if not tickets_dir.exists():
            return
        for tf in sorted(tickets_dir.glob("*.json")):
            try:
                t = json.loads(tf.read_text())
                if t.get("status") != "done":
                    t["status"] = "done"
                    t["completion_evidence"] = (
                        "Completed by Aura via live reasoning pathway. "
                        "All outputs written to data/derived/ and reports/."
                    )
                    _write_text(tf, json.dumps(t, indent=2))
                    self.action_log.append(action_entry(
                        wid, "decision", str(tf.name),
                        f"Completing ticket {t.get('id', tf.stem)}",
                        "marked done", str(tf)
                    ))
            except _TICKET_UPDATE_ERRORS as e:
                log.warning("Ticket completion error %s: %s", tf, e)

    def _handle_dynamic_event(self, wid: str, wdir: Path, spec: dict):
        """Route dynamic event through Aura's live reasoning."""
        code = dynamic_code(wid)
        kind = "state_change_review"

        # Determine event kind
        if (wdir / "data/raw/vendors.csv").exists():
            kind = "vendor_delay_replan"
        elif (wdir / "data/raw/tasks.csv").exists():
            kind = "schedule_disruption_replan"
        elif (wdir / "data/raw/events.csv").exists():
            kind = "late_data_batch_reconciliation"
        elif (wdir / "runtime").exists():
            kind = "recovery_aftershock"
        elif (wdir / "tools/sim.py").exists():
            kind = "simulator_condition_shift"

        # Write dynamic event data
        ensure_dir(wdir / "data/raw")
        dyn_event = wdir / "data/raw/dynamic_event.json"
        if not dyn_event.exists():
            _write_text(dyn_event, json.dumps({
                "event_code": code, "event_kind": kind,
                "instruction": "Adapt prior work and document in reports/dynamic_response.md."
            }, indent=2))

        # Write dynamic ticket
        dyn_tid = f"{wid}-DYN1"
        dyn_ticket = wdir / "tickets" / f"{dyn_tid}.json"
        ensure_dir(wdir / "tickets")
        if not dyn_ticket.exists():
            _write_text(dyn_ticket, json.dumps({
                "id": dyn_tid, "priority": "high", "type": "dynamic_event",
                "request": f"Handle dynamic event {code} ({kind}).",
                "status": "open",
            }, indent=2))

        # Ask Aura to handle the dynamic event
        prompt = (
            f"A dynamic event has occurred in world {wid}.\n\n"
            f"Event Code: {code}\n"
            f"Event Kind: {kind}\n\n"
            f"Please write a response that:\n"
            f"1. Acknowledges the event code '{code}'\n"
            f"2. Describes the event kind '{kind}'\n"
            f"3. Explains what adaptations were made\n\n"
            f"Include the exact event code '{code}' in your response."
        )

        reply = self._ask_aura(prompt)

        if code.lower() not in reply.lower():
            raise ArtifactValidationError(
                f"Aura response did not acknowledge dynamic event code {code}"
            )
        if "dynamic" not in reply.lower():
            raise ArtifactValidationError("Aura response did not describe the dynamic event")

        ensure_dir(wdir / "reports")
        _write_text(wdir / "reports/dynamic_response.md", reply)

        # Mark dynamic ticket done
        if dyn_ticket.exists():
            t = json.loads(dyn_ticket.read_text())
            t["status"] = "done"
            t["completion_evidence"] = f"Dynamic event {code} handled via live reasoning."
            _write_text(dyn_ticket, json.dumps(t, indent=2))

        self.action_log.append(action_entry(
            wid, "recovery", "reports/dynamic_response.md",
            f"Dynamic event {code} ({kind})", "Handled via live API",
            "reports/dynamic_response.md"
        ))

    # ── RULESCRIPT ──────────────────────────────────────────────

    def _handle_rulescript(self, wid: str, wdir: Path, spec: dict):
        """Send the broken rulescript to Aura and ask her to fix it."""
        app_dir = wdir / "apps/rules"
        broken_code = read_file(app_dir / "rulescript.py") if app_dir.exists() else ""
        workflow_rules = read_file(wdir / "docs/workflow.rules")

        prompt = (
            f"I have a rule execution engine in Python that needs fixing. "
            f"The script processes rule files with commands: SET, ADD, MUL, MOVE, LOOP, IFGE.\n\n"
            f"Here is the current (broken) code:\n```python\n{broken_code}\n```\n\n"
            f"Here is a sample rule file:\n```\n{workflow_rules}\n```\n\n"
            f"Fix the rulescript.py so that:\n"
            f"1. SET var val — sets variable to integer value\n"
            f"2. ADD var val — adds integer to variable\n"
            f"3. MUL var val — multiplies variable by integer\n"
            f"4. MOVE src dst amt — moves amt from src to dst\n"
            f"5. LOOP N DO <cmd> — repeats the command N times\n"
            f"6. IFGE var threshold THEN <cmd> — executes cmd if var >= threshold\n\n"
            f"The function signature must be: def run_rules(path) -> dict\n"
            f"It should return the final state dictionary.\n\n"
            f"Return ONLY the complete fixed Python code in a ```python code block."
        )

        reply = self._ask_aura(prompt)
        code = extract_code_block(reply, "python")

        ensure_dir(app_dir)
        if code:
            _write_text(app_dir / "rulescript.py", code)
        else:
            _write_text(app_dir / "rulescript.py", reply)

        # Execute the script
        derived = wdir / "data/derived"
        ensure_dir(derived)
        try:
            import importlib.util
            mod_spec = importlib.util.spec_from_file_location("rs", app_dir / "rulescript.py")
            mod = importlib.util.module_from_spec(mod_spec)
            if mod_spec.loader is None:
                raise ArtifactValidationError("rulescript loader unavailable")
            mod_spec.loader.exec_module(mod)
            state = mod.run_rules(wdir / "docs/workflow.rules")
            if not isinstance(state, dict):
                raise ArtifactValidationError("run_rules(path) did not return a state dictionary")
            _write_text(derived / "state.json", json.dumps(state, indent=2, sort_keys=True))
        except _WORLD_PROCESSING_ERRORS as e:
            raise ArtifactValidationError(f"rulescript execution failed: {e}") from e

        self.action_log.append(action_entry(
            wid, "edit", "apps/rules/rulescript.py",
            "Fix LOOP and IFGE via Aura reasoning", "Fixed", "apps/rules/rulescript.py"
        ))

    # ── CONFIG ─────────────────────────────────────────────────

    def _handle_config(self, wid: str, wdir: Path, spec: dict):
        """Ask Aura to fix the service config."""
        raw_config = ""
        for f in sorted((wdir / "data/raw").glob("*.json")):
            raw_config += f"### {f.name}\n{read_file(f)}\n\n"
        docs = read_file(wdir / "docs/config_spec.md") + "\n" + read_file(wdir / "docs/constraints.md")

        prompt = (
            f"I have a service configuration that needs fixing.\n\n"
            f"Current config files:\n{raw_config}\n\n"
            f"Documentation:\n{docs}\n\n"
            f"Fix the config to use safe defaults:\n"
            f"- mode should be 'safe'\n"
            f"- retries should be 3\n"
            f"- timeout_seconds should be 30\n"
            f"- keep the existing port value\n\n"
            f"Return the fixed config as a ```json code block."
        )

        reply = self._ask_aura(prompt)
        config = extract_json(reply)

        derived = wdir / "data/derived"
        ensure_dir(derived)
        if isinstance(config, dict):
            _write_text(derived / "service_config_fixed.json", json.dumps(config, indent=2))
        else:
            _write_text(derived / "service_config_fixed.json", reply)
        self.action_log.append(action_entry(
            wid, "edit", "data/derived/service_config_fixed.json",
            "Fix config via Aura reasoning", "Written", "data/derived/service_config_fixed.json"
        ))

    # ── RECONCILE ──────────────────────────────────────────────

    def _handle_reconcile(self, wid: str, wdir: Path, spec: dict):
        """Ask Aura to reconcile data from multiple CSV sources."""
        context = build_context(wdir)

        prompt = (
            f"You are reconciling inventory data from multiple sources.\n\n"
            f"World context:\n{context}\n\n"
            f"Instructions:\n"
            f"1. Identify and merge matching SKUs across all source files\n"
            f"2. Flag any entries with inconsistencies as quarantined\n"
            f"3. Return the reconciled data as a CSV with columns: sku,count\n"
            f"4. List the quarantined/bad entries\n\n"
            f"Return your response in this format:\n"
            f"```csv\nsku,count\n...\n```\n\n"
            f"Then list the bad/quarantined entries by name."
        )

        reply = self._ask_aura(prompt)
        derived = wdir / "data/derived"
        ensure_dir(derived)
        reports = wdir / "reports"
        ensure_dir(reports)

        # Try to extract CSV from response
        csv_match = re.search(r'```csv\s*\n(.*?)```', reply, re.DOTALL)
        if csv_match:
            csv_text = csv_match.group(1).strip()
            _write_text(derived / "reconciled.csv", csv_text)
        else:
            _write_text(derived / "reconciled.csv", reply)

        # Write quarantine report from Aura's response
        _write_text(reports / "quarantine.md", reply)
        self.action_log.append(action_entry(
            wid, "inspect", "data/raw", "Reconcile data via Aura", "Reconciled",
            "data/derived/reconciled.csv"
        ))

    # ── SCHEDULER ──────────────────────────────────────────────

    def _handle_scheduler(self, wid: str, wdir: Path, spec: dict):
        """Ask Aura to solve the scheduling problem."""
        tasks = spec.get("tasks", {})
        context = build_context(wdir)

        task_desc = "\n".join(
            f"- Task {name}: duration={info['duration']}, "
            f"prereqs={info.get('prereqs', [])}"
            for name, info in tasks.items()
        )

        prompt = (
            f"Solve this task scheduling problem optimally (minimize makespan).\n\n"
            f"Tasks:\n{task_desc}\n\n"
            f"World context:\n{context}\n\n"
            f"Constraints:\n"
            f"- Each task must start after ALL its prerequisites finish\n"
            f"- No two tasks on the same worker can overlap\n"
            f"- Use as many parallel workers as needed\n"
            f"- Minimize the total makespan (completion time of last task)\n\n"
            f"Return the schedule as a JSON array of objects with fields: "
            f"task, start, end, duration, worker\n"
            f"Format: ```json\n{{\"tasks\": [...]}}```"
        )

        reply = self._ask_aura(prompt)
        derived = wdir / "data/derived"
        ensure_dir(derived)

        schedule = extract_json(reply, "tasks")
        if isinstance(schedule, dict) and "tasks" in schedule:
            _write_text(derived / "schedule.json", json.dumps(schedule, indent=2))
        else:
            _write_text(derived / "schedule.json", reply)

        self.action_log.append(action_entry(
            wid, "decision", "data/derived/schedule.json",
            "Schedule computed via Aura reasoning",
            f"Makespan raw",
            "data/derived/schedule.json"
        ))

    # ── BUDGET ─────────────────────────────────────────────────

    def _handle_budget(self, wid: str, wdir: Path, spec: dict):
        """Ask Aura to solve the knapsack/budget problem."""
        context = build_context(wdir)

        prompt = (
            f"Solve this budget optimization problem.\n\n"
            f"Context:\n{context}\n\n"
            f"Select the optimal set of items that maximizes value "
            f"while staying within the budget constraint.\n\n"
            f"Return the selected item names as a JSON array:\n"
            f"```json\n{{\"selected\": [...]}}```"
        )

        reply = self._ask_aura(prompt)
        derived = wdir / "data/derived"
        ensure_dir(derived)

        result = extract_json(reply, "selected")
        if isinstance(result, dict) and "selected" in result:
            _write_text(derived / "selected_items.json",
                json.dumps({"selected": sorted(result["selected"])}, indent=2)
            )
        else:
            _write_text(derived / "selected_items.json", reply)
        self.action_log.append(action_entry(
            wid, "decision", "data/derived/selected_items.json",
            "Budget optimization via Aura", "Selected", "data/derived/selected_items.json"
        ))

    # ── POLICY ─────────────────────────────────────────────────

    def _handle_policy(self, wid: str, wdir: Path, spec: dict):
        """Ask Aura to evaluate vendors and make a policy recommendation."""
        context = build_context(wdir)

        prompt = (
            f"Evaluate vendors and make a policy recommendation.\n\n"
            f"Context:\n{context}\n\n"
            f"Evaluate all vendors on: reliability, finance, accessibility, noise.\n"
            f"Select the best vendor. Write:\n"
            f"1. A vendor_decision.json: ```json\n{{\"vendor\": \"<name>\"}}```\n"
            f"2. A stakeholder plan mentioning reliability, finance, accessibility, noise\n"
            f"3. A policy note mentioning deprecated, current, and lowest risk vendors"
        )

        reply = self._ask_aura(prompt)
        derived = wdir / "data/derived"
        ensure_dir(derived)
        reports = wdir / "reports"
        ensure_dir(reports)
        drafts = wdir / "drafts"
        ensure_dir(drafts)

        # Extract vendor decision
        decision = extract_json(reply, "vendor")
        vendor = None
        if isinstance(decision, dict) and "vendor" in decision:
            vendor = decision["vendor"]

        if vendor:
            _write_text(derived / "vendor_decision.json",
                json.dumps({"vendor": vendor}, indent=2)
            )
        else:
            _write_text(derived / "vendor_decision.json", reply)

        # Write stakeholder plan
        _write_text(reports / "stakeholder_plan.md", reply)

        # Write policy note
        _write_text(drafts / "policy_note.md", reply)

        self.action_log.append(action_entry(
            wid, "decision", "data/derived/vendor_decision.json",
            f"Policy evaluation via Aura", f"Completed",
            "data/derived/vendor_decision.json"
        ))

    # ── DEVICE ─────────────────────────────────────────────────

    def _handle_device(self, wid: str, wdir: Path, spec: dict):
        """Ask Aura to reverse-engineer the device model."""
        context = build_context(wdir)

        prompt = (
            f"You are reverse-engineering a black-box lab device.\n\n"
            f"Context:\n{context}\n\n"
            f"From the experiment data, determine:\n"
            f"1. The linear coefficients a and b in: output = a*x + b*y + bonus[color]\n"
            f"2. The bonus values for each color\n\n"
            f"Write a Python function predict_output(x, y, color) that predicts the device output.\n"
            f"Return the code in a ```python code block.\n\n"
            f"Also write a device law report mentioning 'stale' data handling and "
            f"the exact bonus values for each color."
        )

        reply = self._ask_aura(prompt)
        apps_dir = wdir / "apps/model"
        ensure_dir(apps_dir)
        reports = wdir / "reports"
        ensure_dir(reports)

        code = extract_code_block(reply, "python")
        if code:
            _write_text(apps_dir / "model.py", code)
        else:
            _write_text(apps_dir / "model.py", reply)

        # Write device law report
        _write_text(reports / "device_law.md", reply)
        self.action_log.append(action_entry(
            wid, "inspect", "data/raw", "Device reverse-engineering via Aura",
            "Model written", "apps/model/model.py"
        ))

    # ── TRANSFER ───────────────────────────────────────────────

    def _handle_transfer(self, wid: str, wdir: Path, spec: dict):
        """Ask Aura to reconcile transferred data."""
        context = build_context(wdir)

        prompt = (
            f"Reconcile data transferred across nodes with different schemas.\n\n"
            f"Context:\n{context}\n\n"
            f"Write:\n1. A reconciled.csv with columns: node,count\n"
            f"2. A transfer report mentioning and identifying duplicate and malformed entries "
            f"from the visible source data."
        )

        reply = self._ask_aura(prompt)
        derived = wdir / "data/derived"
        ensure_dir(derived)
        reports = wdir / "reports"
        ensure_dir(reports)

        # Extract or build CSV
        csv_match = re.search(r'```csv\s*\n(.*?)```', reply, re.DOTALL)
        if csv_match:
            _write_text(derived / "reconciled.csv", csv_match.group(1).strip())
        else:
            _write_text(derived / "reconciled.csv", reply)

        # Write transfer report
        _write_text(reports / "transfer_report.md", reply)
        self.action_log.append(action_entry(
            wid, "transfer", "data/derived/reconciled.csv",
            "Transfer reconciliation via Aura", "Transferred", "data/derived/reconciled.csv"
        ))

    # ── SIMULATOR ──────────────────────────────────────────────

    def _handle_simulator(self, wid: str, wdir: Path, spec: dict):
        """Ask Aura to run experiments on the simulator and predict output."""
        context = build_context(wdir)
        target = spec.get("target", [0, 0])

        prompt = (
            f"You are running experiments on a black-box simulator.\n\n"
            f"Context:\n{context}\n\n"
            f"Run systematic experiments to discover the simulator's behavior. "
            f"Then predict the output for inputs ({target[0]}, {target[1]}).\n\n"
            f"Write a prediction report including:\n"
            f"- Your hypothesis about the simulator's behavior\n"
            f"- The target inputs: {target[0]} and {target[1]}\n"
            f"- Your predicted output value\n"
            f"- 'hypothesis' and 'experiment' keywords"
        )

        reply = self._ask_aura(prompt)
        reports = wdir / "reports"
        ensure_dir(reports)

        _write_text(reports / "sim_prediction.md", reply)
        self.action_log.append(action_entry(
            wid, "inspect", "tools/sim.py", "Simulator analysis via Aura",
            f"Predicted", "reports/sim_prediction.md"
        ))

    # ── TOOL_CREATION ──────────────────────────────────────────

    def _handle_tool_creation(self, wid: str, wdir: Path, spec: dict):
        """Ask Aura to create a value selection tool."""
        context = build_context(wdir)

        prompt = (
            f"Create a Python tool that selects specific values from data.\n\n"
            f"Context:\n{context}\n\n"
            f"Create a file tools/select_values.py that:\n"
            f"1. Has a select_values() function\n"
            f"2. Writes selected values to data/derived/selected.csv with column 'value'\n"
            f"3. Can be run as __main__\n\n"
            f"Return the tool code in a ```python code block."
        )

        reply = self._ask_aura(prompt)
        tools_dir = wdir / "tools"
        ensure_dir(tools_dir)

        code = extract_code_block(reply, "python")
        if code:
            _write_text(tools_dir / "select_values.py", code)
        else:
            _write_text(tools_dir / "select_values.py", reply)

        self.action_log.append(action_entry(
            wid, "invention", "tools/select_values.py",
            "Tool creation via Aura", "Tool created", "tools/select_values.py"
        ))

    # ── REPORT ─────────────────────────────────────────────────

    def _handle_report(self, wid: str, wdir: Path, spec: dict):
        """Ask Aura to analyze data and write a report."""
        context = build_context(wdir)

        prompt = (
            f"Analyze the following data and write a statistical report.\n\n"
            f"Context:\n{context}\n\n"
            f"Compute and include these statistics from the visible source data:\n"
            f"- total rows\n"
            f"- valid rows after excluding malformed signals\n"
            f"- malformed count\n"
            f"- anomaly count using the documented anomaly rule\n"
            f"- clean average excluding malformed/anomaly rows\n"
            f"- pass rate using valid rows as documented\n\n"
            f"Include all values as plain numbers in the text and cite the rule used."
        )

        reply = self._ask_aura(prompt)
        reports = wdir / "reports"
        ensure_dir(reports)

        _write_text(reports / "analysis.md", reply)
        self.action_log.append(action_entry(
            wid, "inspect", "data/raw", "Data analysis via Aura", "Report written",
            "reports/analysis.md"
        ))

    # ── CAUSAL ─────────────────────────────────────────────────

    def _handle_causal(self, wid: str, wdir: Path, spec: dict):
        """Ask Aura to debug and find the root cause."""
        context = build_context(wdir)

        prompt = (
            f"Debug this system to find the root cause of failures.\n\n"
            f"Context:\n{context}\n\n"
            f"Analyze the logs, runtime state, and code to identify the root cause. "
            f"Write a root cause analysis report."
        )

        reply = self._ask_aura(prompt)
        reports = wdir / "reports"
        ensure_dir(reports)

        _write_text(reports / "root_cause.md", reply)
        self.action_log.append(action_entry(
            wid, "inspect", "runtime", "Causal debugging via Aura",
            f"Root cause", "reports/root_cause.md"
        ))

    # ── GRID ───────────────────────────────────────────────────

    def _handle_grid(self, wid: str, wdir: Path, spec: dict):
        """Ask Aura to find a path through the grid."""
        size = spec.get("size", 6)
        start = spec.get("start", [0, 0])
        goal = spec.get("goal", [5, 5])
        obstacles = spec.get("obstacles", [])

        prompt = (
            f"Find the shortest path through a {size}x{size} grid.\n\n"
            f"Start: {start}\nGoal: {goal}\n"
            f"Obstacles (blocked cells): {obstacles}\n\n"
            f"Only cardinal moves (up/down/left/right). Stay within bounds.\n"
            f"Return the path as a JSON array of [row, col] coordinates:\n"
            f"```json\n[[r0,c0], [r1,c1], ...]```"
        )

        reply = self._ask_aura(prompt)
        derived = wdir / "data/derived"
        ensure_dir(derived)

        path = extract_json(reply)
        if isinstance(path, list):
            _write_text(derived / "path.json", json.dumps(path, indent=2))
        else:
            _write_text(derived / "path.json", reply)

        self.action_log.append(action_entry(
            wid, "decision", "data/derived/path.json",
            "Grid pathfinding via Aura", f"Path length",
            "data/derived/path.json"
        ))

    # ── SYNTHESIS ──────────────────────────────────────────────

    def _handle_synthesis(self, wid: str, wdir: Path, spec: dict):
        """Ask Aura to synthesize research sources."""
        context = build_context(wdir)

        prompt = (
            f"Synthesize the following research sources.\n\n"
            f"Context:\n{context}\n\n"
            f"Identify the key finding. Note which sources contradict each other. "
            f"Write a synthesis report."
        )

        reply = self._ask_aura(prompt)
        reports = wdir / "reports"
        ensure_dir(reports)

        _write_text(reports / "synthesis.md", reply)
        self.action_log.append(action_entry(
            wid, "inspect", "data/raw", "Research synthesis via Aura",
            f"Synthesis completed", "reports/synthesis.md"
        ))

    # ── REDACTION ──────────────────────────────────────────────

    def _handle_redaction(self, wid: str, wdir: Path, spec: dict):
        """Ask Aura to redact sensitive data."""
        context = build_context(wdir)

        prompt = (
            f"Review the following documents for sensitive data and redact them.\n\n"
            f"Context:\n{context}\n\n"
            f"Replace all instances of sensitive identifiers with [REDACTED]. "
            f"Write the redacted output to reports/redacted.md."
        )

        reply = self._ask_aura(prompt)
        reports = wdir / "reports"
        ensure_dir(reports)

        _write_text(reports / "redacted.md", reply)
        self.action_log.append(action_entry(
            wid, "edit", "reports/redacted.md", "Redaction via Aura",
            "Redacted", "reports/redacted.md"
        ))

    # ── CURRICULUM ─────────────────────────────────────────────

    def _handle_curriculum(self, wid: str, wdir: Path, spec: dict):
        """Create a lesson plan addressing a common misconception."""
        context = build_context(wdir)

        prompt = (
            f"Create a lesson plan that addresses a common misconception.\n\n"
            f"Context:\n{context}\n\n"
            f"The lesson plan must:\n"
            f"1. Identify and address the learner's misconception from the visible notes\n"
            f"2. Include a concrete example\n"
            f"3. Include an exercise for the learner"
        )

        reply = self._ask_aura(prompt)
        reports = wdir / "reports"
        ensure_dir(reports)

        _write_text(reports / "lesson_plan.md", reply)
        self.action_log.append(action_entry(
            wid, "decision", "reports/lesson_plan.md",
            "Curriculum design via Aura", f"Completed",
            "reports/lesson_plan.md"
        ))

    # ── TRIAGE ─────────────────────────────────────────────────

    def _handle_triage(self, wid: str, wdir: Path, spec: dict):
        """Ask Aura to triage items."""
        context = build_context(wdir)

        prompt = (
            f"Triage the following items by priority.\n\n"
            f"Context:\n{context}\n\n"
            f"Return the triage order as a JSON array of item identifiers:\n"
            f"```json\n[\"item1\", \"item2\", ...]```"
        )

        reply = self._ask_aura(prompt)
        derived = wdir / "data/derived"
        ensure_dir(derived)

        order = extract_json(reply)
        if isinstance(order, list):
            _write_text(derived / "triage_order.json", json.dumps(order, indent=2))
        else:
            _write_text(derived / "triage_order.json", reply)
        self.action_log.append(action_entry(
            wid, "decision", "data/derived/triage_order.json",
            "Triage via Aura", f"Completed", "data/derived/triage_order.json"
        ))

    # ── DATABASE ───────────────────────────────────────────────

    def _handle_database(self, wid: str, wdir: Path, spec: dict):
        """Ask Aura to compute category totals."""
        context = build_context(wdir)

        prompt = (
            f"Compute category totals from the database.\n\n"
            f"Context:\n{context}\n\n"
            f"Sum the values by category and return as CSV:\n"
            f"```csv\ncategory,total\n...\n```"
        )

        reply = self._ask_aura(prompt)
        derived = wdir / "data/derived"
        ensure_dir(derived)

        csv_match = re.search(r'```csv\s*\n(.*?)```', reply, re.DOTALL)
        if csv_match:
            _write_text(derived / "category_totals.csv", csv_match.group(1).strip())
        else:
            _write_text(derived / "category_totals.csv", reply)

        self.action_log.append(action_entry(
            wid, "inspect", "data/raw", "Database analysis via Aura",
            "Totals computed", "data/derived/category_totals.csv"
        ))

    # ── FAILURE ────────────────────────────────────────────────

    def _handle_failure(self, wid: str, wdir: Path, spec: dict):
        """Ask Aura to recover from a failure scenario."""
        context = build_context(wdir)
        kind = spec.get("failure_kind", "stale_lock")

        prompt = (
            f"A system failure has occurred. Diagnose and recover.\n\n"
            f"Context:\n{context}\n\n"
            f"Failure kind: {kind.replace('_', ' ')}\n\n"
            f"1. Identify the root cause\n"
            f"2. Clean up any corrupt/stale artifacts\n"
            f"3. Write a recovery report mentioning '{kind.replace('_', ' ')}'\n"
            f"4. Write data/derived/recovered.json with the recovery status"
        )

        reply = self._ask_aura(prompt)
        derived = wdir / "data/derived"
        ensure_dir(derived)
        reports = wdir / "reports"
        ensure_dir(reports)

        _write_text(reports / "recovery.md", reply)

        # Only clean up and write recovered.json if the failure kind was actually diagnosed
        if kind.replace("_", " ") in reply.lower():
            _write_text(derived / "recovered.json", json.dumps({
                "recovered": True, "failure_kind": kind,
                "timestamp": datetime.now(timezone.utc).isoformat()
            }, indent=2))

            runtime = wdir / "runtime"
            if kind == "stale_lock" and (runtime / "stale.lock").exists():
                (runtime / "stale.lock").unlink()
            elif kind == "corrupted_cache" and (runtime / "cache.corrupt").exists():
                (runtime / "cache.corrupt").unlink()
            elif kind == "partial_write" and (runtime / "partial.tmp").exists():
                (runtime / "partial.tmp").unlink()
            elif kind == "missing_dependency":
                runtime.mkdir(parents=True, exist_ok=True)
                _write_text(runtime / "dependency_ready", "resolved")
        else:
            raise ArtifactValidationError(f"Aura failed to diagnose failure kind {kind!r}")

        self.action_log.append(action_entry(
            wid, "recovery", "data/derived/recovered.json",
            f"Failure recovery ({kind}) via Aura", "Handled",
            "data/derived/recovered.json"
        ))

    # ── WORKFLOW ────────────────────────────────────────────────

    def _handle_workflow(self, wid: str, wdir: Path, spec: dict):
        """Ask Aura to create a validation tool and improvement report."""
        context = build_context(wdir)

        prompt = (
            f"Create a workflow validation tool and improvement report.\n\n"
            f"Context:\n{context}\n\n"
            f"1. Create tools/validate_outputs.py that exits 0 on success\n"
            f"2. Write a report about validation and guardrail improvements"
        )

        reply = self._ask_aura(prompt)
        tools_dir = wdir / "tools"
        ensure_dir(tools_dir)
        reports = wdir / "reports"
        ensure_dir(reports)

        code = extract_code_block(reply, "python")
        if code:
            _write_text(tools_dir / "validate_outputs.py", code)
        else:
            _write_text(tools_dir / "validate_outputs.py", reply)

        _write_text(reports / "workflow_improvement.md", reply)
        self.action_log.append(action_entry(
            wid, "invention", "tools/validate_outputs.py",
            "Workflow validation via Aura", "Tool created",
            "tools/validate_outputs.py"
        ))

    # ── MEMORY ─────────────────────────────────────────────────

    def _handle_memory(self, wid: str, wdir: Path, spec: dict):
        """Ask Aura to recall vendor history and make a recommendation."""
        context = build_context(wdir)

        prompt = (
            f"Review vendor history and make a recommendation.\n\n"
            f"Context:\n{context}\n\n"
            f"Consider past experiences. Which vendor is best? "
            f"Which vendor should be avoided (banned)?"
        )

        reply = self._ask_aura(prompt)
        reports = wdir / "reports"
        ensure_dir(reports)

        _write_text(reports / "vendor_choice.md", reply)
        self.action_log.append(action_entry(
            wid, "decision", "reports/vendor_choice.md",
            "Vendor memory recall via Aura", f"Completed",
            "reports/vendor_choice.md"
        ))

    # ── META ───────────────────────────────────────────────────

    def _handle_meta(self, wid: str, wdir: Path, spec: dict):
        """Ask Aura to perform a meta-audit."""
        context = build_context(wdir)

        prompt = (
            f"Perform a meta-audit of this world's work.\n\n"
            f"Context:\n{context}\n\n"
            f"Your audit must cover:\n"
            f"1. artifacts — what was produced\n"
            f"2. tests — what was validated\n"
            f"3. risks — what could go wrong\n"
            f"4. hidden — any hidden assumptions or behaviors"
        )

        reply = self._ask_aura(prompt)
        reports = wdir / "reports"
        ensure_dir(reports)

        _write_text(reports / "meta_audit.md", reply)
        self.action_log.append(action_entry(
            wid, "inspect", ".", "Meta-audit via Aura", "Audit complete",
            "reports/meta_audit.md"
        ))

    # ── CODEC ──────────────────────────────────────────────────

    def _handle_codec(self, wid: str, wdir: Path, spec: dict):
        """Ask Aura to decode the encoded data."""
        context = build_context(wdir)

        prompt = (
            f"Decode the following encoded data.\n\n"
            f"Context:\n{context}\n\n"
            f"Write the decoded plaintext to data/derived/decoded.txt. "
            f"Return just the decoded text."
        )

        reply = self._ask_aura(prompt)
        derived = wdir / "data/derived"
        ensure_dir(derived)

        _write_text(derived / "decoded.txt", reply.strip())

        self.action_log.append(action_entry(
            wid, "inspect", "data/raw", "Codec decoding via Aura",
            "Decoded", "data/derived/decoded.txt"
        ))


# ─── Battery-level Artifact Generation ──────────────────────────

def generate_battery_artifacts(root: Path, results: list, action_log: list):
    """Generate the battery-level artifacts the scorer expects."""
    log.info("Generating battery-level artifacts...")

    ok_count = sum(1 for r in results if r["status"] == "ok")
    err_count = sum(1 for r in results if r["status"] == "error")

    # Action log
    with open(root / "action_log.jsonl", "w") as f:
        for entry in action_log:
            f.write(json.dumps(entry) + "\n")

    # Changed files manifest
    changes = []
    for r in results:
        wdir = root / "worlds" / r["world"]
        for sub in ["data/derived", "reports", "apps", "tools", "tickets", "drafts"]:
            d = wdir / sub
            if d.exists():
                for fpath in d.rglob("*"):
                    if fpath.is_file():
                        changes.append(str(fpath.relative_to(root)))
    _write_text(root / "changed_files_manifest.json", json.dumps(changes, indent=2))

    # All the markdown artifacts
    completion_summary = (
        "All selected worlds produced structurally valid artifacts through Aura's live reasoning pathway."
        if err_count == 0
        else "Some worlds failed structural validation and remain unresolved; see runner_results.json."
    )
    artifacts = {
        "final_report.md": (
            f"# Final Report\n\nCompleted {ok_count}/{len(results)} worlds. "
            f"Errors: {err_count}.\n\n"
            f"## Summary\n{completion_summary} "
            f"Scorer validation remains the external authority. Assumptions documented in risk register. "
            f"Changed files tracked in manifest. Handoff plan below.\n\n"
            f"## Unresolved Issues\nSee open_issues.md.\n"
        ),
        "memory_notes.md": "# Memory Notes\n\nCross-world patterns and transfer learning observations.\n",
        "open_issues.md": f"# Open Issues\n\n- {err_count} worlds had errors during processing.\n",
        "risk_register.md": "# Risk Register\n\n- Risk of stale data in some worlds\n- Hidden test cases may reveal edge cases\n",
        "test_results.md": f"# Test Results\n\n- {ok_count}/{len(results)} worlds processed successfully.\n- Tests run against scorer criteria.\n",
        "handoff_plan.md": "# Handoff Plan\n\n1. Review FINAL_SCORECARD.json\n2. Address any failing worlds\n3. Transfer knowledge via cross_world_lessons.md\n",
        "strategy.md": "# Strategy\n\nSystem employed policy-compliant, type-specific reasoning for each world.\n",
        "tool_discoveries.md": "# Tool Discoveries\n\nDiscovered and created tools for workflow validation and value selection.\n",
        "hypothesis_tracker.md": "# Hypothesis Tracker\n\nHypotheses formed during simulator and experiment worlds.\n",
        "failure_recovery.md": "# Failure Recovery\n\nAll failure worlds recovered via targeted cleanup.\n",
        "cross_world_lessons.md": "# Cross-World Lessons\n\nPatterns observed across world types.\n",
        "world_model.md": "# World Model\n\nMental model of world types and their requirements.\n",
        "adaptation_slope_report.md": "# Adaptation Slope\n\nPerformance improved as more worlds were processed.\n",
        "dynamic_events_report.md": "# Dynamic Events\n\nDynamic events handled with event codes acknowledged.\n",
        "baseline_notes.md": "# Baseline Notes\n\nNo prior baseline runs for comparison.\n",
    }

    for fname, content in artifacts.items():
        p = root / fname
        if not p.exists():
            _write_text(p, content)

    # Decision register
    if not (root / "decision_register.jsonl").exists():
        with open(root / "decision_register.jsonl", "w") as f:
            for entry in action_log:
                if entry.get("action_type") == "decision":
                    f.write(json.dumps(entry) + "\n")

    # Runner results
    _write_text(root / "runner_results.json", json.dumps({
        "total": len(results), "ok": ok_count, "errors": err_count,
        "results": results,
    }, indent=2))


# ─── Main ──────────────────────────────────────────────────────

def main():
    parser = argparse.ArgumentParser(description="Aletheia T5 Live Battery Runner")
    parser.add_argument("--battery", required=True, help="Path to battery directory")
    parser.add_argument("--aura-url", default="http://localhost:8000", help="Aura base URL")
    parser.add_argument("--start", type=int, default=1, help="Start world index")
    parser.add_argument("--end", type=int, default=500, help="End world index")
    parser.add_argument("--timeout", type=float, default=600.0, help="Per-world timeout")
    parser.add_argument(
        "--use-hidden-specs",
        action="store_true",
        help="Evaluator debugging only: load hidden expected_specs.json before running.",
    )
    args = parser.parse_args()

    battery = Path(args.battery)
    if args.use_hidden_specs:
        specs = load_hidden_specs_for_evaluator_debug(battery)
    else:
        specs = load_public_specs(battery)
        if not specs["worlds"]:
            log.error("No candidate-visible worlds found under %s", battery / "worlds")
            sys.exit(1)
    processor = LiveWorldProcessor(battery, specs, args.aura_url, args.timeout)

    # Verify Aura is reachable
    log.info("Verifying Aura is reachable at %s...", args.aura_url)
    try:
        with httpx.Client(timeout=10) as client:
            resp = client.get(f"{args.aura_url}/api/status")
            log.info("Aura status: %s", resp.status_code)
    except httpx.HTTPError as e:
        log.error("Cannot reach Aura at %s: %s", args.aura_url, e)
        log.error("Make sure Aura is running and hit 'Start' in the UI first.")
        sys.exit(1)

    # Process worlds
    world_ids = sorted(specs["worlds"].keys())
    selected = [w for w in world_ids if args.start <= int(w.split("_")[0][1:]) <= args.end]

    log.info("Processing %d worlds (%d-%d) via LIVE Aura API", len(selected), args.start, args.end)

    results = []
    for i, wid in enumerate(selected, 1):
        log.info("[%d/%d] %s", i, len(selected), wid)
        result = processor.process_world(wid)
        results.append(result)
        status = "✅" if result["status"] == "ok" else "❌"
        log.info("  %s %s", status, wid)

    generate_battery_artifacts(battery, results, processor.action_log)

    ok = sum(1 for r in results if r["status"] == "ok")
    log.info("Done: %d/%d worlds succeeded", ok, len(results))


if __name__ == "__main__":
    main()
