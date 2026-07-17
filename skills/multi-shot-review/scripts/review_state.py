#!/usr/bin/env python3
"""State management and runner helpers for multi-shot Codex reviews."""

from __future__ import annotations

import argparse
import fcntl
import json
import os
import re
import secrets
import shutil
import subprocess
import sys
import tempfile
import time
import uuid
from concurrent.futures import ThreadPoolExecutor, as_completed
from contextlib import AbstractContextManager
from dataclasses import dataclass
from datetime import datetime, timezone
from pathlib import Path
from typing import Any, Callable, Iterable


SCHEMA_VERSION = 1
DEFAULT_MODEL = "gpt-5.6-terra"
DEFAULT_REASONING = "high"
MAX_ACTIVE_SLICES = 10
TASK_ENTRYPOINT = "task.md"
RELATED_TASKS_DIR = "related-tasks"
ORIGINAL_REQUEST_START = "<!-- multi-shot-review:original-request:start -->"
ORIGINAL_REQUEST_END = "<!-- multi-shot-review:original-request:end -->"
SLICE_RE = re.compile(r"^[a-z0-9][a-z0-9._-]{0,63}$")
PRIORITY_RE = re.compile(r"\[(?:P[0-3])\]", re.IGNORECASE)
REVIEW_COMMENT_RE = re.compile(r"Review comment:", re.IGNORECASE)
FULL_REVIEW_COMMENTS_RE = re.compile(r"^Full review comments:\s*(.*)", re.IGNORECASE | re.DOTALL | re.MULTILINE)
QUIET_RE = re.compile(
    r"\b(no actionable issues|no blocking issues|no findings|no issues found|did not find\b.*\b(?:bug|issue|problem|defect)s?|lgtm|looks good to me)\b"
    r"|(?=[\s\S]*\b(?:is|are|remains?|looks?) consistent with\b)(?=[\s\S]*\b(?:tests?|typechecks?|checks?)\b[\w\s/-]*\bpassed\b)",
    re.IGNORECASE,
)
CONTRAST_RE = re.compile(r"\b(but|however|except|although)\b", re.IGNORECASE)
QUIET_SUMMARY_RE = re.compile(
    r"^\s*(?:no actionable issues(?: found)?|no blocking issues(?: found)?|no findings(?: found)?|no issues found|lgtm|looks good to me)\.?\s*$",
    re.IGNORECASE,
)
EMPTY_SUMMARY_RE = re.compile(r"^\s*(?:none|n/a|no comments?)\.?\s*$", re.IGNORECASE)
QUIET_PRIORITY_RE = re.compile(
    r"\b(?:there\s+(?:are|were)\s+)?no\s+(?:findings|issues)\s+(?:above|at or above)\s+\[(?:P[0-3])\]|\b(?:there\s+(?:are|were)\s+)?no\s+(?:\[(?:P[0-3])\](?:(?:\s*,\s*|\s+(?:or|and)\s+|\s*,\s*(?:or|and)\s+)\[(?:P[0-3])\])*\s+)?(?:findings|issues)(?:\s+remain)?|\bi did not find\s+(?:any\s+)?(?:\[(?:P[0-3])\](?:(?:\s*,\s*|\s+(?:or|and)\s+|\s*,\s*(?:or|and)\s+)\[(?:P[0-3])\])*\s+)?(?:findings|issues|bugs|problems|defects)",
    re.IGNORECASE,
)


class ReviewStateError(RuntimeError):
    """Raised when review state is invalid or a requested mutation is rejected."""


def now_iso() -> str:
    return datetime.now(timezone.utc).isoformat(timespec="milliseconds").replace("+00:00", "Z")


def filename_timestamp() -> str:
    return datetime.now(timezone.utc).strftime("%Y%m%d-%H%M")


def session_id() -> str:
    return f"{filename_timestamp()}-{secrets.token_hex(4)}"


def parse_iso(value: str) -> datetime | None:
    try:
        return datetime.fromisoformat(value.replace("Z", "+00:00"))
    except ValueError:
        return None


def repo_root(path: Path | None = None) -> Path:
    start = Path.cwd() if path is None else path
    try:
        proc = subprocess.run(
            ["git", "rev-parse", "--show-toplevel"],
            cwd=start,
            text=True,
            stdout=subprocess.PIPE,
            stderr=subprocess.PIPE,
            check=False,
        )
    except OSError:
        return start.resolve()
    if proc.returncode == 0 and proc.stdout.strip():
        return Path(proc.stdout.strip()).resolve()
    return start.resolve()


def create_review_dir(root: Path) -> Path:
    review_root = root.resolve() / ".review"
    for _ in range(10):
        review_dir = review_root / session_id()
        try:
            review_dir.mkdir(parents=True, exist_ok=False)
        except FileExistsError:
            continue
        return review_dir
    raise ReviewStateError("could not create a unique review directory after 10 attempts")


def init_review_state(root: Path, task: str, *, target: dict[str, str] | None = None) -> Path:
    task = _require_non_empty_text(task, "task")
    review_dir = create_review_dir(root)
    write_task_entrypoint(review_dir, task)
    state = ReviewState.new(
        review_dir=review_dir,
        root=root.resolve(),
        target=target or {"kind": "uncommitted"},
    )
    state.save()
    return review_dir


def task_entrypoint(review_dir: Path) -> Path:
    return review_dir.resolve() / TASK_ENTRYPOINT


def related_tasks_dir(review_dir: Path) -> Path:
    return review_dir.resolve() / RELATED_TASKS_DIR


def write_task_entrypoint(review_dir: Path, original_request: str) -> None:
    original_request = _require_non_empty_text(original_request, "task")
    review_dir = review_dir.resolve()
    related_tasks_dir(review_dir).mkdir(parents=True, exist_ok=True)
    _atomic_write_text(task_entrypoint(review_dir), _render_task_entrypoint(review_dir, original_request))


def add_related_task(review_dir: Path, name: str, *, text: str | None, file: Path | None, directory: Path | None) -> None:
    ReviewState._validate_slice_name(name)
    input_count = sum(value is not None for value in (text, file, directory))
    if input_count != 1:
        raise ReviewStateError("choose exactly one related task input: --text, --file, or --dir")

    review_dir = review_dir.resolve()
    with ReviewState.locked(review_dir):
        entrypoint = task_entrypoint(review_dir)
        if not entrypoint.exists():
            raise ReviewStateError(f"missing task entrypoint: {entrypoint}")

        related_dir = related_tasks_dir(review_dir)
        related_dir.mkdir(parents=True, exist_ok=True)
        file_target = related_dir / f"{name}.md"
        dir_target = related_dir / name
        tmp_target: Path | None = None

        try:
            if text is not None:
                tmp_target = related_dir / f".{name}.{uuid.uuid4().hex}.tmp.md"
                tmp_target.write_text(_require_non_empty_text(text, "related task text"), encoding="utf-8")
                final_target = file_target
            elif file is not None:
                if not file.is_file():
                    raise ReviewStateError(f"related task file is not a file: {file}")
                source_text = _require_non_empty_text(file.read_text(encoding="utf-8"), "related task file")
                tmp_target = related_dir / f".{name}.{uuid.uuid4().hex}.tmp.md"
                tmp_target.write_text(source_text, encoding="utf-8")
                final_target = file_target
            elif directory is not None:
                if not directory.is_dir():
                    raise ReviewStateError(f"related task directory is not a directory: {directory}")
                if _path_is_relative_to(related_dir.resolve(), directory.resolve()):
                    raise ReviewStateError("related task directory cannot contain the review directory")
                tmp_target = related_dir / f".{name}.{uuid.uuid4().hex}.tmp"
                shutil.copytree(directory, tmp_target)
                final_target = dir_target

            backups = _backup_related_task_targets(
                file_target=file_target,
                dir_target=dir_target,
            )
            replaced = False
            try:
                os.replace(tmp_target, final_target)
                replaced = True
                tmp_target = None
                refresh_task_entrypoint(review_dir)
            except Exception:
                if replaced:
                    _remove_related_task_target(final_target)
                _restore_related_task_backups(backups)
                raise
            _remove_related_task_backups(backups)
            tmp_target = None
        finally:
            if tmp_target is not None and tmp_target.exists():
                _remove_related_task_target(tmp_target)


def refresh_task_entrypoint(review_dir: Path) -> None:
    review_dir = review_dir.resolve()
    entrypoint = task_entrypoint(review_dir)
    if not entrypoint.exists():
        raise ReviewStateError(f"missing task entrypoint: {entrypoint}")
    original_request = _extract_original_request(entrypoint.read_text(encoding="utf-8"))
    _atomic_write_text(entrypoint, _render_task_entrypoint(review_dir, original_request))


def build_task_context_prompt(review_dir: Path) -> str:
    entrypoint = task_entrypoint(review_dir)
    if not entrypoint.exists():
        raise ReviewStateError(f"missing task entrypoint: {entrypoint}")
    return (
        "Review task context:\n"
        f"- Read {entrypoint} before reviewing.\n"
        "- It contains the original user request and any related/future tasks.\n"
        "- Treat related/future tasks as deferred-work context, not as part of the current review scope.\n"
        "- Avoid flagging missing follow-up work when it is clearly covered by related/future tasks.\n"
    )


def _require_non_empty_text(value: str, label: str) -> str:
    if not isinstance(value, str) or not value.strip():
        raise ReviewStateError(f"{label} must be non-empty")
    return value.strip()


def _validate_session_target(target: Any) -> dict[str, str]:
    if not isinstance(target, dict):
        raise ReviewStateError("target must be an object")
    kind = target.get("kind")
    if kind == "uncommitted":
        if set(target) != {"kind"}:
            raise ReviewStateError("uncommitted target accepts only kind")
        return {"kind": "uncommitted"}
    if kind not in {"base", "commit"}:
        raise ReviewStateError("target kind must be uncommitted, base, or commit")
    value = target.get("value")
    if not isinstance(value, str) or not value.strip():
        raise ReviewStateError(f"{kind} target requires a value")
    if set(target) != {"kind", "value"}:
        raise ReviewStateError(f"{kind} target accepts only kind and value")
    return {"kind": kind, "value": value.strip()}


def _native_target_from_session(target: dict[str, str]) -> dict[str, Any]:
    target = _validate_session_target(target)
    if target["kind"] == "uncommitted":
        return {"uncommitted": True}
    return {target["kind"]: target["value"]}


def _render_task_entrypoint(review_dir: Path, original_request: str) -> str:
    original_request = _require_non_empty_text(original_request, "task")
    related_items = _related_task_index_items(review_dir)
    related_section = "\n".join(related_items) if related_items else "No related/future tasks registered."
    return (
        "# Review Task\n\n"
        "## Original User Request\n\n"
        f"{ORIGINAL_REQUEST_START}\n"
        f"{original_request}\n\n"
        f"{ORIGINAL_REQUEST_END}\n\n"
        "## Related/Future Tasks\n\n"
        f"{related_section}\n\n"
        "## Reviewer Guidance\n\n"
        "- Review the current slice against the original user request.\n"
        "- Treat related/future tasks as deferred-work context, not as current review scope.\n"
        "- Do not flag missing follow-up work when it is clearly covered by a related/future task.\n"
        "- Report actionable findings introduced, worsened, or made reachable by the change when "
        "they have plausible production impact or imminent maintainability impact.\n"
        "- Missing-test findings require a meaningful regression path.\n"
        "- Return no findings when this threshold is unmet.\n"
        "- An explicit lower threshold in the original user request takes precedence.\n"
    )


def _related_task_index_items(review_dir: Path) -> list[str]:
    related_dir = related_tasks_dir(review_dir)
    if not related_dir.exists():
        return []
    items: list[str] = []
    for path in sorted(related_dir.iterdir(), key=lambda item: item.name):
        if path.name.startswith("."):
            continue
        if path.is_file() and path.suffix == ".md":
            items.append(f"- [{path.stem}]({RELATED_TASKS_DIR}/{path.name})")
        elif path.is_dir():
            items.append(f"- [{path.name}]({RELATED_TASKS_DIR}/{path.name}/)")
    return items


def _extract_original_request(task_text: str) -> str:
    if ORIGINAL_REQUEST_START in task_text and ORIGINAL_REQUEST_END in task_text:
        original_request = task_text.split(ORIGINAL_REQUEST_START, 1)[1].rsplit(ORIGINAL_REQUEST_END, 1)[0]
        return _require_non_empty_text(original_request, "task")

    start_marker = "## Original User Request\n\n"
    end_marker = "\n\n## Related/Future Tasks\n\n"
    if start_marker not in task_text or end_marker not in task_text:
        raise ReviewStateError("task entrypoint has an unsupported format")
    original_request = task_text.split(start_marker, 1)[1].split(end_marker, 1)[0]
    return _require_non_empty_text(original_request, "task")


def _remove_related_task_target(path: Path) -> None:
    if path.is_dir():
        shutil.rmtree(path)
    elif path.exists():
        path.unlink()


def _backup_related_task_targets(
    *,
    file_target: Path,
    dir_target: Path,
) -> list[tuple[Path, Path]]:
    targets = [file_target, dir_target]
    backups: list[tuple[Path, Path]] = []
    for target in targets:
        if not target.exists():
            continue
        backup = target.parent / f".{target.name}.{uuid.uuid4().hex}.bak"
        os.replace(target, backup)
        backups.append((target, backup))
    return backups


def _restore_related_task_backups(backups: list[tuple[Path, Path]]) -> None:
    for target, backup in reversed(backups):
        if backup.exists():
            _remove_related_task_target(target)
            os.replace(backup, target)


def _remove_related_task_backups(backups: list[tuple[Path, Path]]) -> None:
    for _target, backup in backups:
        if backup.exists():
            _remove_related_task_target(backup)


def _atomic_write_text(path: Path, text: str) -> None:
    path.parent.mkdir(parents=True, exist_ok=True)
    tmp_path = path.parent / f".{path.name}.{uuid.uuid4().hex}.tmp"
    try:
        with tmp_path.open("w", encoding="utf-8") as fh:
            fh.write(text)
            fh.flush()
            os.fsync(fh.fileno())
        os.replace(tmp_path, path)
    finally:
        if tmp_path.exists():
            tmp_path.unlink()


def _path_is_relative_to(path: Path, parent: Path) -> bool:
    try:
        path.relative_to(parent)
    except ValueError:
        return False
    return True


def classify_output(text: str) -> str:
    """Return findings, quiet, or uncertain for a successful review output."""
    if count_findings(text) > 0:
        return "findings"

    if (QUIET_RE.search(text) and not CONTRAST_RE.search(text)) or any(
        QUIET_PRIORITY_RE.search(line) and not CONTRAST_RE.search(line) for line in text.splitlines()
    ):
        return "quiet"

    return "uncertain"


def count_findings(text: str) -> int:
    """Count recognizable review findings in successful Codex review output."""
    full_comments = FULL_REVIEW_COMMENTS_RE.search(text)
    if full_comments:
        body = full_comments.group(1).strip()
        if not body or re.fullmatch(r"(none\.?|n/a|no comments?\.?|no findings\.?)", body, re.IGNORECASE):
            return 0

        raw_lines = [line.rstrip() for line in body.splitlines() if line.strip()]
        lines = [line.strip() for line in raw_lines]
        bullet_lines = [line for line in raw_lines if re.match(r"^([-*]|\d+[.)])\s+", line)]
        if bullet_lines:
            finding_count = 0
            for line in bullet_lines:
                bullet_text = re.sub(r"^([-*]|\d+[.)])\s+", "", line)
                quiet_stripped = QUIET_PRIORITY_RE.sub("", bullet_text).strip(" \t.,;:")
                if EMPTY_SUMMARY_RE.fullmatch(bullet_text) or QUIET_SUMMARY_RE.fullmatch(bullet_text):
                    continue
                if not CONTRAST_RE.search(bullet_text) and QUIET_PRIORITY_RE.match(bullet_text) and not quiet_stripped:
                    continue
                finding_count += 1
            for line in raw_lines:
                if line.startswith((" ", "\t")) or re.match(r"^([-*]|\d+[.)])\s+", line):
                    continue
                line_without_quiet_priority = QUIET_PRIORITY_RE.sub("", line)
                finding_count += len(PRIORITY_RE.findall(line_without_quiet_priority))
            return finding_count
        body_priority_count = 0
        for line in lines:
            line_without_quiet_priority = QUIET_PRIORITY_RE.sub("", line)
            body_priority_count += len(PRIORITY_RE.findall(line_without_quiet_priority))
        if body_priority_count:
            return body_priority_count
        if all(_line_is_quiet_summary(line) for line in lines):
            return 0
        return 1

    priority_count = 0
    review_comment_count = 0
    for line in text.splitlines():
        line_without_quiet_priority = QUIET_PRIORITY_RE.sub("", line)
        priority_count += len(PRIORITY_RE.findall(line_without_quiet_priority))
        if REVIEW_COMMENT_RE.search(line_without_quiet_priority) and not PRIORITY_RE.search(line_without_quiet_priority):
            comment_text = REVIEW_COMMENT_RE.sub("", line_without_quiet_priority).strip()
            if comment_text:
                review_comment_count += 1
    if priority_count:
        return priority_count + review_comment_count

    review_comment_count = sum(
        1
        for line in text.splitlines()
        for _match in REVIEW_COMMENT_RE.finditer(line)
        if not _review_comment_is_quiet(line)
    )
    if review_comment_count:
        return review_comment_count
    return 0


def _review_comment_is_quiet(line: str) -> bool:
    comment_text = REVIEW_COMMENT_RE.sub("", line).strip()
    return bool(comment_text and _line_is_quiet_summary(comment_text))


def _line_is_quiet_summary(line: str) -> bool:
    return bool(
        EMPTY_SUMMARY_RE.fullmatch(line)
        or QUIET_SUMMARY_RE.fullmatch(line)
        or (QUIET_PRIORITY_RE.match(line) and not QUIET_PRIORITY_RE.sub("", line).strip(" \t.,;:"))
    )


def append_error(review_dir: Path, title: str, details: str) -> None:
    errors = review_dir / "_errors.md"
    with errors.open("a", encoding="utf-8") as fh:
        fh.write(f"## {now_iso()} {title}\n\n")
        fh.write(details.rstrip())
        fh.write("\n\n")


@dataclass(frozen=True)
class Reservation:
    run_id: str
    slice_name: str
    pass_number: int
    output_file: Path
    slice_data: dict[str, Any]


@dataclass(frozen=True)
class ReviewExecution:
    reservation: Reservation
    proc: subprocess.CompletedProcess[str]
    stdout_log: Path
    stderr_log: Path
    launch_error: OSError | None = None
    timed_out: bool = False


class LockedReviewState(AbstractContextManager["ReviewState"]):
    def __init__(self, review_dir: Path):
        self.review_dir = review_dir.resolve()
        self._fh: Any = None
        self.state: ReviewState | None = None

    def __enter__(self) -> "ReviewState":
        try:
            self.review_dir.mkdir(parents=True, exist_ok=True)
            self._fh = (self.review_dir / "_state.lock").open("a+", encoding="utf-8")
            fcntl.flock(self._fh.fileno(), fcntl.LOCK_EX)
            self.state = ReviewState.load(self.review_dir)
            return self.state
        except OSError as exc:
            self._release()
            raise ReviewStateError(f"could not open review state lock: {exc}") from exc
        except Exception:
            self._release()
            raise

    def __exit__(self, exc_type: object, exc: object, tb: object) -> bool:
        self._release()
        return False

    def _release(self) -> None:
        if self._fh is not None:
            fcntl.flock(self._fh.fileno(), fcntl.LOCK_UN)
            self._fh.close()
            self._fh = None
        self.state = None


class ReviewState:
    """Rich wrapper around the persisted review session state."""

    def __init__(self, review_dir: Path, data: dict[str, Any]):
        self.review_dir = review_dir.resolve()
        self.data = data
        self.validate()

    @classmethod
    def new(
        cls,
        review_dir: Path,
        root: Path,
        target: dict[str, str] | None = None,
    ) -> "ReviewState":
        target = _validate_session_target(target or {"kind": "uncommitted"})
        data: dict[str, Any] = {
            "schema_version": SCHEMA_VERSION,
            "session": {
                "created_at": now_iso(),
                "review_dir": str(review_dir.resolve()),
                "root": str(root.resolve()),
                "target": target,
            },
            "slices": {},
            "history": [],
            "completed": False,
            "last_error": None,
        }
        return cls(review_dir, data)

    @classmethod
    def load(cls, review_dir: Path) -> "ReviewState":
        state_path = review_dir.resolve() / "_state.json"
        if not state_path.exists():
            raise ReviewStateError(f"missing review state: {state_path}")
        try:
            with state_path.open("r", encoding="utf-8") as fh:
                data = json.load(fh)
        except json.JSONDecodeError as exc:
            raise ReviewStateError(f"invalid review state JSON: {exc}") from exc
        session = data.get("session")
        if isinstance(session, dict):
            target = session.setdefault("target", {"kind": "uncommitted"})
            if isinstance(target, dict) and target.get("kind") == "base":
                target.pop("head", None)
        return cls(review_dir.resolve(), data)

    @classmethod
    def locked(cls, review_dir: Path) -> LockedReviewState:
        return LockedReviewState(review_dir)

    def save(self) -> None:
        self.validate()
        self.review_dir.mkdir(parents=True, exist_ok=True)
        fd, tmp_name = tempfile.mkstemp(
            prefix="_state.",
            suffix=".tmp",
            dir=str(self.review_dir),
            text=True,
        )
        try:
            with os.fdopen(fd, "w", encoding="utf-8") as fh:
                json.dump(self.data, fh, indent=2, sort_keys=True)
                fh.write("\n")
                fh.flush()
                os.fsync(fh.fileno())
            os.replace(tmp_name, self.review_dir / "_state.json")
        finally:
            if os.path.exists(tmp_name):
                os.unlink(tmp_name)

    def validate(self) -> None:
        data = self.data
        if not isinstance(data, dict):
            raise ReviewStateError("state must be a JSON object")
        if data.get("schema_version") != SCHEMA_VERSION:
            raise ReviewStateError(f"unsupported review state schema: {data.get('schema_version')!r}")
        if not isinstance(data.get("session"), dict):
            raise ReviewStateError("state session must be an object")
        session = data["session"]
        if not isinstance(session.get("created_at"), str) or not session["created_at"]:
            raise ReviewStateError("state session must have created_at")
        if not isinstance(session.get("review_dir"), str) or not session["review_dir"]:
            raise ReviewStateError("state session must have review_dir")
        if not isinstance(session.get("root"), str) or not session["root"]:
            raise ReviewStateError("state session must have root")
        try:
            _validate_session_target(session.get("target"))
        except ReviewStateError as exc:
            raise ReviewStateError(f"state session has invalid target: {exc}") from exc
        if not isinstance(data.get("slices"), dict):
            raise ReviewStateError("state slices must be an object")
        if not isinstance(data.get("history"), list):
            raise ReviewStateError("state history must be an array")
        if not isinstance(data.get("completed"), bool):
            raise ReviewStateError("state completed must be a boolean")
        for name, item in data["slices"].items():
            self._validate_slice_name(name)
            if not isinstance(item, dict):
                raise ReviewStateError(f"slice {name!r} must be an object")
            if item.get("name") != name:
                raise ReviewStateError(f"slice {name!r} has mismatched name")
            if item.get("mode") not in {"native", "prompt"}:
                raise ReviewStateError(f"slice {name!r} has invalid mode")
            if item["mode"] == "native":
                self._validate_native_target(name, item.get("target"))
                if item["target"] != _native_target_from_session(session["target"]):
                    raise ReviewStateError(
                        f"native slice {name!r} target must match session target"
                    )
                if item.get("prompt") is not None:
                    raise ReviewStateError(f"native slice {name!r} cannot have prompt text")
            if item["mode"] == "prompt":
                if item.get("target") is not None:
                    raise ReviewStateError(f"prompt slice {name!r} cannot have native target")
                if not isinstance(item.get("prompt"), str) or not item["prompt"].strip():
                    raise ReviewStateError(f"prompt slice {name!r} must have prompt text")
            if not isinstance(item.get("cwd"), str) or not item["cwd"]:
                raise ReviewStateError(f"slice {name!r} must have cwd")
            if not isinstance(item.get("model"), str) or not item["model"]:
                raise ReviewStateError(f"slice {name!r} must have model")
            if not isinstance(item.get("reasoning"), str) or not item["reasoning"]:
                raise ReviewStateError(f"slice {name!r} must have reasoning")
            if not isinstance(item.get("next_pass"), int) or item["next_pass"] < 1:
                raise ReviewStateError(f"slice {name!r} must have a positive next_pass")
            if not isinstance(item.get("complete"), bool):
                raise ReviewStateError(f"slice {name!r} must have complete boolean")
            if not isinstance(item.get("runs"), list):
                raise ReviewStateError(f"slice {name!r} must have runs array")
            if item.get("source", "classifier") not in {"classifier", "user"}:
                raise ReviewStateError(f"slice {name!r} has invalid source")
            if not isinstance(item.get("removed", False), bool):
                raise ReviewStateError(f"slice {name!r} has invalid removed marker")
            if item.get("removal_source") not in {None, "classifier", "user"}:
                raise ReviewStateError(f"slice {name!r} has invalid removal source")
            definition_version = item.get("definition_version", 1)
            if not isinstance(definition_version, int) or definition_version < 1:
                raise ReviewStateError(f"slice {name!r} has invalid definition version")
            for run in item["runs"]:
                self._validate_run(name, run)

    @staticmethod
    def _validate_run(slice_name: str, run: Any) -> None:
        if not isinstance(run, dict):
            raise ReviewStateError(f"slice {slice_name!r} has non-object run entry")
        if not isinstance(run.get("id"), str) or not run["id"]:
            raise ReviewStateError(f"slice {slice_name!r} has run with invalid id")
        if not isinstance(run.get("pass"), int) or run["pass"] < 1:
            raise ReviewStateError(f"slice {slice_name!r} has run with invalid pass")
        if not isinstance(run.get("output_file"), str) or not run["output_file"]:
            raise ReviewStateError(f"slice {slice_name!r} has run with invalid output_file")
        if run.get("status") not in {"running", "findings", "quiet", "uncertain", "failed", "timeout", "ignored"}:
            raise ReviewStateError(f"slice {slice_name!r} has run with invalid status")
        if not isinstance(run.get("started_at"), str) or not run["started_at"]:
            raise ReviewStateError(f"slice {slice_name!r} has run with invalid started_at")
        if run.get("ended_at") is not None and not isinstance(run.get("ended_at"), str):
            raise ReviewStateError(f"slice {slice_name!r} has run with invalid ended_at")
        if run.get("exit_code") is not None and not isinstance(run.get("exit_code"), int):
            raise ReviewStateError(f"slice {slice_name!r} has run with invalid exit_code")
        if run.get("classification") is not None and not isinstance(run.get("classification"), str):
            raise ReviewStateError(f"slice {slice_name!r} has run with invalid classification")
        finding_count = run.get("finding_count")
        if finding_count is not None and (not isinstance(finding_count, int) or finding_count < 0):
            raise ReviewStateError(f"slice {slice_name!r} has run with invalid finding_count")
        ignored_count = run.get("ignored_count")
        if ignored_count is not None and (not isinstance(ignored_count, int) or ignored_count < 0):
            raise ReviewStateError(f"slice {slice_name!r} has run with invalid ignored_count")
        if run.get("runner_pid") is not None and not isinstance(run.get("runner_pid"), int):
            raise ReviewStateError(f"slice {slice_name!r} has run with invalid runner_pid")
        if run.get("runner_key") is not None and not isinstance(run.get("runner_key"), str):
            raise ReviewStateError(f"slice {slice_name!r} has run with invalid runner_key")
        if run.get("error") is not None and not isinstance(run.get("error"), str):
            raise ReviewStateError(f"slice {slice_name!r} has run with invalid error")
        definition_version = run.get("definition_version", 1)
        if not isinstance(definition_version, int) or definition_version < 1:
            raise ReviewStateError(f"slice {slice_name!r} has run with invalid definition version")

    @staticmethod
    def _validate_native_target(slice_name: str, target: Any) -> None:
        if not isinstance(target, dict):
            raise ReviewStateError(f"native slice {slice_name!r} must have target object")
        target_count = sum(
            (
                target.get("uncommitted") is True,
                isinstance(target.get("base"), str) and bool(target["base"]),
                isinstance(target.get("commit"), str) and bool(target["commit"]),
            )
        )
        if target_count != 1:
            raise ReviewStateError(f"native slice {slice_name!r} must have exactly one target")
        allowed = {"uncommitted", "base", "commit"}
        extra = set(target) - allowed
        if extra:
            raise ReviewStateError(f"native slice {slice_name!r} has unsupported target keys")
        if "uncommitted" in target and target.get("uncommitted") is not True:
            raise ReviewStateError(f"native slice {slice_name!r} has invalid uncommitted target")
        for key in ("base", "commit"):
            if key in target and (not isinstance(target[key], str) or not target[key]):
                raise ReviewStateError(f"native slice {slice_name!r} has invalid {key} target")

    @staticmethod
    def _validate_slice_name(name: str) -> None:
        if not isinstance(name, str) or not SLICE_RE.fullmatch(name):
            raise ReviewStateError(
                "slice names must be 1-64 chars of lowercase letters, digits, '.', '_' or '-', "
                "starting with a letter or digit"
            )
        if "/" in name or "\\" in name or name in {".", ".."}:
            raise ReviewStateError("slice names cannot contain path separators or dot names")

    def add_slice(
        self,
        *,
        name: str,
        mode: str,
        target: dict[str, Any] | None,
        prompt: str | None,
        cwd: Path,
        model: str = DEFAULT_MODEL,
        reasoning: str = DEFAULT_REASONING,
        source: str = "classifier",
        user_directive: str | None = None,
    ) -> None:
        self._validate_slice_name(name)
        if source not in {"classifier", "user"}:
            raise ReviewStateError("slice source must be classifier or user")
        if source == "user":
            user_directive = _require_non_empty_text(user_directive or "", "user directive")
        if mode not in {"native", "prompt"}:
            raise ReviewStateError("slice mode must be native or prompt")
        if mode == "native":
            if not target:
                raise ReviewStateError("native slices require --uncommitted, --base, or --commit")
            expected_target = _native_target_from_session(self.data["session"]["target"])
            if target != expected_target:
                raise ReviewStateError(
                    f"native slice target must match session target: {expected_target}"
                )
            if prompt:
                raise ReviewStateError("native target flags cannot be combined with prompt input")
        if mode == "prompt":
            if target:
                raise ReviewStateError("prompt slices cannot be combined with native target flags")
            if not prompt or not prompt.strip():
                raise ReviewStateError("prompt slices require non-empty prompt text")
        definition = {
            "name": name,
            "mode": mode,
            "target": target,
            "prompt": prompt,
            "cwd": str(cwd.resolve()),
            "model": model,
            "reasoning": reasoning,
            "next_pass": 1,
            "complete": False,
            "last_error": None,
            "source": source,
            "user_directive": user_directive,
            "removed": False,
            "definition_version": 1,
        }
        existing = self.data["slices"].get(name)
        if existing is not None:
            if not existing.get("removed"):
                raise ReviewStateError(f"slice already exists: {name}")
            if source == "classifier" and (
                existing.get("source") == "user"
                or existing.get("removal_source") == "user"
            ):
                raise ReviewStateError(f"slice is controlled by an explicit user directive: {name}")
        active_count = sum(
            not item.get("removed")
            for item in self.data["slices"].values()
        )
        if active_count >= MAX_ACTIVE_SLICES:
            raise ReviewStateError(
                f"maximum of {MAX_ACTIVE_SLICES} active slices reached; "
                "remove or consolidate an active slice first"
            )
        if existing is not None:
            definition["runs"] = existing["runs"]
            definition["next_pass"] = existing["next_pass"]
            definition["definition_version"] = existing.get("definition_version", 1) + 1
            self.data["slices"][name] = definition
            self.data["history"].append(
                {
                    "event": "slice_reactivated",
                    "slice": name,
                    "source": source,
                    "at": now_iso(),
                }
            )
        else:
            definition["runs"] = []
            self.data["slices"][name] = definition
            self.data["history"].append(
                {"event": "slice_added", "slice": name, "source": source, "at": now_iso()}
            )
        self.data["completed"] = False

    def remove_slice(
        self,
        name: str,
        *,
        source: str = "classifier",
        user_directive: str | None = None,
    ) -> None:
        self._validate_slice_name(name)
        if source not in {"classifier", "user"}:
            raise ReviewStateError("slice source must be classifier or user")
        if source == "user":
            user_directive = _require_non_empty_text(user_directive or "", "user directive")
        item = self.data["slices"].get(name)
        if item is None:
            raise ReviewStateError(f"slice not found: {name}")
        if item.get("removed"):
            raise ReviewStateError(f"slice already removed: {name}")
        if source == "classifier" and item.get("source") == "user":
            raise ReviewStateError(f"slice is controlled by an explicit user directive: {name}")
        item["removed"] = True
        item["removal_source"] = source
        item["removal_directive"] = user_directive
        item["complete"] = False
        item["last_error"] = None
        self.data["history"].append(
            {
                "event": "slice_removed",
                "slice": name,
                "source": source,
                "user_directive": user_directive,
                "at": now_iso(),
            }
        )
        self._refresh_completed()

    def reserve_eligible(self) -> list[Reservation]:
        reservations: list[Reservation] = []
        self._recover_stale_running_runs()
        if self._has_running_runs():
            self._refresh_completed()
            return reservations
        for name in sorted(self.data["slices"]):
            item = self.data["slices"][name]
            if item.get("removed") or item["complete"]:
                continue
            if any(run.get("status") == "running" for run in item["runs"]):
                continue
            pass_number = item["next_pass"]
            output_file = self._next_output_file(pass_number, name, item["runs"])
            run_id = uuid.uuid4().hex
            run = {
                "id": run_id,
                "pass": pass_number,
                "output_file": str(output_file),
                "status": "running",
                "started_at": now_iso(),
                "ended_at": None,
                "exit_code": None,
                "classification": None,
                "finding_count": None,
                "ignored_count": 0,
                "runner_pid": os.getpid(),
                "runner_key": _process_key(os.getpid()),
                "error": None,
                "definition_version": item.get("definition_version", 1),
            }
            item["runs"].append(run)
            item["last_error"] = None
            self.data["history"].append(
                {"event": "run_reserved", "slice": name, "run_id": run_id, "pass": pass_number, "at": now_iso()}
            )
            reservations.append(
                Reservation(
                    run_id=run_id,
                    slice_name=name,
                    pass_number=pass_number,
                    output_file=output_file,
                    slice_data={
                        **json.loads(json.dumps(item)),
                        "session_target": json.loads(
                            json.dumps(self.data["session"]["target"])
                        ),
                    },
                )
            )
        self._refresh_completed()
        return reservations

    def complete_run(
        self,
        *,
        run_id: str,
        slice_name: str,
        status: str,
        exit_code: int | None,
        classification: str | None,
        finding_count: int | None = None,
        error: str | None = None,
    ) -> bool:
        item = self.data["slices"][slice_name]
        run = next((candidate for candidate in item["runs"] if candidate.get("id") == run_id), None)
        if run is None:
            raise ReviewStateError(f"run not found: {run_id}")
        if run.get("status") != "running":
            self.data["history"].append(
                {
                    "event": "late_run_completion_ignored",
                    "slice": slice_name,
                    "run_id": run_id,
                    "current_status": run.get("status"),
                    "attempted_status": status,
                    "at": now_iso(),
                }
            )
            self._refresh_completed()
            return False
        if item.get("removed"):
            run["status"] = "ignored"
            run["ended_at"] = now_iso()
            run["exit_code"] = exit_code
            run["classification"] = "removed_during_execution"
            run["finding_count"] = 0
            run["error"] = None
            self.data["history"].append(
                {
                    "event": "removed_run_completion_ignored",
                    "slice": slice_name,
                    "run_id": run_id,
                    "at": now_iso(),
                }
            )
            self._refresh_completed()
            return True
        if run.get("definition_version", 1) != item.get("definition_version", 1):
            run["status"] = "ignored"
            run["ended_at"] = now_iso()
            run["exit_code"] = exit_code
            run["classification"] = "superseded_during_execution"
            run["finding_count"] = 0
            run["error"] = None
            item["complete"] = False
            self.data["history"].append(
                {
                    "event": "superseded_run_completion_ignored",
                    "slice": slice_name,
                    "run_id": run_id,
                    "at": now_iso(),
                }
            )
            self._refresh_completed()
            return True
        run["status"] = status
        run["ended_at"] = now_iso()
        run["exit_code"] = exit_code
        run["classification"] = classification
        run["finding_count"] = finding_count
        run["error"] = error

        if status == "findings":
            item["next_pass"] = max(item["next_pass"], int(run["pass"]) + 1)
            item["complete"] = False
            item["last_error"] = None
        elif status in {"quiet", "uncertain"}:
            item["complete"] = True
            item["last_error"] = None
        elif status in {"failed", "timeout"}:
            item["complete"] = False
            item["last_error"] = error or ("review process timed out" if status == "timeout" else "review process failed")
            self.data["last_error"] = {"slice": slice_name, "run_id": run_id, "error": item["last_error"], "at": now_iso()}
        else:
            raise ReviewStateError(f"invalid run status: {status}")

        self.data["history"].append(
            {
                "event": "run_completed",
                "slice": slice_name,
                "run_id": run_id,
                "status": status,
                "classification": classification,
                "at": now_iso(),
            }
        )
        self._refresh_completed()
        return True

    def report_ignored_findings(
        self,
        *,
        ignored_count: int,
        slice_name: str | None = None,
        run_id: str | None = None,
        pass_number: int | None = None,
    ) -> tuple[bool, str]:
        if ignored_count < 0:
            raise ReviewStateError("ignored count must be zero or greater")
        candidates = self._find_ignored_report_candidates(
            slice_name=slice_name,
            run_id=run_id,
            pass_number=pass_number,
        )
        if not candidates:
            raise ReviewStateError("no matching finding run found")
        if len(candidates) > 1:
            names = ", ".join(f"{name}:pass-{run['pass']}" for name, run in candidates)
            raise ReviewStateError(f"multiple matching finding runs found; pass --slice or --run-id: {names}")

        name, run = candidates[0]
        finding_count = run.get("finding_count")
        if not isinstance(finding_count, int) or finding_count < 1:
            raise ReviewStateError("target run does not have a positive finding_count")
        if ignored_count > finding_count:
            raise ReviewStateError(
                f"ignored count {ignored_count} exceeds finding count {finding_count} for slice {name}"
            )
        if ignored_count < finding_count:
            return False, (
                f"unchanged: slice {name} has {finding_count} findings and only {ignored_count} ignored; "
                "follow-up remains required."
            )

        run["status"] = "ignored"
        run["classification"] = "ignored_findings"
        run["ignored_count"] = ignored_count
        run["ignored_at"] = now_iso()
        item = self.data["slices"][name]
        item["complete"] = True
        item["last_error"] = None
        self.data["history"].append(
            {
                "event": "findings_ignored",
                "slice": name,
                "run_id": run["id"],
                "pass": run["pass"],
                "ignored_count": ignored_count,
                "finding_count": finding_count,
                "at": now_iso(),
            }
        )
        self._refresh_completed()
        return True, f"complete: slice {name} pass {run['pass']} had {finding_count} findings and all were ignored."

    def _find_ignored_report_candidates(
        self,
        *,
        slice_name: str | None,
        run_id: str | None,
        pass_number: int | None,
    ) -> list[tuple[str, dict[str, Any]]]:
        if slice_name is not None:
            self._validate_slice_name(slice_name)
            if slice_name not in self.data["slices"]:
                raise ReviewStateError(f"slice not found: {slice_name}")
        candidates: list[tuple[str, dict[str, Any]]] = []
        for name, item in self.data["slices"].items():
            if slice_name is not None and name != slice_name:
                continue
            latest_run = item["runs"][-1] if item["runs"] else None
            for run in item["runs"]:
                if run_id is not None and run.get("id") != run_id:
                    continue
                if pass_number is not None and run.get("pass") != pass_number:
                    continue
                if (
                    run.get("status") == "findings"
                    and run is latest_run
                    and run.get("definition_version", 1)
                    == item.get("definition_version", 1)
                ):
                    candidates.append((name, run))
        candidates.sort(key=lambda pair: str(pair[1].get("started_at", "")), reverse=True)
        return candidates

    def _recover_stale_running_runs(self) -> None:
        for name, item in self.data["slices"].items():
            for run in item["runs"]:
                if run.get("status") != "running":
                    continue
                if _running_reservation_is_active(run):
                    continue
                if item.get("removed"):
                    run["status"] = "ignored"
                    run["ended_at"] = now_iso()
                    run["exit_code"] = None
                    run["classification"] = "removed_stale_recovered"
                    run["finding_count"] = 0
                    run["error"] = None
                    item["last_error"] = None
                    self.data["history"].append(
                        {
                            "event": "removed_stale_run_recovered",
                            "slice": name,
                            "run_id": run["id"],
                            "pass": run.get("pass"),
                            "at": now_iso(),
                        }
                    )
                    continue
                error = "stale running reservation recovered; review run will be retried"
                run["status"] = "failed"
                run["ended_at"] = now_iso()
                run["exit_code"] = None
                run["classification"] = None
                run["error"] = error
                item["complete"] = False
                item["last_error"] = error
                self.data["last_error"] = {"slice": name, "run_id": run["id"], "error": error, "at": now_iso()}
                append_error(
                    self.review_dir,
                    f"stale running review recovered for {name}",
                    f"Slice: {name}\nOutput: {run.get('output_file')}\nError: {error}",
                )
                self.data["history"].append(
                    {
                        "event": "stale_run_recovered",
                        "slice": name,
                        "run_id": run["id"],
                        "pass": run.get("pass"),
                        "at": now_iso(),
                    }
                )

    def _has_running_runs(self) -> bool:
        return any(
            run.get("status") == "running"
            for item in self.data["slices"].values()
            if not item.get("removed")
            for run in item["runs"]
        )

    def _refresh_completed(self) -> None:
        slices = self.data["slices"].values()
        self.data["completed"] = bool(self.data["slices"]) and all(
            item.get("removed")
            or (item["complete"] and not any(run.get("status") == "running" for run in item["runs"]))
            for item in slices
        )
        if self.data["completed"] and all(item.get("last_error") is None for item in self.data["slices"].values()):
            self.data["last_error"] = None

    def _next_output_file(self, pass_number: int, name: str, runs: Iterable[dict[str, Any]]) -> Path:
        used = {str(run.get("output_file")) for run in runs}
        attempt = sum(1 for run in runs if run.get("pass") == pass_number) + 1
        timestamp = filename_timestamp()
        while True:
            retry_suffix = "" if attempt == 1 else f"-retry{attempt}"
            candidate = self.review_dir / f"{timestamp}-{pass_number}-{name}{retry_suffix}.md"
            if str(candidate) not in used and not candidate.exists():
                return candidate
            attempt += 1


def build_review_command(slice_data: dict[str, Any], output_file: Path) -> tuple[list[str], str | None]:
    task_prompt = build_task_context_prompt(output_file.parent)
    cmd = [
        "codex",
        "exec",
        "review",
        "--ephemeral",
        "-m",
        slice_data["model"],
        "-c",
        f'model_reasoning_effort="{slice_data["reasoning"]}"',
    ]
    session_target = slice_data.get("session_target")
    target = (
        _native_target_from_session(session_target)
        if session_target is not None
        else slice_data.get("target")
    )
    if target is not None:
        if target.get("uncommitted"):
            cmd.append("--uncommitted")
        elif "base" in target:
            cmd.extend(["--base", target["base"]])
        elif "commit" in target:
            cmd.extend(["--commit", target["commit"]])
        else:
            raise ReviewStateError("slice target is invalid")

    if slice_data["mode"] == "native":
        cmd.extend(["-o", str(output_file), task_prompt])
        return cmd, None

    prompt = f"{task_prompt}\nSlice instructions:\n{slice_data['prompt']}"
    cmd.extend(["-o", str(output_file), prompt])
    return cmd, None


def _pid_is_alive(pid: int) -> bool:
    if pid <= 0:
        return False
    try:
        os.kill(pid, 0)
    except ProcessLookupError:
        return False
    except PermissionError:
        return True
    return True


def _process_key(pid: int) -> str | None:
    stat_path = Path("/proc") / str(pid) / "stat"
    try:
        stat = stat_path.read_text(encoding="utf-8")
    except OSError:
        try:
            proc = subprocess.run(
                ["ps", "-o", "lstart=", "-p", str(pid)],
                text=True,
                stdout=subprocess.PIPE,
                stderr=subprocess.PIPE,
                check=False,
            )
        except OSError:
            return None
        if proc.returncode == 0 and proc.stdout.strip():
            return f"{pid}:{proc.stdout.strip()}"
        return None
    fields = stat.rsplit(") ", 1)
    if len(fields) != 2:
        return None
    parts = fields[1].split()
    if len(parts) < 20:
        return None
    return f"{pid}:{parts[19]}"


def _running_reservation_is_active(run: dict[str, Any]) -> bool:
    runner_pid = run.get("runner_pid")
    if not isinstance(runner_pid, int) or not _pid_is_alive(runner_pid):
        return False

    runner_key = run.get("runner_key")
    if isinstance(runner_key, str) and runner_key:
        current_key = _process_key(runner_pid)
        return current_key is not None and runner_key == current_key

    started_at = run.get("started_at")
    return isinstance(started_at, str) and parse_iso(started_at) is not None


Runner = Callable[[list[str], Path, str | None, Path, dict[str, Any]], subprocess.CompletedProcess[str]]


def default_runner(
    cmd: list[str],
    cwd: Path,
    input_text: str | None,
    output_file: Path,
    slice_data: dict[str, Any],
) -> subprocess.CompletedProcess[str]:
    del output_file
    timeout = slice_data.get("_child_timeout_seconds") or None
    stdout_log = Path(slice_data["_stdout_log"])
    stderr_log = Path(slice_data["_stderr_log"])
    stdout_log.parent.mkdir(parents=True, exist_ok=True)
    stderr_log.parent.mkdir(parents=True, exist_ok=True)
    with stdout_log.open("w", encoding="utf-8") as out_fh, stderr_log.open("w", encoding="utf-8") as err_fh:
        return subprocess.run(
            cmd,
            cwd=cwd,
            input=input_text,
            text=True,
            stdout=out_fh,
            stderr=err_fh,
            timeout=timeout,
            check=False,
        )


def _log_paths(review_dir: Path, reservation: Reservation) -> tuple[Path, Path]:
    log_dir = review_dir / "_logs"
    safe_slice = re.sub(r"[^a-zA-Z0-9._-]+", "-", reservation.slice_name)
    prefix = f"{reservation.run_id}-{reservation.pass_number}-{safe_slice}"
    return log_dir / f"{prefix}.stdout.log", log_dir / f"{prefix}.stderr.log"


def _write_completed_process_logs(proc: subprocess.CompletedProcess[str], stdout_log: Path, stderr_log: Path) -> None:
    stdout_log.parent.mkdir(parents=True, exist_ok=True)
    if proc.stdout:
        stdout_log.write_text(str(proc.stdout), encoding="utf-8")
    else:
        stdout_log.touch(exist_ok=True)
    if proc.stderr:
        stderr_log.write_text(str(proc.stderr), encoding="utf-8")
    else:
        stderr_log.touch(exist_ok=True)


def run_reserved_review(
    reservation: Reservation,
    command_runner: Runner,
    child_timeout_seconds: float | None = None,
) -> ReviewExecution:
    stdout_log, stderr_log = _log_paths(reservation.output_file.parent, reservation)
    slice_data = json.loads(json.dumps(reservation.slice_data))
    slice_data["_stdout_log"] = str(stdout_log)
    slice_data["_stderr_log"] = str(stderr_log)
    slice_data["_child_timeout_seconds"] = child_timeout_seconds
    enriched = Reservation(
        run_id=reservation.run_id,
        slice_name=reservation.slice_name,
        pass_number=reservation.pass_number,
        output_file=reservation.output_file,
        slice_data=slice_data,
    )
    cmd, input_text = build_review_command(slice_data, enriched.output_file)
    try:
        proc = command_runner(
            cmd,
            Path(slice_data["cwd"]),
            input_text,
            enriched.output_file,
            slice_data,
        )
        _write_completed_process_logs(proc, stdout_log, stderr_log)
    except subprocess.TimeoutExpired as exc:
        timeout_msg = f"review command timed out after {exc.timeout} seconds"
        proc = subprocess.CompletedProcess(cmd, 124, exc.stdout or "", exc.stderr or "")
        _write_completed_process_logs(proc, stdout_log, stderr_log)
        with stderr_log.open("a", encoding="utf-8") as fh:
            if stderr_log.stat().st_size:
                fh.write("\n")
            fh.write(f"[runner] {timeout_msg}\n")
        return ReviewExecution(reservation=enriched, proc=proc, stdout_log=stdout_log, stderr_log=stderr_log, timed_out=True)
    except OSError as exc:
        proc = subprocess.CompletedProcess(cmd, 1, "", str(exc))
        _write_completed_process_logs(proc, stdout_log, stderr_log)
        return ReviewExecution(reservation=enriched, proc=proc, stdout_log=stdout_log, stderr_log=stderr_log, launch_error=exc)
    return ReviewExecution(reservation=enriched, proc=proc, stdout_log=stdout_log, stderr_log=stderr_log)


def evaluate_completed_process(
    review_dir: Path,
    reservation: Reservation,
    proc: subprocess.CompletedProcess[str],
    *,
    stdout_log: Path,
    stderr_log: Path,
    timed_out: bool = False,
) -> tuple[str, str | None, int | None, str | None]:
    output_file = reservation.output_file
    if timed_out:
        error = (
            f"Slice: {reservation.slice_name}\n"
            f"Output: {output_file}\n"
            f"Exit code: {proc.returncode}\n"
            f"stdout log: {stdout_log}\n"
            f"stderr log: {stderr_log}\n"
            "Error: review command timed out"
        )
        append_error(review_dir, f"timed out review for {reservation.slice_name}", error)
        return "timeout", None, None, "review command timed out"
    if proc.returncode != 0:
        error = (
            f"Slice: {reservation.slice_name}\n"
            f"Output: {output_file}\n"
            f"Exit code: {proc.returncode}\n"
            f"stdout log: {stdout_log}\n"
            f"stderr log: {stderr_log}"
        )
        append_error(review_dir, f"failed review for {reservation.slice_name}", error)
        return "failed", None, None, f"review command exited with {proc.returncode}"

    try:
        text = output_file.read_text(encoding="utf-8")
    except OSError as exc:
        error = f"Slice: {reservation.slice_name}\nOutput: {output_file}\nError: {exc}"
        append_error(review_dir, f"unreadable review output for {reservation.slice_name}", error)
        return "failed", None, None, f"review output is unreadable: {exc}"

    if not text.strip():
        error = f"Slice: {reservation.slice_name}\nOutput: {output_file}\nError: empty review output"
        append_error(review_dir, f"empty review output for {reservation.slice_name}", error)
        return "failed", None, None, "review output is empty"

    classification = classify_output(text)
    finding_count = count_findings(text) if classification == "findings" else 0
    if classification == "uncertain":
        append_error(
            review_dir,
            f"uncertain successful review output for {reservation.slice_name}",
            f"Slice: {reservation.slice_name}\nOutput: {output_file}\nAction: marked complete, but classifier was uncertain.",
        )
    return classification, classification, finding_count, None


def _relative_path(path: Path, *, base: Path | None = None) -> str:
    resolved = path.resolve()
    base = Path.cwd().resolve() if base is None else base.resolve()
    try:
        return resolved.relative_to(base).as_posix()
    except ValueError:
        return resolved.as_posix()


def _remaining_count(state: ReviewState) -> int:
    return sum(
        1
        for item in state.data["slices"].values()
        if not item.get("complete") and not item.get("removed")
    )


def _summary(
    review_dir: Path,
    *,
    status: str,
    ok: bool,
    ran: int,
    remaining: int,
    out_records: list[dict[str, Any]],
    err_records: list[dict[str, Any]] | None,
) -> dict[str, Any]:
    ordered_errors = (
        sorted(err_records, key=lambda rec: (rec.get("p", 0), rec.get("s", ""), rec.get("f", "")))
        if err_records
        else None
    )
    return {
        "dir": _relative_path(review_dir),
        "err": ordered_errors,
        "ok": ok,
        "out": sorted(out_records, key=lambda rec: (rec["p"], rec["s"], rec["f"])),
        "ran": ran,
        "rem": remaining,
        "st": status,
        "state": _relative_path(review_dir / "_state.json"),
        "v": 1,
    }


def _error_record_for_run(
    review_dir: Path,
    *,
    slice_name: str,
    pass_number: int,
    output_file: Path,
    run_id: str,
    status: str,
    code: int | None,
    msg: str | None,
) -> dict[str, Any]:
    reservation = Reservation(
        run_id=run_id,
        slice_name=slice_name,
        pass_number=pass_number,
        output_file=output_file,
        slice_data={},
    )
    stdout_log, stderr_log = _log_paths(review_dir, reservation)
    return {
        "code": code,
        "f": _relative_path(output_file),
        "msg": msg or status,
        "p": pass_number,
        "s": slice_name,
        "st": "timeout" if status == "timeout" else "failed",
        "stderr": _relative_path(stderr_log),
        "stdout": _relative_path(stdout_log),
    }


def compact_summary_json(summary: dict[str, Any], *, pretty: bool = False) -> str:
    if pretty:
        return json.dumps(summary, indent=2, sort_keys=True)
    return json.dumps(summary, separators=(",", ":"), sort_keys=True)


def write_summary_json(path: Path, summary: dict[str, Any], *, pretty: bool = False) -> None:
    text = compact_summary_json(summary, pretty=pretty) + "\n"
    _atomic_write_text(path, text)


def _emit_summary(
    summary: dict[str, Any],
    *,
    review_dir: Path,
    summary_json: Path | None,
    no_stdout: bool,
    stdout_json: bool,
    stdout: Any,
    pretty_json: bool,
) -> None:
    default_summary_json = review_dir / "_last-run.json"
    write_summary_json(default_summary_json, summary, pretty=pretty_json)
    if summary_json is not None:
        requested_summary_json = summary_json.resolve()
        if requested_summary_json != default_summary_json.resolve():
            write_summary_json(requested_summary_json, summary, pretty=pretty_json)
    if stdout_json and not no_stdout:
        stdout.write(compact_summary_json(summary, pretty=pretty_json) + "\n")
        stdout.flush()


def run_reviews(
    review_dir: Path,
    *,
    command_runner: Runner = default_runner,
    stdout: Any = sys.stdout,
    stream_progress: bool = False,
    progress_stream: Any | None = None,
    summary_json: Path | None = None,
    no_stdout: bool = False,
    stdout_json: bool = False,
    pretty_json: bool = False,
    child_timeout_seconds: float | None = None,
) -> tuple[int, dict[str, Any]]:
    if no_stdout and summary_json is None:
        raise ReviewStateError("--no-stdout requires --summary-json")
    if stream_progress and no_stdout:
        raise ReviewStateError("--stream-progress is incompatible with --no-stdout")
    if child_timeout_seconds is not None and child_timeout_seconds <= 0:
        child_timeout_seconds = None

    review_dir = review_dir.resolve()
    build_task_context_prompt(review_dir)
    remaining = 0
    any_running = False
    active_run_ids: set[str] = set()
    with ReviewState.locked(review_dir) as state:
        active_count = sum(
            not item.get("removed")
            for item in state.data["slices"].values()
        )
        if active_count > MAX_ACTIVE_SLICES:
            raise ReviewStateError(
                f"{active_count} active slices exceeds maximum of {MAX_ACTIVE_SLICES}; "
                "remove or consolidate slices before running reviews"
            )
        reservations = state.reserve_eligible()
        state.save()
        remaining = _remaining_count(state)
        any_running = state._has_running_runs()
        if any_running and not reservations:
            active_run_ids = {
                str(run["id"])
                for item in state.data["slices"].values()
                for run in item.get("runs", [])
                if run.get("status") == "running"
            }

    if not reservations:
        waited_errors: list[dict[str, Any]] = []
        waited_out: list[dict[str, Any]] = []
        if any_running:
            while True:
                time.sleep(0.25)
                with ReviewState.locked(review_dir) as state:
                    state._recover_stale_running_runs()
                    state._refresh_completed()
                    state.save()
                    remaining = _remaining_count(state)
                    if state._has_running_runs():
                        continue
                    for slice_name, item in state.data["slices"].items():
                        for run in item.get("runs", []):
                            if run.get("id") not in active_run_ids:
                                continue
                            if run.get("status") in {"failed", "timeout"}:
                                waited_errors.append(
                                    _error_record_for_run(
                                        review_dir,
                                        slice_name=slice_name,
                                        pass_number=int(run["pass"]),
                                        output_file=Path(run["output_file"]),
                                        run_id=str(run["id"]),
                                        status=str(run["status"]),
                                        code=run.get("exit_code"),
                                        msg=run.get("error"),
                                    )
                                )
                            elif run.get("status") in {"quiet", "uncertain", "findings", "ignored"}:
                                waited_out.append(
                                    {
                                        "f": _relative_path(Path(run["output_file"])),
                                        "p": int(run["pass"]),
                                        "s": slice_name,
                                        "st": "done",
                                    }
                                )
                    break
        ok = not waited_errors
        status = "failed" if waited_errors else ("partial" if remaining else "no_work")
        summary = _summary(
            review_dir,
            status=status,
            ok=ok,
            ran=0,
            remaining=remaining,
            out_records=waited_out,
            err_records=waited_errors,
        )
        _emit_summary(
            summary,
            review_dir=review_dir,
            summary_json=summary_json,
            no_stdout=no_stdout,
            stdout_json=stdout_json,
            stdout=stdout,
            pretty_json=pretty_json,
        )
        return (0 if ok else 2), summary

    out_records: list[dict[str, Any]] = []
    err_records: list[dict[str, Any]] = []
    progress_stream = sys.stderr if progress_stream is None else progress_stream
    with ThreadPoolExecutor(max_workers=len(reservations)) as executor:
        futures = [
            executor.submit(run_reserved_review, reservation, command_runner, child_timeout_seconds)
            for reservation in reservations
        ]
        for future in as_completed(futures):
            execution = future.result()
            reservation = execution.reservation
            proc = execution.proc
            if execution.launch_error is not None:
                exc = execution.launch_error
                append_error(
                    review_dir,
                    f"failed to launch review for {reservation.slice_name}",
                    f"Slice: {reservation.slice_name}\nOutput: {reservation.output_file}\nError: {exc}",
                )
                status, classification, finding_count, error = (
                    "failed",
                    None,
                    None,
                    f"review command failed to launch: {exc}",
                )
            else:
                status, classification, finding_count, error = evaluate_completed_process(
                    review_dir,
                    reservation,
                    proc,
                    stdout_log=execution.stdout_log,
                    stderr_log=execution.stderr_log,
                    timed_out=execution.timed_out,
                )
            with ReviewState.locked(review_dir) as state:
                completion_applied = state.complete_run(
                    run_id=reservation.run_id,
                    slice_name=reservation.slice_name,
                    status=status,
                    exit_code=proc.returncode,
                    classification=classification,
                    finding_count=finding_count,
                    error=error,
                )
                persisted_run = next(
                    run
                    for run in state.data["slices"][reservation.slice_name]["runs"]
                    if run.get("id") == reservation.run_id
                )
                persisted_status = str(persisted_run.get("status"))
                state.save()
                remaining = _remaining_count(state)
            display_status = persisted_status if completion_applied else "skipped-late-completion"
            if stream_progress:
                print(
                    f"{reservation.slice_name}: pass {reservation.pass_number} {display_status} -> {reservation.output_file}",
                    file=progress_stream,
                    flush=True,
                )
            if persisted_status in {"failed", "timeout"}:
                err_record: dict[str, Any] = {
                    "code": proc.returncode,
                    "f": _relative_path(reservation.output_file),
                    "msg": error or display_status,
                    "p": reservation.pass_number,
                    "s": reservation.slice_name,
                    "st": "timeout" if persisted_status == "timeout" else "failed",
                    "stderr": _relative_path(execution.stderr_log),
                    "stdout": _relative_path(execution.stdout_log),
                }
                err_records.append(err_record)
            elif persisted_status != "ignored":
                out_records.append(
                    {
                        "f": _relative_path(reservation.output_file),
                        "p": reservation.pass_number,
                        "s": reservation.slice_name,
                        "st": "done",
                    }
                )

    ok = not err_records
    with ReviewState.locked(review_dir) as state:
        remaining = _remaining_count(state)
    if err_records:
        top_status = "partial" if out_records else "failed"
    elif remaining:
        top_status = "partial"
    else:
        top_status = "done"
    rc = 0 if ok else 2
    summary = _summary(
        review_dir,
        status=top_status,
        ok=ok,
        ran=len(reservations),
        remaining=remaining,
        out_records=out_records,
        err_records=err_records,
    )
    _emit_summary(
        summary,
        review_dir=review_dir,
        summary_json=summary_json,
        no_stdout=no_stdout,
        stdout_json=stdout_json,
        stdout=stdout,
        pretty_json=pretty_json,
    )
    return rc, summary


def parse_add_slice_args(argv: list[str] | None = None) -> argparse.Namespace:
    parser = argparse.ArgumentParser(description="Register one review slice in an initialized review state.")
    parser.add_argument("--review-dir", required=True, type=Path)
    parser.add_argument("--name", required=True)
    parser.add_argument("--uncommitted", action="store_true")
    parser.add_argument("--base")
    parser.add_argument("--commit")
    parser.add_argument("--prompt-file", type=Path)
    parser.add_argument("--model", default=DEFAULT_MODEL)
    parser.add_argument("--reasoning", default=DEFAULT_REASONING)
    parser.add_argument("--cwd", type=Path)
    parser.add_argument(
        "--user-directive-file",
        type=Path,
        help="Record the explicit user instruction authorizing this slice.",
    )
    return parser.parse_args(argv)


def add_slice_from_args(args: argparse.Namespace, *, stdin: Any = sys.stdin) -> None:
    native_count = sum(bool(value) for value in (args.uncommitted, args.base, args.commit))
    prompt_requested = args.prompt_file is not None
    if native_count > 1:
        raise ReviewStateError("choose only one native target flag: --uncommitted, --base, or --commit")
    if native_count and prompt_requested:
        raise ReviewStateError("native target flags cannot be combined with --prompt-file")

    target: dict[str, Any] | None = None
    prompt: str | None = None
    mode: str
    if native_count:
        mode = "native"
        if args.uncommitted:
            target = {"uncommitted": True}
        elif args.base:
            target = {"base": args.base}
        else:
            target = {"commit": args.commit}
    else:
        mode = "prompt"
        if args.prompt_file is not None:
            if str(args.prompt_file) == "-":
                prompt = stdin.read()
            else:
                prompt = args.prompt_file.read_text(encoding="utf-8")
        else:
            prompt = stdin.read()

    with ReviewState.locked(args.review_dir) as state:
        session_root = Path(state.data["session"]["root"]).resolve()
        cwd = args.cwd.resolve() if args.cwd is not None else session_root
        if not cwd.is_dir():
            raise ReviewStateError(f"slice cwd is not a directory: {cwd}")
        if not _path_is_relative_to(cwd, session_root):
            raise ReviewStateError("slice cwd must remain within the session repository")
        user_directive = (
            args.user_directive_file.read_text(encoding="utf-8")
            if args.user_directive_file is not None
            else None
        )
        state.add_slice(
            name=args.name,
            mode=mode,
            target=target,
            prompt=prompt,
            cwd=cwd,
            model=args.model,
            reasoning=args.reasoning,
            source="user" if user_directive is not None else "classifier",
            user_directive=user_directive,
        )
        state.save()


def parse_report_ignored_args(argv: list[str] | None = None) -> argparse.Namespace:
    parser = argparse.ArgumentParser(
        description="Report how many findings were ignored for a finding run; state rules decide the next step."
    )
    parser.add_argument("--review-dir", required=True, type=Path)
    parser.add_argument("--count", required=True, type=int, help="Number of findings from the run that were ignored.")
    parser.add_argument("--slice", dest="slice_name")
    parser.add_argument("--run-id")
    parser.add_argument("--pass", dest="pass_number", type=int)
    return parser.parse_args(argv)


def report_ignored_from_args(args: argparse.Namespace) -> tuple[bool, str]:
    with ReviewState.locked(args.review_dir) as state:
        changed, message = state.report_ignored_findings(
            ignored_count=args.count,
            slice_name=args.slice_name,
            run_id=args.run_id,
            pass_number=args.pass_number,
        )
        if changed:
            state.save()
        return changed, message
