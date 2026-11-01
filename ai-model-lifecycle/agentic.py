"""agentic.py — agentic runs: the model migrates the project the way a developer
would, with tools, until it delivers.

A single-shot run (runner.py) hands the model the sources as text and takes one
reply; nothing is compiled or tested. Here the model works inside a copy of the
case's project with Claude Code: it edits files, builds, runs the tests, reads
the errors and fixes them, until the case's goal is met (Claude Code's `/goal`)
or the time limit is reached.

Every attempt runs in a throwaway Docker container (docker/agent/Dockerfile:
Java 17 + Maven, Node 20 + Chromium, PostgreSQL 17), so model-run commands never
touch the host; the workspace is the only thing mounted. The container logs in
with CLAUDE_CODE_OAUTH_TOKEN (`claude setup-token`, the claude.ai subscription),
passed by name from the environment so the token never appears on a command line.
No sub-agents (the Agent tool is disallowed) and no MCP servers or user settings.

When the agent stops, the files it delivered (each case's `deliverables`) are
turned into a FILE/DELETE answer and scored by the case's own scorer — the same
acceptance check as single-shot, including hidden tests the agent never sees.
Answer keys and hidden tests are never copied into the workspace.

Records go to runs/<pair>/agentic/<run_id>/ (outside the single-shot runs, so
the scorecard never mixes them in) with a REPORT.md.

Usage:
    python agentic.py --pair sonnet-5.5-cc-vs-deepseek-v4-pro --role current \\
        --case r1b_jhipster_boot3 [--repeats 1] [--time-limit 3600] [--effort medium]
"""

from __future__ import annotations

import argparse
import base64
import fnmatch
import json
import os
import re
import shutil
import subprocess
import sys
import threading
import time
import uuid
from dataclasses import asdict, dataclass, field
from datetime import datetime
from pathlib import Path
from typing import Any, Callable

import common
from cases import sources
from common import case_dir, load_config, load_env, new_run_id

IMAGE = os.environ.get("GATE1_AGENT_IMAGE", "gate1-agent:latest")
TOKEN_ENV = "CLAUDE_CODE_OAUTH_TOKEN"
DEFAULT_TIME_LIMIT_S = 3600
# Build caches shared across attempts (dependencies only; never model output).
M2_VOLUME = "gate1_agent_m2"
NPM_VOLUME = "gate1_agent_npm"

SYSTEM_NOTE = (
    "You are a senior software engineer doing a real migration. The project is in "
    "the current directory (/work). Work the way you would on a real project: read "
    "the code, make the changes, build, run the tests, read the errors and fix them, "
    "until the goal is met. Do not delete, skip or disable tests to make them pass. "
    "There is no human to ask; make reasonable decisions and keep going."
)


# --------------------------------------------------------------------------- #
# Cases                                                                        #
# --------------------------------------------------------------------------- #
@dataclass
class AgenticCase:
    """How one case is set up for an agent and harvested for scoring."""
    goal: str                               # the `/goal` condition
    deliverables: list[str]                 # workspace globs scored (fnmatch, ** ok)
    setup: Callable[[Path], None]           # fills the empty workspace
    task_note: str                          # replaces the prompt's output-format section
    postgres: bool = False                  # start PostgreSQL in the sandbox
    exclude: list[str] = field(default_factory=list)   # globs never harvested


def _copy(src: Path, dest: Path) -> None:
    """Copy a file or tree; on macOS a copy-on-write clone (cheap for node_modules)."""
    dest.parent.mkdir(parents=True, exist_ok=True)
    if sys.platform == "darwin":
        rc = subprocess.run(["cp", "-cR", str(src), str(dest)], capture_output=True).returncode
        if rc == 0:
            return
    if src.is_dir():
        shutil.copytree(src, dest, symlinks=True, dirs_exist_ok=True)
    else:
        shutil.copy2(src, dest)


def _setup_r1(ws: Path) -> None:
    cd = case_dir("r1_springboot2to3")
    for name in ("pom.xml", "src"):
        _copy(cd / name, ws / name)


def _setup_r1b(ws: Path) -> None:
    # The full app at the pinned commit (frontend + Cypress included, so the
    # agent can run the e2e suite), from the cache setup_e2e.sh builds.
    from scorers.base import cache_dir
    frontend = cache_dir() / "r1b_jhipster_boot3" / "frontend"
    if not (frontend / "node_modules" / ".bin" / "cypress").exists():
        raise RuntimeError("r1b needs the e2e cache: run cases/r1b_jhipster_boot3/setup_e2e.sh")
    for entry in frontend.iterdir():
        if entry.name != "target":
            _copy(entry, ws / entry.name)


_R2_BACKEND = """#!/bin/sh
# Start the original GWT app (its REST API at /api) on http://localhost:8888,
# serving the current Angular build (dist/carstore/browser) at /ng/.
# Each start is a fresh copy, so the datastore is re-seeded.
set -e
rm -rf /tmp/war && cp -R /work/backend/carstore-war /tmp/war
[ -d /work/dist/carstore/browser ] && cp -R /work/dist/carstore/browser /tmp/war/ng
export JAVA_HOME=/opt/java8 PATH=/opt/java8/bin:$PATH
exec sh /work/backend/gae-sdk/appengine-java-sdk-1.9.17/bin/dev_appserver.sh --address=0.0.0.0 --port=8888 /tmp/war
"""


def _setup_r2(ws: Path) -> None:
    from scorers.base import cache_dir
    cd = case_dir("r2_gwt_to_angular")
    cache = cache_dir() / "r2_gwt_to_angular"
    if not (cache / "deps" / "node_modules").is_dir() or not (cache / "carstore-war").is_dir():
        raise RuntimeError("r2 needs its cache: run cases/r2_gwt_to_angular/setup.sh")
    for entry in (cd / "workspace").iterdir():
        _copy(entry, ws / entry.name)
    _copy(cd / "gwt", ws / "gwt")
    _copy(cd / "e2e", ws / "e2e")
    _copy(cache / "deps" / "node_modules", ws / "node_modules")
    _copy(cache / "carstore-war", ws / "backend" / "carstore-war")
    _copy(cache / "gae-sdk", ws / "backend" / "gae-sdk")
    (ws / "backend" / "run.sh").write_text(_R2_BACKEND, encoding="utf-8")


def _setup_r3(ws: Path) -> None:
    # The Oracle sources, the seed data and the Oracle results on that data
    # (what a real migration compares against). Never golden_postgres.sql.
    cd = case_dir("r3_oracle_to_postgres")
    _copy(cd / "procedures", ws / "oracle")
    _copy(cd / "seed.sql", ws / "seed.sql")
    for name in ("golden_output.csv", "golden_output_monthly.csv"):
        _copy(cd / name, ws / "expected" / name.replace("golden_", ""))


def _setup_r4(ws: Path) -> None:
    cd = case_dir("r4_schema_load_optimize")
    for name in ("schema.sql", "target_query.sql"):
        _copy(cd / name, ws / name)


def _setup_r5(ws: Path) -> None:
    cd = case_dir("r5_etl_dashboard")
    for name in ("etl_spec.md", "dashboard_schema.sql"):
        _copy(cd / name, ws / name)
    # sample source data: R4's schema and its deterministic seeder
    r4 = case_dir("r4_schema_load_optimize")
    _copy(r4 / "schema.sql", ws / "source" / "schema.sql")
    _copy(r4 / "seed.py", ws / "source" / "seed.py")


_PG_NOTE = ("A PostgreSQL 17 server is running in this sandbox: `psql` connects to "
            "database aidb as user ai (PGHOST/PGUSER/PGPASSWORD/PGDATABASE are set).")

CASES: dict[str, AgenticCase] = {
    "r1_springboot2to3": AgenticCase(
        goal=("pom.xml uses Spring Boot 3.x and Java 17; nothing under src uses the "
              "javax.persistence, javax.validation, javax.annotation or javax.servlet "
              "packages; no spring.factories file is left; and `mvn -B test` passes with "
              "every existing test migrated to JUnit 5 and actually run (none deleted, "
              "skipped or disabled)."),
        deliverables=["pom.xml", "src/**"],
        setup=_setup_r1,
        task_note="Edit the project in place. Maven and Java 17 are installed.",
    ),
    "r1b_jhipster_boot3": AgenticCase(
        goal=("pom.xml uses Spring Boot 3.x and Java 17; no javax.persistence, "
              "javax.validation or javax.servlet imports remain in src/main; "
              "`./mvnw -P-webapp verify` passes with at least 52 unit tests and 140 "
              "integration tests run and none skipped or deleted; and with the app "
              "running (`./mvnw`), `npm run e2e:headless` passes all 54 Cypress tests."),
        deliverables=["pom.xml", "src/main/java/**", "src/main/resources/**"],
        exclude=["src/main/webapp/**"],
        setup=_setup_r1b,
        task_note=("The whole application is checked out here (backend and Angular "
                   "frontend, with node_modules installed). Change the backend only; "
                   "leave the frontend under src/main/webapp unchanged. Java 17, Maven "
                   "(./mvnw), Node and Chromium are installed (CHROME_BIN is set; Cypress "
                   "can use `--browser chromium` or electron)."),
    ),
    "r2_gwt_to_angular": AgenticCase(
        goal=("`npx ng build` succeeds; and served at http://localhost:8888/ng/ by "
              "`sh backend/run.sh`, the Angular app implements the Manufacturers, Ratings and "
              "Reports screens, the header menubar and the success/error messages so that "
              "every scenario in e2e/ (Manufacturers, Ratings and Reports features) works "
              "against the real REST API, with the element ids, table layout, hash routing "
              "and delete confirmation the task's acceptance criteria require."),
        # everything under src/: the scorer restores the fixed files (main.ts,
        # index.html) itself, and an app may keep assets beside src/app (Opus
        # put the original PNGs in src/images, used from styles.css)
        deliverables=["src/**"],
        setup=_setup_r2,
        task_note=("The Angular workspace (the task's `workspace/`) is the current "
                   "directory, with node_modules installed; `gwt/` and `e2e/` are here too. "
                   "Write the app under src/app/: the fixed src/main.ts bootstraps "
                   "AppComponent from src/app/app.component.ts and appConfig from "
                   "src/app/app.config.ts, so both must exist. package.json, angular.json, "
                   "tsconfig*.json, src/main.ts and src/index.html are fixed (changes are "
                   "discarded); you may add global CSS to src/styles.css. `sh backend/run.sh` "
                   "starts the original GWT app with its REST API on http://localhost:8888 "
                   "and serves your latest `npx ng build` at http://localhost:8888/ng/. "
                   "Chromium is installed (CHROME_BIN) for browser checks."),
    ),
    "r3_oracle_to_postgres": AgenticCase(
        goal=("postgres/schema.sql and postgres/procedures.sql exist; applied in that order "
              "to an empty database and loaded with seed.sql, sp_customer_tier() returns "
              "exactly the rows in expected/output.csv and sp_monthly_report('2026-09') "
              "exactly the rows in expected/output_monthly.csv; and neither file uses DUAL, "
              "NVL(, ROWNUM, (+), VARCHAR2 or sysdate."),
        # in the order they are applied
        deliverables=["postgres/schema.sql", "postgres/procedures.sql", "postgres/**"],
        setup=_setup_r3,
        postgres=True,
        task_note=("The Oracle sources are in oracle/. Write the PostgreSQL version as "
                   "postgres/schema.sql and postgres/procedures.sql. seed.sql loads the "
                   "test data, and expected/ holds the result sets the Oracle procedures "
                   "return on that data. " + _PG_NOTE),
    ),
    "r4_schema_load_optimize": AgenticCase(
        goal=("solution.sql, run top to bottom with `psql -v ON_ERROR_STOP=1` on a fresh "
              "empty schema, creates the four tables, loads about 100,000 orders with "
              "their order_items, and creates the index(es); after ANALYZE, EXPLAIN "
              "ANALYZE of target_query.sql uses an index or bitmap index scan on orders, "
              "no sequential scan on orders, and runs in under 1 second."),
        deliverables=["solution.sql"],
        setup=_setup_r4,
        postgres=True,
        task_note="Write the deliverable as solution.sql. " + _PG_NOTE,
    ),
    "r5_etl_dashboard": AgenticCase(
        goal=("etl.sql runs top to bottom with `psql -v ON_ERROR_STOP=1` on source tables "
              "built from source/schema.sql and source/seed.py plus dashboard_schema.sql; "
              "it reconciles exactly as etl_spec.md defines (source order count minus "
              "loaded order count is 0, recorded in etl_run_log); running it twice gives "
              "the same dashboard row counts; both dashboard tables are non-empty; and it "
              "handles the cases etl_spec.md §5 describes (multi-category orders and "
              "completed orders without lines)."),
        deliverables=["etl.sql"],
        setup=_setup_r5,
        postgres=True,
        task_note=("Write the deliverable as etl.sql. Sample source data: source/schema.sql "
                   "creates the tables and `python3 source/seed.py --help` shows how to "
                   "generate rows. " + _PG_NOTE),
    ),
}


def task_prompt(case_id: str) -> str:
    """The case's prompt.md with its output-format section replaced by
    workspace instructions (the agent edits files instead of replying)."""
    text = (case_dir(case_id) / "prompt.md").read_text(encoding="utf-8")
    lines, out, skipping = text.splitlines(), [], False
    for line in lines:
        heading = line.startswith("## ")
        if heading:
            low = line.lower()
            skipping = "output" in low or "deliverable" in low
            if skipping:
                out += ["## Workspace", "", CASES[case_id].task_note, ""]
                continue
        if not skipping:
            out.append(line)
    if not any(line == "## Workspace" for line in out):
        out += ["", "## Workspace", "", CASES[case_id].task_note]
    return "\n".join(out).strip() + "\n"


# --------------------------------------------------------------------------- #
# Harvest: the delivered files as an answer the case's scorer reads            #
# --------------------------------------------------------------------------- #
def _match(rel: str, patterns: list[str]) -> bool:
    return any(fnmatch.fnmatch(rel, p) or (p.endswith("/**") and rel.startswith(p[:-2]))
               for p in patterns)


def snapshot(ws: Path, spec: AgenticCase) -> dict[str, bytes]:
    """{relative path: content} of every deliverable file in the workspace."""
    out = {}
    for f in ws.rglob("*"):
        if f.is_file() and not f.is_symlink():
            rel = f.relative_to(ws).as_posix()
            if _match(rel, spec.deliverables) and not _match(rel, spec.exclude):
                out[rel] = f.read_bytes()
    return out


def answer_from(before: dict[str, bytes], after: dict[str, bytes],
                order: list[str] | None = None) -> str:
    """FILE blocks for every new or changed deliverable, DELETE for removed ones.

    Files come in `order` (a case's deliverable patterns, first match wins),
    then by path: SQL scorers run the files in answer order, so r3's schema
    must come before the procedures that use its row types (alphabetical order
    put procedures.sql first and failed two correct answers, 2026-10-31)."""
    def rank(rel: str) -> tuple[int, str]:
        hits = [i for i, p in enumerate(order or []) if _match(rel, [p])]
        return (hits[0] if hits else len(order or []), rel)

    parts = []
    for rel in sorted(set(before) - set(after)):
        parts.append(f"### DELETE: {rel}\n")
    for rel in sorted(after, key=rank):
        if before.get(rel) == after[rel]:
            continue
        try:
            body = after[rel].decode("utf-8")
        except UnicodeDecodeError:
            # images and other binaries travel base64-encoded (scorers.base
            # parse_binaries); dropping them failed a correct r2 build whose
            # CSS used the original app's PNGs (2026-10-31)
            data = base64.encodebytes(after[rel]).decode("ascii").rstrip("\n")
            parts.append(f"### BINARY: {rel}\n```base64\n{data}\n```\n")
            continue
        # scorers.base.parse_files ends a block at any fence line, so a
        # deliverable that itself contains one (rare: code, SQL and config
        # files don't) would arrive cut short
        parts.append(f"### FILE: {rel}\n```\n{body.rstrip(chr(10))}\n```\n")
    return "\n".join(parts)


# --------------------------------------------------------------------------- #
# One attempt                                                                  #
# --------------------------------------------------------------------------- #
@dataclass
class AgenticResult:
    pair_id: str
    case_id: str
    model_slug: str
    model_name: str
    role: str
    rep: int
    run_id: str
    mode: str = "agentic"
    effort_override: str | None = None
    reasoning_requested: dict[str, Any] | None = None
    time_limit_s: int = DEFAULT_TIME_LIMIT_S
    goal: str = ""
    provider: str = "claude-code"
    ok: bool = False                    # the agent ran and finished (not an infra error)
    error: str | None = None
    timed_out: bool = False
    latency_s: float = 0.0              # wall time of the agent session
    num_turns: int | None = None
    tool_calls: int = 0
    duration_api_ms: int | None = None  # model time: the session's time in API requests
    tool_time_s: float | None = None    # tools running (builds, tests), overlaps merged
    thinking_time_s: float | None = None  # the model's reported thinking time
    input_tokens: int = 0
    output_tokens: int = 0
    cache_read_tokens: int = 0
    cache_write_tokens: int = 0
    cost_estimate_usd: float | None = None
    final_message: str = ""
    files_changed: int = 0
    output_text: str = ""               # the harvested answer the scorer reads
    passed: bool | None = None
    reason: str = ""
    checks: dict[str, Any] = field(default_factory=dict)
    created_at: float = 0.0


def agentic_dir(pair_id: str, run_id: str) -> Path:
    return Path(common.RUNS_DIR) / pair_id / "agentic" / run_id


def record_path(pair_id: str, run_id: str, slug: str, case_id: str, rep: int) -> Path:
    suffix = f".r{rep}" if rep else ""
    return agentic_dir(pair_id, run_id) / f"{slug.replace('/', '__')}.{case_id}.{run_id}{suffix}.json"


def write_control(control: Path, goal: str, system: str) -> None:
    """The goal and task go to files the sandbox reads, never onto a command
    line: there they show in `ps`, and an agent that stops its own servers by
    pattern (`kill` every process mentioning "java") killed its own session
    on r2 (2026-10-31)."""
    control.mkdir(parents=True, exist_ok=True)
    (control / "prompt.txt").write_text(f"/goal {goal}", encoding="utf-8")
    (control / "system.md").write_text(system, encoding="utf-8")


def docker_command(name: str, ws: Path, control: Path, model: str,
                   effort: str | None, postgres: bool) -> list[str]:
    cmd = ["docker", "run", "--rm", "--name", name,
           "-v", f"{ws}:/work", "-v", f"{control}:/gate1:ro",
           "-v", f"{M2_VOLUME}:/home/agent/.m2", "-v", f"{NPM_VOLUME}:/home/agent/.npm",
           "-e", TOKEN_ENV,                    # by name: the value comes from our env
           "-e", f"GATE1_POSTGRES={1 if postgres else 0}",
           "--shm-size", "1g", IMAGE,
           # the prompt (`/goal ...`) arrives on stdin, the task in a file
           "sh", "-c", 'exec claude -p "$@" < /gate1/prompt.txt', "claude",
           "--model", model,
           "--append-system-prompt-file", "/gate1/system.md",
           "--dangerously-skip-permissions",
           "--disallowedTools", "Agent",
           "--setting-sources", "", "--strict-mcp-config",
           "--output-format", "stream-json", "--verbose",
           "--no-session-persistence"]
    if effort:
        cmd += ["--effort", effort]
    return cmd


def _container_env() -> dict[str, str]:
    """Only what docker needs plus the subscription token: never an API key
    (that would bill the API instead of the subscription)."""
    keep = ("PATH", "HOME", "DOCKER_HOST", "DOCKER_CONFIG", "DOCKER_CONTEXT", TOKEN_ENV)
    return {k: v for k, v in os.environ.items() if k in keep}


def _ts(value: Any) -> float | None:
    try:
        return datetime.fromisoformat(str(value).replace("Z", "+00:00")).timestamp()
    except ValueError:
        return None


def stream_timing(lines: list[str]) -> tuple[float | None, float | None]:
    """(tool time, thinking time) in seconds from a Claude Code session stream.

    Tool time runs from each tool_use message to its tool_result, by the
    events' own timestamps, with overlapping (parallel) calls merged so no
    second counts twice. Thinking time sums the model's reported
    thinking_duration_ms. None when the stream carries no such data: a
    missing measurement is never zero (docs/METRICS_PLAN.md)."""
    started: dict[str, float] = {}
    spans: list[tuple[float, float]] = []
    thinking_ms, saw_thinking = 0.0, False
    for line in lines:
        try:
            ev = json.loads(line)
        except json.JSONDecodeError:
            continue
        if not isinstance(ev, dict):
            continue
        if isinstance(ev.get("thinking_duration_ms"), (int, float)):
            thinking_ms += float(ev["thinking_duration_ms"])
            saw_thinking = True
        at = _ts(ev.get("timestamp"))
        for block in (ev.get("message") or {}).get("content") or []:
            if not isinstance(block, dict) or at is None:
                continue
            if block.get("type") == "tool_use" and block.get("id"):
                started[block["id"]] = at
            elif block.get("type") == "tool_result" and block.get("tool_use_id") in started:
                spans.append((started.pop(block["tool_use_id"]), at))
    tool = None
    if spans:
        tool, end = 0.0, float("-inf")
        for a, b in sorted(spans):
            if b > end:
                tool += b - max(a, end)
                end = b
    return (round(tool, 2) if tool is not None else None,
            round(thinking_ms / 1000, 2) if saw_thinking else None)


def _summarize_stream(lines: list[str], res: AgenticResult) -> None:
    """Fold the stream into the result.

    A session that uses background tools (Monitor, ScheduleWakeup) emits one
    `result` event per wake-up segment. In each, num_turns and usage cover that
    segment only, while total_cost_usd and duration_api_ms are running totals.
    So turns and tokens are summed and cost/API time come from the last event.
    """
    res.tool_time_s, res.thinking_time_s = stream_timing(lines)
    turns = None
    last_error = None
    tokens = {"input_tokens": 0, "output_tokens": 0,
              "cache_read_input_tokens": 0, "cache_creation_input_tokens": 0}
    for line in lines:
        try:
            ev = json.loads(line)
        except json.JSONDecodeError:
            continue
        if ev.get("type") == "assistant":
            for block in (ev.get("message") or {}).get("content") or []:
                if isinstance(block, dict) and block.get("type") == "tool_use":
                    res.tool_calls += 1
        elif ev.get("type") == "result":
            usage = ev.get("usage") or {}
            if ev.get("num_turns") is not None:
                turns = (turns or 0) + int(ev["num_turns"])
            for k in tokens:
                tokens[k] += int(usage.get(k) or 0)
            res.duration_api_ms = ev.get("duration_api_ms")
            res.cost_estimate_usd = ev.get("total_cost_usd")
            message = str(ev.get("result") or "")[:4000]
            if message:
                res.final_message = message
            last_error = (f"claude error: {message[:300] or ev.get('subtype')}"
                          if ev.get("is_error") else None)
    if last_error:
        res.error = last_error
    res.num_turns = turns
    res.input_tokens = tokens["input_tokens"]
    res.output_tokens = tokens["output_tokens"]
    res.cache_read_tokens = tokens["cache_read_input_tokens"]
    res.cache_write_tokens = tokens["cache_creation_input_tokens"]


def run_attempt(cfg, pair_id: str, role: str, model, case_id: str, rep: int, run_id: str,
                *, time_limit_s: int = DEFAULT_TIME_LIMIT_S, effort: str | None = None,
                workroot: Path | None = None, score: bool = True,
                scorer: Callable | None = None) -> AgenticResult:
    spec = CASES[case_id]
    sources.ensure(case_id)
    res = AgenticResult(pair_id=pair_id, case_id=case_id, model_slug=model.id,
                        model_name=model.name, role=role, rep=rep, run_id=run_id,
                        effort_override=effort,
                        reasoning_requested={"effort": effort} if effort else None,
                        time_limit_s=time_limit_s, goal=spec.goal, created_at=time.time())
    out = record_path(pair_id, run_id, model.id, case_id, rep)
    out.parent.mkdir(parents=True, exist_ok=True)
    root = workroot or Path(common.RUNS_DIR).parent / ".agentic-work"
    ws = root / f"{case_id}-{run_id}-{model.id.replace('/', '__')}-r{rep}"
    shutil.rmtree(ws, ignore_errors=True)
    ws.mkdir(parents=True)
    try:
        spec.setup(ws)
        before = snapshot(ws, spec)
        name = f"gate1-agent-{uuid.uuid4().hex[:10]}"
        control = ws.with_name(ws.name + ".control")
        write_control(control, spec.goal,
                      SYSTEM_NOTE + "\n\n# The task\n\n" + task_prompt(case_id))
        cmd = docker_command(name, ws, control, model.id, effort, spec.postgres)
        lines: list[str] = []
        stream_log = out.with_suffix(".stream.jsonl")
        t0 = time.monotonic()
        with open(stream_log, "w", encoding="utf-8") as log:
            proc = subprocess.Popen(cmd, stdout=subprocess.PIPE, stderr=subprocess.STDOUT,
                                    stdin=subprocess.DEVNULL, text=True, env=_container_env())

            def pump() -> None:
                for line in proc.stdout:            # type: ignore[union-attr]
                    log.write(line)
                    lines.append(line)

            reader = threading.Thread(target=pump, daemon=True)
            reader.start()
            try:
                proc.wait(timeout=time_limit_s)
            except subprocess.TimeoutExpired:
                res.timed_out = True
                subprocess.run(["docker", "kill", name], capture_output=True)
                proc.wait(timeout=60)
            reader.join(timeout=30)
        res.latency_s = round(time.monotonic() - t0, 2)
        _summarize_stream(lines, res)
        if proc.returncode not in (0, None) and not res.timed_out and res.num_turns is None:
            tail = "".join(lines[-5:]).strip()
            res.error = res.error or f"agent did not run (exit {proc.returncode}): {tail[-400:]}"
        after = snapshot(ws, spec)
        res.output_text = answer_from(before, after, spec.deliverables)
        res.files_changed = sum(res.output_text.count(h)
                                for h in ("### FILE:", "### DELETE:", "### BINARY:"))
        # A session that ran to its end or to the time limit delivered whatever
        # it left behind. One that never started, or that Claude Code ended
        # with an error (login, usage limit, API), says nothing about the
        # model: an infra error, never scored.
        res.ok = res.error is None
        if score and res.ok:
            from scorers.dispatch import score_case
            scored = (scorer or score_case)(case_id, res.output_text, model.id)
            res.passed, res.reason, res.checks = bool(scored.passed), scored.reason, dict(scored.checks)
    except Exception as exc:                        # noqa: BLE001 — recorded, never crashes a batch
        res.error = res.error or f"{type(exc).__name__}: {exc}"
        res.ok = False
    finally:
        out.write_text(json.dumps(asdict(res), indent=2), encoding="utf-8")
        shutil.rmtree(ws, ignore_errors=True)
        shutil.rmtree(ws.with_name(ws.name + ".control"), ignore_errors=True)
    return res


# --------------------------------------------------------------------------- #
# Report                                                                       #
# --------------------------------------------------------------------------- #
def load_records(pair_id: str, run_id: str) -> list[dict]:
    return [json.loads(f.read_text()) for f in sorted(agentic_dir(pair_id, run_id).glob("*.json"))]


def render_report(pair_id: str, run_id: str, recs: list[dict]) -> str:
    lines = [f"# Agentic runs — {pair_id} · run {run_id}", "",
             "The model works on a copy of the project inside a sandbox with Claude Code "
             "(edit, build, test, fix) until its `/goal` is met or the time limit is hit; "
             "what it delivered is then scored by the case's acceptance check, including "
             "hidden tests it never saw. Infra errors (the session never ran) are left out.",
             "", "## Summary", "",
             "| Case | Model | Effort | Passed | Mean time (min) | Mean cost (USD) | Mean turns |",
             "|---|---|---|---:|---:|---:|---:|"]
    groups: dict[tuple, list[dict]] = {}
    for r in recs:
        groups.setdefault((r["case_id"], r["model_name"], r.get("effort_override") or "default"),
                          []).append(r)
    for (case, name, effort), rs in sorted(groups.items()):
        ran = [r for r in rs if r.get("ok")]
        passed = sum(1 for r in ran if r.get("passed"))
        infra = len(rs) - len(ran)
        mean = lambda key: (sum(float(r.get(key) or 0) for r in ran) / len(ran)) if ran else None  # noqa: E731
        t, c, n = mean("latency_s"), mean("cost_estimate_usd"), mean("num_turns")
        lines.append(f"| {case} | {name} | {effort} | {passed}/{len(ran)}"
                     f"{f' (+{infra} infra)' if infra else ''} | "
                     f"{'n/a' if t is None else f'{t / 60:.1f}'} | "
                     f"{'n/a' if c is None else f'${c:.2f}'} | {'n/a' if n is None else f'{n:.0f}'} |")
    lines += ["", "## Per attempt", "",
              "| Case | Rep | Model | Result | Time (min) | Cost (USD) | Turns | Tool calls | Files | Reason |",
              "|---|---:|---|---|---:|---:|---:|---:|---:|---|"]
    for r in recs:
        result = ("infra error" if not r.get("ok") else "✅" if r.get("passed") else "❌")
        if r.get("timed_out"):
            result += " (time limit)"
        reason = (r.get("error") if not r.get("ok") else r.get("reason") or "").replace("|", "\\|")
        cost = r.get("cost_estimate_usd")
        lines.append(f"| {r['case_id']} | {r['rep'] + 1} | {r['model_name']} | {result} | "
                     f"{float(r.get('latency_s') or 0) / 60:.1f} | "
                     f"{'n/a' if cost is None else f'${cost:.2f}'} | {r.get('num_turns') or 'n/a'} | "
                     f"{r.get('tool_calls', 0)} | {r.get('files_changed', 0)} | {reason[:160]} |")
    return "\n".join(lines) + "\n"


# --------------------------------------------------------------------------- #
# CLI                                                                          #
# --------------------------------------------------------------------------- #
_LIMIT_RE = re.compile(r"usage limit|rate limit|hit your (?:[\w-]+ )?limit|Not logged in|"
                       r"credit balance", re.I)


class NotReady(RuntimeError):
    pass


def preflight() -> None:
    if not os.environ.get(TOKEN_ENV):
        raise NotReady(f"{TOKEN_ENV} is not set: run `claude setup-token` and add the token "
                       "to .env (agentic runs log in with it inside the sandbox)")
    if shutil.which("docker") is None:
        raise NotReady("docker not found on PATH")
    if subprocess.run(["docker", "image", "inspect", IMAGE], capture_output=True).returncode:
        raise NotReady(f"sandbox image {IMAGE} not built: docker build -t {IMAGE} docker/agent")


def run(cfg, pair_id: str, *, role: str = "current", case: str | None = None,
        repeats: int = 1, time_limit_s: int = DEFAULT_TIME_LIMIT_S,
        effort: str | None = None) -> tuple[str, list[AgenticResult]]:
    pair = cfg.get_pair(pair_id)
    model = pair.current if role == "current" else pair.target
    api = cfg.api_for(model)
    if api is None or api.family != "claude-code":
        raise ValueError(f"agentic runs use Claude Code: {model.name} is not on the Claude Code route")
    # a comma-separated list, a suite name from models.yaml, or every case
    if case in (None, "all"):
        cases = list(CASES)
    elif case in cfg.suites:
        cases = list(load_config(suite=None if case == "sanity" else case).cases)
    else:
        cases = [c.strip() for c in case.split(",") if c.strip()]
    unknown = [c for c in cases if c not in CASES]
    if unknown:
        raise ValueError(f"no agentic setup for case(s): {', '.join(unknown)}")
    effort = effort or cfg.effort
    run_id = new_run_id()
    results = []
    stop = False
    print(f"agentic run id: {run_id}  model: {model.name}  effort: {effort or 'default'}")
    for case_id in cases:
        for rep in range(repeats):
            if stop:
                break
            r = run_attempt(cfg, pair_id, role, model, case_id, rep, run_id,
                            time_limit_s=time_limit_s, effort=effort)
            results.append(r)
            status = ("INFRA " + (r.error or "")[:120] if not r.ok else
                      ("PASS" if r.passed else f"FAIL ({r.reason[:120]})"))
            print(f"  {case_id} rep {rep + 1}/{repeats}: {r.latency_s / 60:.1f} min, "
                  f"{r.num_turns or 0} turns, ${r.cost_estimate_usd or 0:.2f}"
                  f"{' [time limit]' if r.timed_out else ''}  {status}", flush=True)
            if not r.ok and r.error and _LIMIT_RE.search(r.error):
                # every later attempt would fail the same way
                print(f"stopping: {r.error[:120]}", flush=True)
                stop = True
    report = agentic_dir(pair_id, run_id) / "REPORT.md"
    report.write_text(render_report(pair_id, run_id, load_records(pair_id, run_id)), encoding="utf-8")
    print(f"wrote {report}")
    return run_id, results


def main(argv: list[str] | None = None) -> int:
    ap = argparse.ArgumentParser(description=__doc__.split("\n\n")[0])
    ap.add_argument("--pair", required=True)
    ap.add_argument("--role", choices=("current", "target"), default="current")
    ap.add_argument("--case", help="case id(s), comma-separated, or a suite (sanity, real); "
                                   "default: every case with an agentic setup")
    ap.add_argument("--repeats", type=int, default=1)
    ap.add_argument("--time-limit", type=int, default=DEFAULT_TIME_LIMIT_S,
                    help="seconds per attempt (default 3600)")
    ap.add_argument("--effort", help="Claude Code --effort level (default: models.yaml defaults.effort)")
    args = ap.parse_args(argv)
    load_env()
    cfg = load_config()
    try:
        preflight()
        run(cfg, args.pair, role=args.role, case=args.case, repeats=args.repeats,
            time_limit_s=args.time_limit, effort=args.effort)
    except (NotReady, ValueError, KeyError) as exc:
        print(f"error: {exc}", file=sys.stderr)
        return 2
    return 0


if __name__ == "__main__":
    sys.exit(main())
