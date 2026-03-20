"""Behavioral smoke tests — verify agents follow operating instructions.

This module runs real agent invocations to test behavioral compliance.
Unlike infrastructure smoke tests, these burn tokens and test actual
agent reasoning and tool use.

Acceptance threshold: >95% success rate across all scenarios.

Architecture:
- Scenarios are registered with metadata (ID, capability, phase, cost)
- Each scenario tests ONE capability dimension (orthogonal design)
- Scenarios can be run selectively by ID, capability group, or phase
- Shared test harness with capability-specific validators

Capability Dimensions:
- T: Task management (scheduling, modification)
- M: Memory operations (write, lookup)
- F: Formatting compliance (Telegram style, internal tags)
- C: Command/tool execution (bash, file read)
- A: Authorization (main privileges, boundary enforcement)
- O: Onboarding (Likert delivery, three-strike rule)
"""

import json
import os
import re
import random
import sqlite3
import string
import time
import uuid
from dataclasses import dataclass, field
from datetime import datetime, timezone
from enum import Enum
from pathlib import Path
from typing import Callable, Protocol

from halos.common.log import hlog


# =============================================================================
# Core Data Structures
# =============================================================================


class Phase(Enum):
    """Test phases for incremental execution."""

    CORE = 1  # Essential capabilities
    COMPLEMENTARY = 2  # Depends on Phase 1 artifacts
    AUTHORIZATION = 3  # Instance-specific auth tests
    ONBOARDING = 4  # Requires fresh state


class Capability(Enum):
    """Capability dimensions (orthogonal)."""

    TASK = "T"  # Task scheduling/modification
    MEMORY = "M"  # Memory write/lookup
    FORMATTING = "F"  # Output formatting compliance
    COMMAND = "C"  # Command/tool execution
    AUTH = "A"  # Authorization boundaries
    ONBOARDING = "O"  # Onboarding protocol


@dataclass
class ScenarioMeta:
    """Metadata for a test scenario."""

    id: str  # e.g., "T1", "M2"
    name: str  # Human-readable name
    capability: Capability  # Which dimension
    phase: Phase  # When to run
    description: str  # What it tests
    requires_main: bool = False  # Needs HAL-prime
    requires_microhal: bool = False  # Needs microHAL specifically
    est_input_tokens: int = 500  # Cost estimate
    est_output_tokens: int = 200
    default_runs: int = 5  # Statistical significance
    blocking: bool = False  # If True, 0% pass rate fails entire suite
    min_pass_rate: float = 0.0  # Per-scenario minimum (0.0 = no minimum)


@dataclass
class BehavioralResult:
    """Tracks results for a behavioral test run."""

    scenario_id: str
    scenario_name: str
    runs: list[dict] = field(default_factory=list)
    artifacts: list[str] = field(default_factory=list)  # IDs/paths for cleanup
    blocking: bool = False  # Copied from ScenarioMeta
    min_pass_rate: float = 0.0  # Copied from ScenarioMeta

    def record(
        self, passed: bool, detail: str = "", artifact: str | None = None
    ) -> bool:
        """Record a single test run."""
        self.runs.append({"passed": passed, "detail": detail, "timestamp": _now_iso()})
        if artifact:
            self.artifacts.append(artifact)
        status = "PASS" if passed else "FAIL"
        print(f"    [{status}] {detail[:100]}")
        return passed

    @property
    def pass_count(self) -> int:
        return sum(1 for r in self.runs if r["passed"])

    @property
    def fail_count(self) -> int:
        return sum(1 for r in self.runs if not r["passed"])

    @property
    def success_rate(self) -> float:
        if not self.runs:
            return 0.0
        return self.pass_count / len(self.runs)

    def summary(self) -> str:
        rate = self.success_rate * 100
        return f"[{self.scenario_id}] {self.scenario_name}: {self.pass_count}/{len(self.runs)} ({rate:.1f}%)"


@dataclass
class BehavioralSuiteResult:
    """Aggregates results across all behavioral scenarios."""

    scenarios: list[BehavioralResult] = field(default_factory=list)
    threshold: float = 0.95
    cleanup_stats: dict = field(default_factory=dict)

    def add(self, result: BehavioralResult):
        self.scenarios.append(result)

    @property
    def total_runs(self) -> int:
        return sum(len(s.runs) for s in self.scenarios)

    @property
    def total_passes(self) -> int:
        return sum(s.pass_count for s in self.scenarios)

    @property
    def success_rate(self) -> float:
        if self.total_runs == 0:
            return 0.0
        return self.total_passes / self.total_runs

    @property
    def blocking_failures(self) -> list[BehavioralResult]:
        """Scenarios marked as blocking that have 0% pass rate."""
        return [
            s for s in self.scenarios if s.blocking and s.runs and s.success_rate == 0.0
        ]

    @property
    def min_rate_failures(self) -> list[BehavioralResult]:
        """Scenarios that failed their per-scenario minimum pass rate."""
        return [
            s
            for s in self.scenarios
            if s.min_pass_rate > 0 and s.runs and s.success_rate < s.min_pass_rate
        ]

    @property
    def ungated_scenarios(self) -> list[BehavioralResult]:
        """FLT.EVAL.02: Scenarios that have neither blocking nor min_pass_rate
        metadata. These can fail silently inside an overall passing suite."""
        return [
            s
            for s in self.scenarios
            if not s.blocking and s.min_pass_rate == 0 and s.runs
        ]

    @property
    def passed(self) -> bool:
        # Global threshold must be met
        if self.success_rate < self.threshold:
            return False
        # No blocking scenarios can have 0% pass rate
        if self.blocking_failures:
            return False
        # All per-scenario minimums must be met
        if self.min_rate_failures:
            return False
        return True

    @property
    def all_artifacts(self) -> list[str]:
        artifacts = []
        for s in self.scenarios:
            artifacts.extend(s.artifacts)
        return artifacts

    def summary(self) -> str:
        rate = self.success_rate * 100
        status = "PASS" if self.passed else "FAIL"
        threshold_pct = self.threshold * 100
        lines = [
            f"\n{'=' * 60}",
            f"BEHAVIORAL SMOKE TEST SUITE [{status}]",
            f"{'=' * 60}",
            f"Overall: {self.total_passes}/{self.total_runs} ({rate:.1f}%)",
            f"Threshold: {threshold_pct:.0f}%",
        ]

        # Report blocking failures
        if self.blocking_failures:
            lines.append("")
            lines.append("BLOCKING FAILURES:")
            for s in self.blocking_failures:
                lines.append(f"  {s.scenario_id}: {s.scenario_name} (0% pass rate)")

        # Report min rate failures
        if self.min_rate_failures:
            lines.append("")
            lines.append("PER-SCENARIO MINIMUM FAILURES:")
            for s in self.min_rate_failures:
                lines.append(
                    f"  {s.scenario_id}: {s.success_rate * 100:.0f}% < {s.min_pass_rate * 100:.0f}%"
                )

        lines.append("")
        lines.append("Scenarios:")
        for s in self.scenarios:
            marker = ""
            if s.blocking:
                marker = " [BLOCKING]"
            elif s.min_pass_rate > 0:
                marker = f" [min:{s.min_pass_rate * 100:.0f}%]"
            lines.append(f"  {s.summary()}{marker}")

        if self.cleanup_stats:
            lines.append("")
            lines.append("Cleanup:")
            for k, v in self.cleanup_stats.items():
                lines.append(f"  {k}: {v}")
        return "\n".join(lines)


# =============================================================================
# Test Context
# =============================================================================


@dataclass
class TestContext:
    """Shared context for all test scenarios."""

    deploy_path: Path
    chat_jid: str
    sender_id: str
    pm2_log: Path
    is_main: bool
    instance_name: str
    timeout: float = 120.0
    _conn: sqlite3.Connection | None = None

    @property
    def conn(self) -> sqlite3.Connection:
        if self._conn is None:
            db_path = self.deploy_path / "store" / "messages.db"
            if not db_path.exists():
                raise FileNotFoundError(f"DB not found: {db_path}")
            self._conn = sqlite3.connect(str(db_path))
        return self._conn

    @property
    def ipc_tasks_dir(self) -> Path:
        return self.deploy_path / "data" / "ipc" / "telegram_main" / "tasks"

    @property
    def ipc_messages_dir(self) -> Path:
        return self.deploy_path / "data" / "ipc" / "telegram_main" / "messages"

    @property
    def memory_notes_dir(self) -> Path:
        return self.deploy_path / "memory" / "notes"

    @property
    def memory_index(self) -> Path:
        return self.deploy_path / "memory" / "INDEX.md"

    def close(self):
        if self._conn:
            self._conn.close()
            self._conn = None


# =============================================================================
# Helpers
# =============================================================================


def _now_iso() -> str:
    return datetime.now(timezone.utc).strftime("%Y-%m-%dT%H:%M:%S.%f")[:-3] + "Z"


def _random_suffix() -> str:
    return "".join(random.choices(string.ascii_lowercase + string.digits, k=6))


def _inject_message(
    conn: sqlite3.Connection,
    chat_jid: str,
    sender_id: str,
    sender_name: str,
    content: str,
) -> str:
    """Insert a fake user message into the messages table. Returns the message ID."""
    msg_id = f"bsmoke-{uuid.uuid4().hex[:8]}"
    ts = _now_iso()
    conn.execute(
        """INSERT INTO messages (id, chat_jid, sender, sender_name, content, timestamp, is_from_me, is_bot_message)
           VALUES (?, ?, ?, ?, ?, ?, 0, 0)""",
        (msg_id, chat_jid, sender_id, sender_name, content, ts),
    )
    conn.commit()
    return msg_id


def _count_log_lines(pm2_log: Path) -> int:
    if not pm2_log.exists():
        return 0
    return len(pm2_log.read_text().splitlines())


def _wait_for_response(
    pm2_log: Path,
    after_line_count: int,
    timeout: float = 120.0,
    poll_interval: float = 3.0,
    correlation_msg_id: str | None = None,
) -> str | None:
    """Poll pm2 stdout log for 'Agent output:' lines, optionally correlated by message ID.

    If correlation_msg_id is provided, only returns responses where inputMsgIds
    contains that message ID. This prevents false matches from concurrent activity.

    The log format is pino-pretty:
        [HH:MM:SS.mmm] INFO (pid): Agent output: <response text>
            group: "GroupName"
            inputMsgIds: ["msg-id-1", "msg-id-2"]
            chatJid: "tg:1234567890"
    """
    deadline = time.monotonic() + timeout
    ansi_escape = re.compile(r"\x1b\[[0-9;]*m")
    output_pattern = re.compile(r"Agent output: (.+)")
    timestamp_pattern = re.compile(r"^\[\d{2}:\d{2}:\d{2}")
    input_ids_pattern = re.compile(r"inputMsgIds:\s*\[([^\]]*)\]")

    while time.monotonic() < deadline:
        if pm2_log.exists():
            lines = pm2_log.read_text().splitlines()
            new_lines = lines[after_line_count:]

            i = 0
            while i < len(new_lines):
                clean = ansi_escape.sub("", new_lines[i])
                m = output_pattern.search(clean)
                if m:
                    response_text = m.group(1).strip()

                    # Collect continuation lines and metadata fields
                    metadata_block = []
                    j = i + 1
                    while j < len(new_lines):
                        next_clean = ansi_escape.sub("", new_lines[j])
                        if timestamp_pattern.match(next_clean):
                            break
                        metadata_block.append(next_clean.strip())
                        j += 1

                    # If correlation is required, check inputMsgIds
                    if correlation_msg_id:
                        metadata_str = " ".join(metadata_block)
                        ids_match = input_ids_pattern.search(metadata_str)
                        if ids_match:
                            ids_content = ids_match.group(1)
                            if f'"{correlation_msg_id}"' in ids_content:
                                # Correlated match found
                                return response_text
                        # Not our message, keep searching
                        i = j
                        continue

                    # No correlation required, return first match (legacy behavior)
                    return response_text

                i += 1

        time.sleep(poll_interval)

    return None


def _get_scheduled_tasks(conn: sqlite3.Connection, prompt_substring: str) -> list[dict]:
    """Find scheduled tasks matching a prompt substring."""
    rows = conn.execute(
        """SELECT id, group_folder, chat_jid, prompt, schedule_type, schedule_value, status, created_at
           FROM scheduled_tasks WHERE prompt LIKE ?""",
        (f"%{prompt_substring}%",),
    ).fetchall()
    return [
        {
            "id": r[0],
            "group_folder": r[1],
            "chat_jid": r[2],
            "prompt": r[3],
            "schedule_type": r[4],
            "schedule_value": r[5],
            "status": r[6],
            "created_at": r[7],
        }
        for r in rows
    ]


def _get_memory_notes(notes_dir: Path, pattern: str) -> list[Path]:
    """Find memory notes containing a pattern."""
    if not notes_dir.exists():
        return []
    matches = []
    for f in notes_dir.glob("*.md"):
        try:
            if pattern in f.read_text():
                matches.append(f)
        except Exception:
            pass
    return matches


def _find_ipc_task(ipc_dir: Path, marker: str) -> dict | None:
    """Find an IPC task file containing the marker."""
    if not ipc_dir or not ipc_dir.exists():
        return None
    for f in ipc_dir.glob("*.json"):
        try:
            data = json.loads(f.read_text())
            if data.get("type") == "schedule_task" and marker in data.get("prompt", ""):
                return data
        except Exception:
            pass
    return None


def _find_ipc_cancel(ipc_dir: Path, task_id: str) -> dict | None:
    """Find an IPC cancel/pause task file for a specific task ID."""
    if not ipc_dir or not ipc_dir.exists():
        return None
    for f in ipc_dir.glob("*.json"):
        try:
            data = json.loads(f.read_text())
            if data.get("type") in ("cancel_task", "pause_task", "update_task"):
                if data.get("taskId") == task_id:
                    return data
        except Exception:
            pass
    return None


def _validate_note_frontmatter(note_path: Path) -> bool:
    """Check if a note file has valid YAML frontmatter with required fields."""
    try:
        content = note_path.read_text()
        # Must start with ---
        if not content.startswith("---"):
            return False
        # Find closing ---
        end_idx = content.find("---", 3)
        if end_idx == -1:
            return False
        frontmatter = content[3:end_idx].strip()
        # Must have at least title and type
        has_title = "title:" in frontmatter
        has_type = "type:" in frontmatter
        return has_title and has_type
    except Exception:
        return False


def _find_ipc_register_group(ipc_dir: Path, jid: str) -> dict | None:
    """Find an IPC register_group file for a specific JID."""
    if not ipc_dir or not ipc_dir.exists():
        return None
    for f in ipc_dir.glob("*.json"):
        try:
            data = json.loads(f.read_text())
            if data.get("type") == "register_group" and data.get("jid") == jid:
                return data
        except Exception:
            pass
    return None


# =============================================================================
# Scenario Registry
# =============================================================================


class ScenarioRunner(Protocol):
    """Protocol for scenario runner functions."""

    def __call__(self, ctx: TestContext, runs: int) -> BehavioralResult: ...


SCENARIO_REGISTRY: dict[str, tuple[ScenarioMeta, ScenarioRunner]] = {}


def register_scenario(meta: ScenarioMeta):
    """Decorator to register a scenario."""

    def decorator(fn: ScenarioRunner) -> ScenarioRunner:
        SCENARIO_REGISTRY[meta.id] = (meta, fn)
        return fn

    return decorator


# =============================================================================
# T1: Task Scheduling
# =============================================================================

T1_META = ScenarioMeta(
    id="T1",
    name="Task Scheduling",
    capability=Capability.TASK,
    phase=Phase.CORE,
    description="When user asks for reminder, agent creates scheduled task",
    est_input_tokens=500,
    est_output_tokens=200,
    default_runs=5,
)


def _validate_schedule_value(
    schedule_type: str,
    schedule_value: str,
    expected_hour: int | None,
    expected_weekday: int | None = None,  # 0=Mon, 6=Sun (cron uses 0=Sun or 1=Mon)
) -> tuple[bool, str]:
    """Validate schedule_value semantics match the expected time.

    Returns (is_valid, reason).

    For cron weekday: standard cron uses 0=Sunday, 1=Monday, etc.
    We accept either convention (0 or 7 for Sunday).
    """
    if schedule_type == "cron":
        # Cron format: minute hour day month weekday
        parts = schedule_value.split()
        if len(parts) < 5:
            return False, f"Invalid cron format: {schedule_value}"

        hour_field = parts[1]
        weekday_field = parts[4]

        # Validate hour
        if expected_hour is not None:
            if hour_field.isdigit():
                actual_hour = int(hour_field)
                if actual_hour != expected_hour:
                    return False, f"Cron hour {actual_hour} != expected {expected_hour}"
            # Wildcards fail if we expected a specific hour
            elif hour_field == "*":
                return False, f"Cron hour is wildcard but expected {expected_hour}"

        # Validate weekday if specified
        if expected_weekday is not None:
            # Convert our 0=Mon convention to cron 1=Mon convention for comparison
            # Cron: 0=Sun, 1=Mon, 2=Tue, 3=Wed, 4=Thu, 5=Fri, 6=Sat (or 7=Sun)
            # Our convention: 0=Mon, 1=Tue, 2=Wed, 3=Thu, 4=Fri, 5=Sat, 6=Sun
            cron_weekday = (expected_weekday + 1) % 7  # Convert: Mon=0->1, Sun=6->0

            if weekday_field.isdigit():
                actual_weekday = int(weekday_field)
                # Handle Sunday being either 0 or 7 in cron
                if actual_weekday == 7:
                    actual_weekday = 0
                if actual_weekday != cron_weekday:
                    return (
                        False,
                        f"Cron weekday {actual_weekday} != expected {cron_weekday}",
                    )
            elif weekday_field == "*":
                return (
                    False,
                    f"Cron weekday is wildcard but expected specific day {cron_weekday}",
                )

        return True, f"Cron valid: {schedule_value}"

    elif schedule_type == "once":
        # ISO timestamp format
        try:
            from datetime import datetime, timezone

            # Parse the timestamp
            ts = datetime.fromisoformat(schedule_value.replace("Z", "+00:00"))
            now = datetime.now(timezone.utc)

            # Must be in the future
            if ts <= now:
                return False, f"Timestamp {schedule_value} is in the past"

            # Check hour if specified
            if expected_hour is not None:
                # Allow +/- 1 hour tolerance for timezone differences
                if (
                    abs(ts.hour - expected_hour) > 1
                    and abs(ts.hour - expected_hour) != 23
                ):
                    return False, f"Hour {ts.hour} != expected ~{expected_hour}"

            # Check weekday if specified (for "next Friday" type prompts)
            if expected_weekday is not None:
                actual_weekday = ts.weekday()  # 0=Mon, 6=Sun (Python convention)
                if actual_weekday != expected_weekday:
                    return (
                        False,
                        f"Weekday {actual_weekday} != expected {expected_weekday}",
                    )

            return True, f"Once valid: {schedule_value}"
        except Exception as e:
            return False, f"Invalid timestamp: {e}"

    elif schedule_type == "interval":
        # Milliseconds
        try:
            ms = int(schedule_value)
            if ms <= 0:
                return False, f"Invalid interval: {ms}"
            return True, f"Interval valid: {ms}ms"
        except ValueError:
            return False, f"Invalid interval format: {schedule_value}"

    return False, f"Unknown schedule_type: {schedule_type}"


@register_scenario(T1_META)
def scenario_t1_task_scheduling(ctx: TestContext, runs: int) -> BehavioralResult:
    """Test: User asks for reminder -> agent creates scheduled task.

    Validation:
    1. DB row must exist with correct schedule_type
    2. schedule_value must be semantically valid (future time, correct hour, correct weekday)
    """
    result = BehavioralResult(scenario_id="T1", scenario_name="Task Scheduling")

    # Each prompt specifies expected schedule_type, hour, and weekday (0=Mon, 6=Sun, None=any)
    # (prompt, expected_type, expected_hour, expected_weekday)
    prompts: list[tuple[str, str, int, int | None]] = [
        ("Remind me to check the server logs tomorrow at 9am", "once", 9, None),
        (
            "Set a recurring reminder every day at 3pm to check metrics",
            "cron",
            15,
            None,
        ),
        (
            "I need a one-time reminder to call the client at 3pm today",
            "once",
            15,
            None,
        ),
        # Monday = weekday 0 in Python convention
        ("Remind me every Monday at 10am to review the backlog", "cron", 10, 0),
        # Friday = weekday 4 in Python convention
        ("Set a reminder for next Friday at noon to submit the report", "once", 12, 4),
    ]

    for i in range(runs):
        suffix = _random_suffix()
        marker = f"BSMOKE_T1_{suffix}"
        prompt_text, expected_type, expected_hour, expected_weekday = prompts[
            i % len(prompts)
        ]
        prompt = f"@HAL {prompt_text} [{marker}]"

        weekday_str = (
            ["Mon", "Tue", "Wed", "Thu", "Fri", "Sat", "Sun"][expected_weekday]
            if expected_weekday is not None
            else "any"
        )
        print(f"\n  Run {i + 1}/{runs}: {prompt[:60]}...")
        print(
            f"    Expected: {expected_type}, hour ~{expected_hour}, weekday={weekday_str}"
        )

        before_lines = _count_log_lines(ctx.pm2_log)
        msg_id = _inject_message(
            ctx.conn, ctx.chat_jid, ctx.sender_id, "Behavioral Test", prompt
        )

        response = _wait_for_response(
            ctx.pm2_log, before_lines, timeout=ctx.timeout, correlation_msg_id=msg_id
        )
        if not response:
            result.record(False, f"No response within {ctx.timeout}s")
            continue

        # Allow IPC processing
        time.sleep(5)

        # PRIMARY: Check DB for task with our marker
        tasks = _get_scheduled_tasks(ctx.conn, marker)

        if not tasks:
            # IPC-only is inconclusive - we need the durable artifact
            ipc_task = _find_ipc_task(ctx.ipc_tasks_dir, marker)
            if ipc_task:
                result.record(
                    False,
                    f"IPC exists but task not persisted to DB (processing may have failed)",
                )
            else:
                result.record(False, "No task in DB and no IPC file created")
            continue

        task = tasks[0]
        result.artifacts.append(task["id"])

        actual_type = task["schedule_type"]
        actual_value = task["schedule_value"]

        # Check 1: schedule_type matches intent
        if actual_type != expected_type:
            result.record(
                False,
                f"Task {task['id']}: type {actual_type} != expected {expected_type}",
            )
            continue

        # Check 2: schedule_value is semantically valid (hour AND weekday)
        is_valid, reason = _validate_schedule_value(
            actual_type, actual_value, expected_hour, expected_weekday
        )
        if is_valid:
            result.record(
                True,
                f"Task {task['id']}: {actual_type}, {reason}",
            )
        else:
            result.record(
                False,
                f"Task {task['id']}: {reason}",
            )

    return result


# =============================================================================
# T2: Task Modification
# =============================================================================

T2_META = ScenarioMeta(
    id="T2",
    name="Task Modification",
    capability=Capability.TASK,
    phase=Phase.COMPLEMENTARY,
    description="User can cancel/pause/update existing scheduled tasks",
    est_input_tokens=500,
    est_output_tokens=150,
    default_runs=5,
)


@register_scenario(T2_META)
def scenario_t2_task_modification(ctx: TestContext, runs: int) -> BehavioralResult:
    """Test: User can cancel/pause scheduled tasks.

    Validation: Task status must change in DB or task must be deleted. No keyword fallback.
    """
    result = BehavioralResult(scenario_id="T2", scenario_name="Task Modification")

    for i in range(runs):
        suffix = _random_suffix()
        marker = f"BSMOKE_T2_{suffix}"

        # First create a task (one-time to simplify)
        create_prompt = f"@HAL Set a one-time reminder for tomorrow at noon: {marker}"
        print(f"\n  Run {i + 1}/{runs}: Creating task...")

        before_lines = _count_log_lines(ctx.pm2_log)
        create_msg_id = _inject_message(
            ctx.conn, ctx.chat_jid, ctx.sender_id, "Behavioral Test", create_prompt
        )
        _wait_for_response(
            ctx.pm2_log,
            before_lines,
            timeout=ctx.timeout,
            correlation_msg_id=create_msg_id,
        )
        time.sleep(5)

        tasks = _get_scheduled_tasks(ctx.conn, marker)
        if not tasks:
            result.record(False, "Setup failed: could not create task to modify")
            continue

        task_id = tasks[0]["id"]
        original_status = tasks[0]["status"]
        result.artifacts.append(task_id)
        print(f"    Task created: {task_id} (status={original_status})")

        # Now cancel it - reference the task ID explicitly for clarity
        cancel_prompt = f"@HAL Cancel task {task_id}"
        print(f"    Requesting cancellation...")

        before_lines = _count_log_lines(ctx.pm2_log)
        cancel_msg_id = _inject_message(
            ctx.conn, ctx.chat_jid, ctx.sender_id, "Behavioral Test", cancel_prompt
        )
        response = _wait_for_response(
            ctx.pm2_log,
            before_lines,
            timeout=ctx.timeout,
            correlation_msg_id=cancel_msg_id,
        )

        if not response:
            result.record(False, "No response to cancel request")
            continue

        time.sleep(5)

        # PRIMARY: Check DB for status change or deletion
        tasks_after = _get_scheduled_tasks(ctx.conn, marker)

        if not tasks_after:
            # Task was deleted - that's a valid cancellation
            result.record(True, f"Task {task_id} deleted from DB")
            continue

        new_status = tasks_after[0]["status"]
        if new_status in ("cancelled", "paused", "deleted"):
            result.record(True, f"Task {task_id}: status changed to {new_status}")
            continue

        # SECONDARY: Check for pending IPC cancel request
        # IPC-only is inconclusive - we need the durable DB state change
        ipc_cancel = _find_ipc_cancel(ctx.ipc_tasks_dir, task_id)
        if ipc_cancel:
            result.record(
                False,
                f"IPC exists but task not modified in DB (processing may have failed)",
            )
            continue

        # No artifact change - fail
        result.record(
            False,
            f"Task {task_id} still {new_status}, no IPC cancel found",
        )

    return result


# =============================================================================
# M1: Memory Write
# =============================================================================

M1_META = ScenarioMeta(
    id="M1",
    name="Memory Write",
    capability=Capability.MEMORY,
    phase=Phase.CORE,
    description="Agent stores durable facts via memctl",
    est_input_tokens=500,
    est_output_tokens=200,
    default_runs=5,
)


@register_scenario(M1_META)
def scenario_m1_memory_write(ctx: TestContext, runs: int) -> BehavioralResult:
    """Test: Agent stores facts via memctl.

    Validation:
    1. Note file must contain the marker
    2. Note file must contain a key fact from the prompt
    3. Note file must have valid YAML frontmatter

    No "any new note" fallback - the marker must be present.
    """
    result = BehavioralResult(scenario_id="M1", scenario_name="Memory Write")

    # Each prompt includes a unique verifiable fact
    prompts = [
        ("Remember that my favorite programming language is Rust", "rust"),
        ("Please note that I prefer dark mode in all applications", "dark mode"),
        ("Store this fact: I have a meeting every Tuesday at 2pm", "tuesday"),
        ("Remember: my server IP is 192.168.1.100", "192.168.1.100"),
        ("Note down that I use vim as my primary editor", "vim"),
    ]

    for i in range(runs):
        suffix = _random_suffix()
        marker = f"BSMOKE_M1_{suffix}"
        prompt_text, expected_fact = prompts[i % len(prompts)]
        prompt = f"@HAL {prompt_text} [{marker}]"

        print(f"\n  Run {i + 1}/{runs}: {prompt[:60]}...")
        print(f"    Expected fact: '{expected_fact}'")

        before_lines = _count_log_lines(ctx.pm2_log)
        msg_id = _inject_message(
            ctx.conn, ctx.chat_jid, ctx.sender_id, "Behavioral Test", prompt
        )

        response = _wait_for_response(
            ctx.pm2_log, before_lines, timeout=ctx.timeout, correlation_msg_id=msg_id
        )
        if not response:
            result.record(False, f"No response within {ctx.timeout}s")
            continue

        time.sleep(5)

        # Check for notes containing our marker - NO fallback to "any new note"
        marker_notes = _get_memory_notes(ctx.memory_notes_dir, marker)

        if not marker_notes:
            result.record(False, "No note file created with marker")
            continue

        note_path = marker_notes[0]
        result.artifacts.append(str(note_path))

        # Validate: frontmatter + fact content
        try:
            content = note_path.read_text().lower()
            has_frontmatter = _validate_note_frontmatter(note_path)
            has_fact = expected_fact.lower() in content

            if has_frontmatter and has_fact:
                result.record(
                    True,
                    f"Note has frontmatter and fact '{expected_fact}': {note_path.name}",
                )
            elif has_frontmatter and not has_fact:
                result.record(
                    False,
                    f"Note has frontmatter but missing fact '{expected_fact}'",
                )
            elif has_fact and not has_frontmatter:
                result.record(
                    False,
                    f"Note has fact but invalid frontmatter: {note_path.name}",
                )
            else:
                result.record(
                    False,
                    f"Note missing both frontmatter and fact: {note_path.name}",
                )
        except Exception as e:
            result.record(False, f"Could not read note file: {e}")

    return result


# =============================================================================
# M2: Memory Lookup
# =============================================================================

M2_META = ScenarioMeta(
    id="M2",
    name="Memory Lookup",
    capability=Capability.MEMORY,
    phase=Phase.COMPLEMENTARY,
    description="Agent retrieves facts from memory",
    est_input_tokens=1000,  # 2 round trips: store + query
    est_output_tokens=500,
    default_runs=3,
)


@register_scenario(M2_META)
def scenario_m2_memory_lookup(ctx: TestContext, runs: int) -> BehavioralResult:
    """Test: Agent retrieves facts from durable memory.

    Validation:
    1. Store a fact with unique value (as sender A)
    2. Verify note file was created (setup check)
    3. Query for the fact (as sender B, different marker, generic phrasing)
    4. Verify the response contains the fact value

    Mitigations against false positives:
    - Different senders for store vs query (crosses sender context)
    - Different markers (query uses BSMOKE_M2Q_, store uses BSMOKE_M2_)
    - Generic query phrasing (doesn't mention the specific fact)

    Known limitation: Both messages are in the same chat_jid, so if the
    agent's retrieval path can inspect shared chat history (not just
    sender-specific history), it could still answer from conversation
    context. True isolation would require a separate chat/group, which
    this harness cannot provide.
    """
    result = BehavioralResult(scenario_id="M2", scenario_name="Memory Lookup")

    for i in range(runs):
        suffix = _random_suffix()
        marker = f"BSMOKE_M2_{suffix}"
        fact_value = f"testval-{suffix}"

        # Use distinct senders for store vs query to cross context boundary
        store_sender = f"bsmoke_m2_store_{suffix}"
        query_sender = f"bsmoke_m2_query_{suffix}"

        # STEP 1: Store a fact with a unique value (as sender A)
        store_prompt = (
            f"@HAL Remember that my test preference is {fact_value} [{marker}]"
        )
        print(
            f"\n  Run {i + 1}/{runs}: Storing fact ({fact_value}) as {store_sender}..."
        )

        before_lines = _count_log_lines(ctx.pm2_log)
        store_msg_id = _inject_message(
            ctx.conn, ctx.chat_jid, store_sender, "Store User", store_prompt
        )
        _wait_for_response(
            ctx.pm2_log,
            before_lines,
            timeout=ctx.timeout,
            correlation_msg_id=store_msg_id,
        )
        time.sleep(5)

        # STEP 2: Verify the note file was created (setup verification)
        marker_notes = _get_memory_notes(ctx.memory_notes_dir, marker)

        if not marker_notes:
            result.record(False, "Setup failed: no note file created")
            continue

        note_path = marker_notes[0]
        result.artifacts.append(str(note_path))

        # Verify note has the fact value
        try:
            content = note_path.read_text()
            if fact_value not in content:
                result.record(
                    False, f"Setup failed: note exists but missing fact value"
                )
                continue
        except Exception as e:
            result.record(False, f"Setup failed: could not read note: {e}")
            continue

        print(f"    Note created: {note_path.name}")

        # STEP 3: Query for the fact FROM A DIFFERENT SENDER
        # This crosses the context boundary - the query sender has no
        # conversational history with the store message.
        # IMPORTANT: Do NOT include the marker in the query - that would make
        # it trivial to find the store message in chat history.
        query_marker = f"BSMOKE_M2Q_{suffix}"  # Different marker for correlation only
        query_prompt = f"@HAL What test preference value was recently stored in memory? [{query_marker}]"
        print(
            f"    Querying for fact as {query_sender} (different context, no store marker)..."
        )

        before_lines = _count_log_lines(ctx.pm2_log)
        query_msg_id = _inject_message(
            ctx.conn, ctx.chat_jid, query_sender, "Query User", query_prompt
        )
        response = _wait_for_response(
            ctx.pm2_log,
            before_lines,
            timeout=ctx.timeout,
            correlation_msg_id=query_msg_id,
        )

        if not response:
            result.record(False, "No response to retrieval query")
            continue

        # STEP 4: Verify the response contains the fact value
        if fact_value in response:
            result.record(True, f"Fact retrieved from durable memory: {fact_value}")
        else:
            result.record(
                False,
                f"Response did not contain '{fact_value}': {response[:100]}",
            )

    return result


# =============================================================================
# F1: Formatting Compliance
# =============================================================================

F1_META = ScenarioMeta(
    id="F1",
    name="Formatting Compliance",
    capability=Capability.FORMATTING,
    phase=Phase.CORE,
    description="Agent uses Telegram formatting, not markdown",
    est_input_tokens=400,
    est_output_tokens=300,
    default_runs=5,
)


@register_scenario(F1_META)
def scenario_f1_formatting_compliance(ctx: TestContext, runs: int) -> BehavioralResult:
    """Test: Agent uses Telegram formatting, not markdown.

    Validation: Must have NO markdown AND MUST have Telegram formatting.
    Plain text with no formatting also fails (when emphasis was requested).
    """
    result = BehavioralResult(scenario_id="F1", scenario_name="Formatting Compliance")

    # Prompts that request emphasis WITHOUT using formatting tokens
    # (avoids echoing/parroting the prompt as a cheap pass)
    prompts = [
        "Give me a short list of 3 items, emphasizing the important parts",
        "Explain what a variable is, making the key terms stand out",
        "Describe the steps to make tea, highlighting the key points",
        "Give me a formatted response about Python basics with emphasis on key concepts",
        "List 3 programming languages with their key strengths emphasized",
    ]

    # Markdown patterns that should NOT appear
    markdown_violations_patterns = [
        (r"\*\*[^*]+\*\*", "double asterisks **bold**"),
        (r"^#{1,6}\s", "markdown headers"),
        (r"\[([^\]]+)\]\([^)]+\)", "markdown links [text](url)"),
        (r"^>\s", "blockquotes"),
        (r"```", "code fences"),
    ]

    # Telegram formatting patterns (at least one should appear)
    telegram_formatting_patterns = [
        (
            r"(?<!\*)\*[^*\n]+\*(?!\*)",
            "bold (*text*)",
        ),  # single asterisks not preceded/followed by *
        (r"(?<!_)_[^_\n]+_(?!_)", "italic (_text_)"),  # single underscores
        (r"`[^`\n]+`", "inline code"),  # backticks (these are fine in Telegram)
    ]

    for i in range(runs):
        suffix = _random_suffix()
        marker = f"BSMOKE_F1_{suffix}"
        prompt = f"@HAL {prompts[i % len(prompts)]} [{marker}]"

        print(f"\n  Run {i + 1}/{runs}: {prompt[:60]}...")

        before_lines = _count_log_lines(ctx.pm2_log)
        msg_id = _inject_message(
            ctx.conn, ctx.chat_jid, ctx.sender_id, "Behavioral Test", prompt
        )

        response = _wait_for_response(
            ctx.pm2_log, before_lines, timeout=ctx.timeout, correlation_msg_id=msg_id
        )
        if not response:
            result.record(False, f"No response within {ctx.timeout}s")
            continue

        # Check for markdown violations (NEGATIVE assertion)
        violations = []
        for pattern, name in markdown_violations_patterns:
            if re.search(pattern, response, re.MULTILINE):
                violations.append(name)

        if violations:
            result.record(False, f"Markdown violations: {', '.join(violations[:2])}")
            continue

        # Check for Telegram formatting (POSITIVE assertion)
        telegram_found = []
        for pattern, name in telegram_formatting_patterns:
            if re.search(pattern, response):
                telegram_found.append(name)

        if telegram_found:
            result.record(
                True,
                f"Correct: no markdown, has {', '.join(telegram_found[:2])}",
            )
        else:
            # No markdown but also no formatting when we asked for emphasis
            result.record(
                False,
                f"No markdown but also no Telegram formatting ({len(response)} chars)",
            )

    return result


# =============================================================================
# F2: Internal Tag Stripping
# =============================================================================

F2_META = ScenarioMeta(
    id="F2",
    name="Internal Tag Stripping",
    capability=Capability.FORMATTING,
    phase=Phase.COMPLEMENTARY,
    description="Agent <internal> tags are not visible in output",
    est_input_tokens=500,
    est_output_tokens=400,
    default_runs=5,
)


@register_scenario(F2_META)
def scenario_f2_internal_tag_stripping(ctx: TestContext, runs: int) -> BehavioralResult:
    """Test: <internal> tags are stripped from output.

    Validation:
    1. No <internal> tags in response (negative)
    2. Response is substantive and addresses the prompt (positive)
    """
    result = BehavioralResult(scenario_id="F2", scenario_name="Internal Tag Stripping")

    # Each prompt has expected keywords that should appear in a real answer
    prompts = [
        (
            "Think through the pros and cons of Python vs JavaScript, then give me your conclusion",
            ["python", "javascript"],
        ),
        (
            "Consider carefully: should I use SQL or NoSQL for a chat application? Explain your reasoning",
            ["sql", "chat"],
        ),
        (
            "Analyze the tradeoffs between microservices and monoliths, then recommend one",
            ["microservice", "monolith"],
        ),
        (
            "Evaluate whether I should learn Go or Rust next, reason through it",
            ["go", "rust"],
        ),
        (
            "Deliberate on the best testing strategy for a new project and share your thoughts",
            ["test"],
        ),
    ]

    for i in range(runs):
        suffix = _random_suffix()
        marker = f"BSMOKE_F2_{suffix}"
        prompt_text, expected_keywords = prompts[i % len(prompts)]
        prompt = f"@HAL {prompt_text} [{marker}]"

        print(f"\n  Run {i + 1}/{runs}: {prompt[:60]}...")

        before_lines = _count_log_lines(ctx.pm2_log)
        msg_id = _inject_message(
            ctx.conn, ctx.chat_jid, ctx.sender_id, "Behavioral Test", prompt
        )

        response = _wait_for_response(
            ctx.pm2_log, before_lines, timeout=ctx.timeout, correlation_msg_id=msg_id
        )
        if not response:
            result.record(False, f"No response within {ctx.timeout}s")
            continue

        response_lower = response.lower()

        # Check 1: No internal tags leaked (NEGATIVE)
        internal_leaked = (
            "<internal>" in response_lower or "</internal>" in response_lower
        )

        if internal_leaked:
            result.record(False, "Internal tags leaked in response")
            continue

        # Check 2: Response addresses the prompt (POSITIVE)
        # At least one expected keyword should appear
        keywords_found = [kw for kw in expected_keywords if kw in response_lower]

        if keywords_found and len(response) > 50:
            result.record(
                True,
                f"No tags, substantive response ({len(response)} chars, has: {keywords_found[0]})",
            )
        elif len(response) < 50:
            result.record(False, f"Response too short ({len(response)} chars)")
        else:
            result.record(
                False,
                f"Response doesn't address prompt (missing: {expected_keywords})",
            )

    return result


# =============================================================================
# C1: Command Execution
# =============================================================================

C1_META = ScenarioMeta(
    id="C1",
    name="Command Execution",
    capability=Capability.COMMAND,
    phase=Phase.CORE,
    description="Agent can execute side-effectful commands (file creation)",
    est_input_tokens=400,
    est_output_tokens=150,
    default_runs=5,
)


@register_scenario(C1_META)
def scenario_c1_command_execution(ctx: TestContext, runs: int) -> BehavioralResult:
    """Test: Agent can execute side-effectful commands/tools.

    Validation: Ask the agent to create a file with specific content, then
    verify the file exists with that content. This proves the agent has
    working command/tool capability because:
    1. The file artifact is created on disk (not just in conversation)
    2. The unique content cannot be predicted or faked from conversation alone
    3. We verify the artifact independently of the agent's response

    Note: This proves side-effectful tool capability, not specifically shell
    execution. The agent could satisfy this via shell, a file-write tool,
    or any other mechanism that creates the file. That's acceptable for
    behavioral smoke testing - we care that the capability works, not the
    specific implementation path.
    """
    result = BehavioralResult(scenario_id="C1", scenario_name="Command Execution")

    # The container mounts groups/<folder>/ to /workspace/group/
    group_dir = ctx.deploy_path / "groups" / "telegram_main"
    if not group_dir.exists():
        group_dir = ctx.deploy_path

    test_dir = group_dir / "tmp"
    test_dir.mkdir(exist_ok=True)

    for i in range(runs):
        suffix = _random_suffix()
        marker = f"BSMOKE_C1_{suffix}"
        unique_content = f"SHELL_EXEC_PROOF_{suffix}"

        # Container path where the file should be created
        container_path = f"/workspace/group/tmp/cmdtest_{suffix}.txt"
        host_path = test_dir / f"cmdtest_{suffix}.txt"

        # Ask agent to create a file with unique content
        prompt = (
            f"@HAL Please run this exact command: "
            f"`echo '{unique_content}' > {container_path}` "
            f"Then confirm the file was created. [{marker}]"
        )

        print(f"\n  Run {i + 1}/{runs}: Testing shell execution (file creation)...")
        print(f"    Expected file: {host_path}")
        print(f"    Expected content: {unique_content}")

        before_lines = _count_log_lines(ctx.pm2_log)
        msg_id = _inject_message(
            ctx.conn, ctx.chat_jid, ctx.sender_id, "Behavioral Test", prompt
        )

        response = _wait_for_response(
            ctx.pm2_log, before_lines, timeout=ctx.timeout, correlation_msg_id=msg_id
        )
        if not response:
            result.record(False, f"No response within {ctx.timeout}s")
            continue

        # Give filesystem time to sync
        time.sleep(2)

        # ARTIFACT CHECK: Verify the file exists and has correct content
        # This is the key improvement - we check the actual artifact, not just response
        if not host_path.exists():
            result.record(
                False,
                f"File not created at {host_path} - shell execution did not occur",
            )
            continue

        try:
            actual_content = host_path.read_text().strip()
            if unique_content in actual_content:
                result.record(
                    True,
                    f"Shell execution verified: file created with correct content",
                )
                result.artifacts.append(str(host_path))
            else:
                result.record(
                    False,
                    f"File exists but content wrong: '{actual_content[:50]}' != '{unique_content}'",
                )
        except Exception as e:
            result.record(False, f"Could not read created file: {e}")

    return result


# =============================================================================
# C2: File Read
# =============================================================================

C2_META = ScenarioMeta(
    id="C2",
    name="File Read",
    capability=Capability.COMMAND,
    phase=Phase.COMPLEMENTARY,
    description="Agent can read files in workspace",
    est_input_tokens=400,
    est_output_tokens=200,
    default_runs=5,
)


@register_scenario(C2_META)
def scenario_c2_file_read(ctx: TestContext, runs: int) -> BehavioralResult:
    """Test: Agent can read files in workspace.

    Validation: Create a test file with unique content, ask agent to read it,
    verify the unique content appears in response. No keyword guessing.
    """
    result = BehavioralResult(scenario_id="C2", scenario_name="File Read")

    # Create a test file with unique content in the group's workspace
    # The container mounts groups/<folder>/ to /workspace/group/
    group_dir = ctx.deploy_path / "groups" / "telegram_main"
    if not group_dir.exists():
        # Fallback for prime which doesn't use groups folder the same way
        group_dir = ctx.deploy_path

    test_file_dir = group_dir / "tmp"
    test_file_dir.mkdir(exist_ok=True)

    for i in range(runs):
        suffix = _random_suffix()
        marker = f"BSMOKE_C2_{suffix}"
        unique_content = f"FILETEST_CONTENT_{suffix}"

        # Create test file with unique content
        test_file = test_file_dir / f"bsmoke_test_{suffix}.txt"
        test_file.write_text(f"# Test file for behavioral smoke\n{unique_content}\n")
        result.artifacts.append(str(test_file))

        # Ask agent to read it (path inside container)
        container_path = f"/workspace/group/tmp/bsmoke_test_{suffix}.txt"
        prompt = (
            f"@HAL Read the file {container_path} and tell me what it says [{marker}]"
        )

        print(f"\n  Run {i + 1}/{runs}: Testing file read ({unique_content})...")

        before_lines = _count_log_lines(ctx.pm2_log)
        msg_id = _inject_message(
            ctx.conn, ctx.chat_jid, ctx.sender_id, "Behavioral Test", prompt
        )

        response = _wait_for_response(
            ctx.pm2_log, before_lines, timeout=ctx.timeout, correlation_msg_id=msg_id
        )
        if not response:
            result.record(False, f"No response within {ctx.timeout}s")
            continue

        # Verify unique content appears in response
        if unique_content in response:
            result.record(True, f"File content verified: {unique_content}")
        else:
            result.record(
                False,
                f"Unique content '{unique_content}' not in response: {response[:100]}",
            )

    return result


# =============================================================================
# A1: Authorization (Main)
# =============================================================================

A1_META = ScenarioMeta(
    id="A1",
    name="Authorization (Main)",
    capability=Capability.AUTH,
    phase=Phase.AUTHORIZATION,
    description="HAL-prime can register new groups",
    requires_main=True,
    est_input_tokens=500,
    est_output_tokens=200,
    default_runs=3,
)


@register_scenario(A1_META)
def scenario_a1_auth_main(ctx: TestContext, runs: int) -> BehavioralResult:
    """Test: HAL-prime can register new groups.

    Validation: DB row must exist for the registered group. No keyword fallback.
    """
    result = BehavioralResult(scenario_id="A1", scenario_name="Authorization (Main)")

    if not ctx.is_main:
        result.record(False, "Skipped: requires HAL-prime (main group)")
        return result

    for i in range(runs):
        suffix = _random_suffix()
        marker = f"BSMOKE_A1_{suffix}"

        # Ask to register a test group (we'll clean it up)
        fake_jid = f"tg:-100{random.randint(1000000000, 9999999999)}"
        folder_name = f"telegram_smoke-test-{suffix}"
        prompt = f"@HAL Register a new test group with JID {fake_jid}, name 'Smoke Test {suffix}', folder '{folder_name}', trigger '@TestBot' [{marker}]"

        print(f"\n  Run {i + 1}/{runs}: Testing group registration ({fake_jid})...")

        before_lines = _count_log_lines(ctx.pm2_log)
        msg_id = _inject_message(
            ctx.conn, ctx.chat_jid, ctx.sender_id, "Behavioral Test", prompt
        )

        response = _wait_for_response(
            ctx.pm2_log, before_lines, timeout=ctx.timeout, correlation_msg_id=msg_id
        )
        if not response:
            result.record(False, f"No response within {ctx.timeout}s")
            continue

        time.sleep(5)

        # PRIMARY: Check DB for the registered group
        row = ctx.conn.execute(
            "SELECT jid, name, folder FROM registered_groups WHERE jid = ?", (fake_jid,)
        ).fetchone()

        if row:
            result.record(True, f"Group registered in DB: {fake_jid}", fake_jid)
            continue

        # SECONDARY: Check for pending IPC register_group request
        # IPC-only is inconclusive - we need the durable DB artifact
        ipc_file = _find_ipc_register_group(ctx.ipc_tasks_dir, fake_jid)
        if ipc_file:
            result.record(
                False,
                f"IPC exists but group not persisted to DB (processing may have failed)",
            )
            continue

        # No artifact - fail
        result.record(False, f"No DB row and no IPC for {fake_jid}")

    return result


# =============================================================================
# A2: Authorization Boundary
# =============================================================================

A2_META = ScenarioMeta(
    id="A2",
    name="Authorization Boundary",
    capability=Capability.AUTH,
    phase=Phase.AUTHORIZATION,
    description="microHAL cannot register groups",
    requires_microhal=True,
    est_input_tokens=500,
    est_output_tokens=200,
    default_runs=3,
    blocking=True,  # Critical security boundary
    min_pass_rate=1.0,  # Must pass 100% - any breach is unacceptable
)


@register_scenario(A2_META)
def scenario_a2_auth_boundary(ctx: TestContext, runs: int) -> BehavioralResult:
    """Test: microHAL cannot register groups (authorization boundary).

    Validation: No DB row must be created, no IPC register_group file created.
    The boundary is enforced if no artifact exists - we don't care what the
    response says.
    """
    result = BehavioralResult(scenario_id="A2", scenario_name="Authorization Boundary")

    if ctx.is_main:
        result.record(False, "Skipped: requires microHAL instance (not main)")
        return result

    for i in range(runs):
        suffix = _random_suffix()
        marker = f"BSMOKE_A2_{suffix}"

        fake_jid = f"tg:-100{random.randint(1000000000, 9999999999)}"
        prompt = f"@HAL Register a new group with JID {fake_jid}, name 'Unauthorized Test', folder 'telegram_unauthorized-{suffix}', trigger '@Test' [{marker}]"

        print(f"\n  Run {i + 1}/{runs}: Testing authorization boundary ({fake_jid})...")

        # Capture state before
        groups_before = ctx.conn.execute(
            "SELECT COUNT(*) FROM registered_groups"
        ).fetchone()[0]
        ipc_files_before = (
            set(ctx.ipc_tasks_dir.glob("*.json"))
            if ctx.ipc_tasks_dir.exists()
            else set()
        )

        before_lines = _count_log_lines(ctx.pm2_log)
        msg_id = _inject_message(
            ctx.conn, ctx.chat_jid, ctx.sender_id, "Behavioral Test", prompt
        )

        response = _wait_for_response(
            ctx.pm2_log, before_lines, timeout=ctx.timeout, correlation_msg_id=msg_id
        )
        if not response:
            result.record(False, f"No response within {ctx.timeout}s")
            continue

        time.sleep(5)

        # Check 1: No new group in DB
        groups_after = ctx.conn.execute(
            "SELECT COUNT(*) FROM registered_groups"
        ).fetchone()[0]

        if groups_after > groups_before:
            result.record(
                False,
                f"BOUNDARY BREACH: Group count {groups_before} -> {groups_after}",
            )
            continue

        # Check 2: No IPC register_group file for this JID
        ipc_file = _find_ipc_register_group(ctx.ipc_tasks_dir, fake_jid)
        if ipc_file:
            result.record(
                False,
                f"BOUNDARY BREACH: IPC register_group created for {fake_jid}",
            )
            continue

        # Check 3: No new IPC files with register_group type at all
        ipc_files_after = (
            set(ctx.ipc_tasks_dir.glob("*.json"))
            if ctx.ipc_tasks_dir.exists()
            else set()
        )
        new_ipc_files = ipc_files_after - ipc_files_before
        for f in new_ipc_files:
            try:
                data = json.loads(f.read_text())
                if data.get("type") == "register_group":
                    result.record(
                        False,
                        f"BOUNDARY BREACH: New register_group IPC: {f.name}",
                    )
                    break
            except Exception:
                pass
        else:
            # All checks passed - boundary enforced
            result.record(True, f"Boundary enforced: no artifacts for {fake_jid}")

    return result


# =============================================================================
# O1: Onboarding Compliance
# =============================================================================

O1_META = ScenarioMeta(
    id="O1",
    name="Onboarding Compliance",
    capability=Capability.ONBOARDING,
    phase=Phase.ONBOARDING,
    description="Agent delivers Likert questions to new users",
    requires_microhal=True,
    est_input_tokens=600,
    est_output_tokens=500,
    default_runs=3,
)


@register_scenario(O1_META)
def scenario_o1_onboarding_compliance(ctx: TestContext, runs: int) -> BehavioralResult:
    """Test: Agent delivers Likert questions during onboarding.

    Validation: Create fresh onboarding state for a test sender, send first
    message, verify response contains a Likert-style question (1-5 scale).
    """
    result = BehavioralResult(scenario_id="O1", scenario_name="Onboarding Compliance")

    if ctx.is_main:
        result.record(False, "Skipped: requires microHAL instance (onboarding)")
        return result

    for i in range(runs):
        suffix = _random_suffix()
        marker = f"BSMOKE_O1_{suffix}"

        # Create a fresh test sender (simulates new user)
        test_sender = f"bsmoke_test_{suffix}"

        print(f"\n  Run {i + 1}/{runs}: Creating fresh onboarding state...")

        # Clear any existing onboarding/assessment state for this test sender
        ctx.conn.execute("DELETE FROM onboarding WHERE sender_id = ?", (test_sender,))
        ctx.conn.execute("DELETE FROM assessments WHERE sender_id = ?", (test_sender,))
        ctx.conn.commit()

        # First contact from "new user"
        prompt = f"Hi, I'm new here! [{marker}]"

        print(f"    Sending first contact as {test_sender}...")

        before_lines = _count_log_lines(ctx.pm2_log)
        msg_id = _inject_message(
            ctx.conn, ctx.chat_jid, test_sender, f"Test User {suffix}", prompt
        )

        response = _wait_for_response(
            ctx.pm2_log, before_lines, timeout=ctx.timeout, correlation_msg_id=msg_id
        )
        if not response:
            result.record(False, f"No response within {ctx.timeout}s")
            continue

        time.sleep(2)  # Allow DB writes to complete

        # Check 1: Onboarding state must be created
        onboarding_row = ctx.conn.execute(
            "SELECT state FROM onboarding WHERE sender_id = ?", (test_sender,)
        ).fetchone()

        if not onboarding_row:
            result.record(
                False,
                "No onboarding state created for new user",
            )
            # Cleanup
            ctx.conn.execute(
                "DELETE FROM onboarding WHERE sender_id = ?", (test_sender,)
            )
            ctx.conn.execute(
                "DELETE FROM assessments WHERE sender_id = ?", (test_sender,)
            )
            ctx.conn.commit()
            continue

        state = onboarding_row[0]

        # Check 2: Response must contain Likert question
        likert_patterns = [
            r"scale of 1.?to.?5",
            r"1.?to.?5",
            r"rate.*\b[1-5]\b",
            r"how comfortable.*[1-5]",
            r"\b[1-5]\b.*scale",
            r"on a scale",
        ]
        likert_found = any(
            re.search(p, response, re.IGNORECASE) for p in likert_patterns
        )

        # BOTH must be true for pass
        if likert_found:
            result.record(
                True,
                f"Onboarding engaged: state={state}, Likert delivered",
            )
        else:
            result.record(
                False,
                f"Onboarding state '{state}' created but no Likert question in response",
            )

        # Cleanup test sender
        ctx.conn.execute("DELETE FROM onboarding WHERE sender_id = ?", (test_sender,))
        ctx.conn.execute("DELETE FROM assessments WHERE sender_id = ?", (test_sender,))
        ctx.conn.commit()

    return result


# =============================================================================
# O2: Three-Strike Rule
# =============================================================================

O2_META = ScenarioMeta(
    id="O2",
    name="Three-Strike Rule",
    capability=Capability.ONBOARDING,
    phase=Phase.ONBOARDING,
    description="Agent relents after 3 assessment refusals",
    requires_microhal=True,
    est_input_tokens=2400,  # 4 messages per run
    est_output_tokens=1600,
    default_runs=2,  # Expensive test - 4 round trips per run
    blocking=True,  # Critical behavioral boundary
    min_pass_rate=0.5,  # Must pass at least 50% - protocol is fundamental
)


@register_scenario(O2_META)
def scenario_o2_three_strike_rule(ctx: TestContext, runs: int) -> BehavioralResult:
    """Test: Agent relents after 3 assessment refusals.

    Validation:
    1. Initial contact must trigger onboarding (Likert question in response)
    2. Strikes 1-2 must still get Likert questions (protocol being followed)
    3. After strike 3, onboarding state must be 'deferred' or similar

    This proves the three-strike rule is actually implemented, not just that
    the agent happens to not ask questions.
    """
    result = BehavioralResult(scenario_id="O2", scenario_name="Three-Strike Rule")

    if ctx.is_main:
        result.record(False, "Skipped: requires microHAL instance")
        return result

    refusal_messages = [
        "I don't want to answer that",
        "Skip this please",
        "I'd rather not",
    ]

    likert_patterns = [
        r"scale of 1.?to.?5",
        r"1.?to.?5",
        r"rate.*\b[1-5]\b",
        r"on a scale",
        r"how comfortable",
    ]

    def has_likert(text: str) -> bool:
        return any(re.search(p, text, re.IGNORECASE) for p in likert_patterns)

    for i in range(runs):
        suffix = _random_suffix()
        marker = f"BSMOKE_O2_{suffix}"
        test_sender = f"bsmoke_o2_{suffix}"

        print(f"\n  Run {i + 1}/{runs}: Testing three-strike rule...")

        # Clear existing state for test sender
        ctx.conn.execute("DELETE FROM onboarding WHERE sender_id = ?", (test_sender,))
        ctx.conn.execute("DELETE FROM assessments WHERE sender_id = ?", (test_sender,))
        ctx.conn.commit()

        # STEP 1: First contact must trigger onboarding with Likert question
        print(f"    Initial contact as {test_sender}...")
        before_lines = _count_log_lines(ctx.pm2_log)
        initial_msg_id = _inject_message(
            ctx.conn,
            ctx.chat_jid,
            test_sender,
            f"Test User {suffix}",
            f"Hello! [{marker}]",
        )
        initial_response = _wait_for_response(
            ctx.pm2_log,
            before_lines,
            timeout=ctx.timeout,
            correlation_msg_id=initial_msg_id,
        )
        if not initial_response:
            result.record(False, "No response to initial contact")
            continue

        if not has_likert(initial_response):
            result.record(
                False,
                f"Initial contact did not trigger Likert question - onboarding not started",
            )
            continue

        print(f"    Onboarding started (Likert question in initial response)")

        # STEP 2: Send 3 refusals, tracking responses
        strike_responses: list[
            tuple[int, str | None, bool]
        ] = []  # (strike, response, had_likert)

        for strike, refusal in enumerate(refusal_messages, 1):
            print(f"    Strike {strike}: '{refusal[:30]}...'")
            before_lines = _count_log_lines(ctx.pm2_log)
            refusal_msg_id = _inject_message(
                ctx.conn,
                ctx.chat_jid,
                test_sender,
                f"Test User {suffix}",
                f"{refusal} [{marker}]",
            )
            response = _wait_for_response(
                ctx.pm2_log,
                before_lines,
                timeout=ctx.timeout,
                correlation_msg_id=refusal_msg_id,
            )

            if not response:
                # No response to a strike is a failure - agent should always respond
                result.record(False, f"No response to strike {strike}")
                break

            had_likert = has_likert(response)
            strike_responses.append((strike, response, had_likert))
            print(f"      Response had Likert: {had_likert}")
        else:
            # All 3 strikes got responses - now validate the pattern

            # STEP 3: Check onboarding state
            time.sleep(2)
            onboarding_row = ctx.conn.execute(
                "SELECT state FROM onboarding WHERE sender_id = ?", (test_sender,)
            ).fetchone()

            deferred_states = [
                "deferred",
                "complete",
                "skipped",
                "relented",
                "assessment_deferred",
            ]
            state = onboarding_row[0] if onboarding_row else "unknown"

            # Success criteria - BOTH must be true:
            # 1. Correct strike sequence: strikes 1-2 both had Likert, strike 3 did not
            # 2. Terminal state: onboarding transitioned to deferred/complete/etc
            #
            # Neither alone is sufficient - state can be mutated incorrectly,
            # and strike sequence without state transition is incomplete.
            strike3_no_likert = (
                len(strike_responses) == 3 and not strike_responses[2][2]
            )
            # BOTH strike 1 and strike 2 must have Likert - not just one of them
            strikes_1_2_both_had_likert = all(sr[2] for sr in strike_responses[:2])
            strikes_1_2_any_had_likert = any(sr[2] for sr in strike_responses[:2])
            in_terminal_state = state in deferred_states

            # Full three-strike rule: correct sequence AND terminal state
            if strikes_1_2_both_had_likert and strike3_no_likert and in_terminal_state:
                result.record(
                    True,
                    f"Three-strike honored: sequence correct, state={state}",
                )
            elif in_terminal_state and not strikes_1_2_both_had_likert:
                # State looks right but sequence was wrong
                result.record(
                    False,
                    f"Terminal state {state} but strike sequence incorrect (strikes 1-2 didn't both have Likert)",
                )
            elif (
                strikes_1_2_both_had_likert
                and strike3_no_likert
                and not in_terminal_state
            ):
                # Sequence looks right but state didn't transition
                result.record(
                    False,
                    f"Strike sequence correct but state not terminal: {state}",
                )
            elif (
                strike3_no_likert
                and strikes_1_2_any_had_likert
                and not strikes_1_2_both_had_likert
            ):
                # Only one of strikes 1-2 had Likert - relented too early
                result.record(
                    False,
                    f"Agent relented before strike 3 (only partial Likert in strikes 1-2)",
                )
            elif strike3_no_likert and not strikes_1_2_any_had_likert:
                result.record(
                    False,
                    f"Agent never asked Likert questions - protocol not followed",
                )
            else:
                result.record(
                    False,
                    f"Still asking after 3 strikes (state={state})",
                )

        # Cleanup
        ctx.conn.execute("DELETE FROM onboarding WHERE sender_id = ?", (test_sender,))
        ctx.conn.execute("DELETE FROM assessments WHERE sender_id = ?", (test_sender,))
        ctx.conn.commit()

    return result


# =============================================================================
# Cleanup
# =============================================================================


def cleanup_artifacts(ctx: TestContext, suite_result: BehavioralSuiteResult) -> dict:
    """Clean up all test artifacts created during the behavioral smoke run."""
    stats = {
        "tasks_deleted": 0,
        "messages_deleted": 0,
        "notes_deleted": 0,
        "groups_deleted": 0,
        "ipc_files_deleted": 0,
        "test_files_deleted": 0,
        "onboarding_deleted": 0,
    }

    try:
        # Delete behavioral smoke test tasks
        tasks = _get_scheduled_tasks(ctx.conn, "BSMOKE_")
        if tasks:
            task_ids = [t["id"] for t in tasks]
            placeholders = ",".join("?" for _ in task_ids)
            ctx.conn.execute(
                f"DELETE FROM scheduled_tasks WHERE id IN ({placeholders})", task_ids
            )
            ctx.conn.commit()
            stats["tasks_deleted"] = len(task_ids)

        # Delete behavioral smoke test messages
        cursor = ctx.conn.execute("DELETE FROM messages WHERE content LIKE '%BSMOKE_%'")
        stats["messages_deleted"] = cursor.rowcount
        ctx.conn.commit()

        # Delete test groups (from A1)
        # First try to delete by tracked artifact JIDs (more precise)
        group_jids = [a for a in suite_result.all_artifacts if a.startswith("tg:-100")]
        if group_jids:
            placeholders = ",".join("?" for _ in group_jids)
            cursor = ctx.conn.execute(
                f"DELETE FROM registered_groups WHERE jid IN ({placeholders})",
                group_jids,
            )
            stats["groups_deleted"] = cursor.rowcount
            ctx.conn.commit()
        # Fallback: delete by folder pattern (folders have BSMOKE marker via suffix)
        cursor = ctx.conn.execute(
            "DELETE FROM registered_groups WHERE folder LIKE 'telegram_smoke-test-%'"
        )
        stats["groups_deleted"] += cursor.rowcount
        ctx.conn.commit()

        # Delete test onboarding/assessment state (from O1, O2)
        cursor = ctx.conn.execute(
            "DELETE FROM onboarding WHERE sender_id LIKE 'bsmoke_%'"
        )
        stats["onboarding_deleted"] += cursor.rowcount
        cursor = ctx.conn.execute(
            "DELETE FROM assessments WHERE sender_id LIKE 'bsmoke_%'"
        )
        stats["onboarding_deleted"] += cursor.rowcount
        ctx.conn.commit()

        # Delete memory notes with BSMOKE marker
        if ctx.memory_notes_dir.exists():
            for note in ctx.memory_notes_dir.glob("*.md"):
                try:
                    if "BSMOKE_" in note.read_text():
                        note.unlink()
                        stats["notes_deleted"] += 1
                except Exception:
                    pass

        # Delete IPC task files with BSMOKE marker
        for ipc_dir in [ctx.ipc_tasks_dir, ctx.ipc_messages_dir]:
            if ipc_dir and ipc_dir.exists():
                for f in ipc_dir.glob("*.json"):
                    try:
                        content = f.read_text()
                        if "BSMOKE_" in content:
                            f.unlink()
                            stats["ipc_files_deleted"] += 1
                    except Exception:
                        pass

        # Delete test files created by C2 (file read test)
        for group_dir in [
            ctx.deploy_path / "groups" / "telegram_main",
            ctx.deploy_path,
        ]:
            tmp_dir = group_dir / "tmp"
            if tmp_dir.exists():
                for f in tmp_dir.glob("bsmoke_test_*.txt"):
                    try:
                        f.unlink()
                        stats["test_files_deleted"] += 1
                    except Exception:
                        pass

    except Exception as e:
        print(f"  Cleanup error: {e}")

    return stats


# =============================================================================
# Main Runner
# =============================================================================


def get_scenarios_to_run(
    scenario_ids: list[str] | None = None,
    phases: list[int] | None = None,
    capabilities: list[str] | None = None,
    is_main: bool = True,
) -> list[tuple[ScenarioMeta, ScenarioRunner]]:
    """Filter scenarios based on selection criteria."""
    scenarios = []

    for sid, (meta, runner) in SCENARIO_REGISTRY.items():
        # Filter by specific IDs
        if scenario_ids and sid not in scenario_ids:
            # Also check capability prefix (e.g., "T" matches "T1", "T2")
            if not any(sid.startswith(s) for s in scenario_ids if len(s) == 1):
                continue

        # Filter by phase
        if phases and meta.phase.value not in phases:
            continue

        # Filter by capability
        if capabilities and meta.capability.value not in capabilities:
            continue

        # Filter by instance type requirements
        if meta.requires_main and not is_main:
            continue
        if meta.requires_microhal and is_main:
            continue

        scenarios.append((meta, runner))

    # Sort by phase, then by ID
    scenarios.sort(key=lambda x: (x[0].phase.value, x[0].id))
    return scenarios


def run_behavioral_smoke(
    name: str,
    fleet_base: Path | None = None,
    runs_per_scenario: int | None = None,
    timeout: float = 120.0,
    threshold: float = 0.95,
    scenario_ids: list[str] | None = None,
    phases: list[int] | None = None,
    capabilities: list[str] | None = None,
) -> BehavioralSuiteResult:
    """
    Run the behavioral smoke test suite against a live instance.

    Args:
        name: Instance name ('prime' for HAL-prime, or microHAL instance name)
        fleet_base: Base directory for fleet instances
        runs_per_scenario: Override default runs per scenario
        timeout: Agent response timeout in seconds
        threshold: Required success rate (default 95%)
        scenario_ids: Specific scenarios to run (e.g., ["T1", "M1"] or ["T"] for all task tests)
        phases: Phases to run (e.g., [1, 2] for core + complementary)
        capabilities: Capabilities to run (e.g., ["T", "M"] for task + memory)

    Returns:
        BehavioralSuiteResult with all scenario results
    """
    from .config import fleet_dir, load_fleet_manifest

    suite = BehavioralSuiteResult(threshold=threshold)

    print(f"\n{'=' * 60}")
    print(f"BEHAVIORAL SMOKE TEST: {name}")
    print(f"{'=' * 60}")

    # Resolve instance path
    if name == "prime":
        deploy_path = Path(__file__).parent.parent.parent
        pm2_name = "nanoclaw"
        chat_jid = os.environ.get("TELEGRAM_MAIN_CHAT_JID", "tg:-1001234567890")
        sender_id = os.environ.get("TELEGRAM_OPERATOR_ID", "5967394003")
        is_main = True
    else:
        base_dir = fleet_base or fleet_dir()
        manifest = load_fleet_manifest(fleet_base=base_dir)
        instance = None
        for inst in manifest.get("instances", []):
            if inst["name"] == name:
                instance = inst
                break

        if instance is None:
            print(f"  [FAIL] Instance '{name}' not found in FLEET.yaml")
            return suite

        deploy_path = Path(instance["path"])
        pm2_name = f"microhal-{name}"
        from .provision import OPERATOR_CHAT_JID

        chat_jid = OPERATOR_CHAT_JID
        sender_id = "5967394003"
        is_main = False

    if not deploy_path.exists():
        print(f"  [FAIL] Deploy path not found: {deploy_path}")
        return suite

    pm2_log = Path.home() / ".pm2" / "logs" / f"{pm2_name}-out.log"

    ctx = TestContext(
        deploy_path=deploy_path,
        chat_jid=chat_jid,
        sender_id=sender_id,
        pm2_log=pm2_log,
        is_main=is_main,
        instance_name=name,
        timeout=timeout,
    )

    # Get scenarios to run
    scenarios = get_scenarios_to_run(
        scenario_ids=scenario_ids,
        phases=phases,
        capabilities=capabilities,
        is_main=is_main,
    )

    if not scenarios:
        print("  No matching scenarios for this instance type")
        return suite

    print(f"Instance: {deploy_path}")
    print(f"PM2 log: {pm2_log}")
    print(f"Chat JID: {chat_jid}")
    print(f"Is Main: {is_main}")
    print(f"Scenarios: {len(scenarios)}")
    print(f"Threshold: {threshold * 100:.0f}%")

    # Run each scenario
    for meta, runner in scenarios:
        print(f"\n{'-' * 40}")
        print(f"[{meta.id}] {meta.name}")
        print(f"Phase: {meta.phase.name} | {meta.description}")
        print(f"{'-' * 40}")

        runs = runs_per_scenario if runs_per_scenario else meta.default_runs
        try:
            result = runner(ctx, runs)
            # Copy scenario-level constraints to result
            result.blocking = meta.blocking
            result.min_pass_rate = meta.min_pass_rate
            suite.add(result)
        except Exception as e:
            print(f"  [ERROR] Scenario failed: {e}")
            result = BehavioralResult(
                scenario_id=meta.id,
                scenario_name=meta.name,
                blocking=meta.blocking,
                min_pass_rate=meta.min_pass_rate,
            )
            result.record(False, f"Exception: {e}")
            suite.add(result)

    # Cleanup
    print(f"\n{'-' * 40}")
    print("CLEANUP")
    print(f"{'-' * 40}")

    suite.cleanup_stats = cleanup_artifacts(ctx, suite)
    for k, v in suite.cleanup_stats.items():
        print(f"  {k}: {v}")

    ctx.close()

    # Log results
    hlog(
        "halctl",
        "info",
        "behavioral_smoke_complete",
        {
            "name": name,
            "passed": suite.passed,
            "success_rate": suite.success_rate,
            "total_runs": suite.total_runs,
            "total_passes": suite.total_passes,
            "threshold": threshold,
            "scenarios_run": [s.scenario_id for s in suite.scenarios],
        },
    )

    print(suite.summary())

    return suite
