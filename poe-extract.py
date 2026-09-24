#!/usr/bin/env python3
"""Extract user-voice signals from Claude Code sessions for building a Poe character stack.


Unlike recall-scan (which scores sessions for reusable prompt recipes), this tool mines
the USER turns across all sessions to codify how Nino thinks, decides, corrects, and
pushes back. The output is a queryable voice corpus — a "Poe" in the Altered Carbon sense.

Storage lives in the same SQLite file as recall-cli (~/.claude/recall.db) under the
voice_signals table + FTS5 index, so Poe and recipes share one corpus.

Usage:
    poe-extract.py extract [--limit N] [--since DAYS]   scan all JSONL -> corpus.jsonl
    poe-extract.py extract --session PATH                scan one JSONL -> DB (hook)
    poe-extract.py publish                               corpus.jsonl -> DB
    poe-extract.py assemble                              DB -> stack.md
    poe-extract.py query TERMS [--limit N]               FTS5 search -> markdown
    poe-extract.py run                                   extract + publish + assemble
    poe-extract.py init                                  ensure DB schema exists
"""

from __future__ import annotations

import argparse
import hashlib
import json
import os
import re
import sqlite3
import subprocess
import sys
from collections import Counter, defaultdict
from datetime import datetime, timedelta, timezone
from pathlib import Path

PROJECTS_DIR = Path.home() / ".claude" / "projects"
CODEX_SESSIONS_DIR = Path.home() / ".codex" / "sessions"
CODEX_ARCHIVED_SESSIONS_DIR = Path.home() / ".codex" / "archived_sessions"
GEMINI_SESSIONS_DIR = Path.home() / ".gemini" / "tmp"
POE_DIR = Path.home() / ".claude" / "poe"
CORPUS_PATH = POE_DIR / "corpus.jsonl"
STACK_PATH = POE_DIR / "stack.md"
QUEUE_PATH = POE_DIR / "queue"
HOOK_LOG_PATH = POE_DIR / "hook.log"
RECALL_DB = Path.home() / ".claude" / "recall.db"

# Opportunistic-catchup staleness threshold for read paths (query/assemble).
READ_PATH_STALE_SECONDS = 900  # 15 min

# A surfaced "prior" must be SETTLED history, not a fresh message from an
# in-flight concurrent session. The recall DB is machine-global and ingests
# every session continuously, so without a floor a directive typed into one
# live session leaks into another's prompt-hook as a "prior" within minutes.
# Signals newer than this are excluded from the per-prompt surface.
# (2026-05-29 cross-session-leak postmortem.)
PRIOR_RECENCY_FLOOR_HOURS = 24

NOISE_PREFIXES = (
    "[Request interrupted",
    "This session is being continued",
    "Caveat: The messages below",
    "<local-command-caveat>",
    "<command-name>",
    "<command-message>",
    "<bash-input>",
    "<bash-stdout>",
    "<bash-stderr>",
    # Agent-generated prompts (multi-agent sessions). These arrive through the
    # UserPromptSubmit path but are not Nino's voice — ingesting them drifts
    # the tone fingerprint toward machine-written text.
    "<task-notification>",
    "<teammate-message",
    "<agent-message",
    "Another Claude session sent a message",
    # Our OWN hooks' feedback. Claude Code injects a Stop hook's `reason` as a
    # user turn, so anti-hesitation.py's prose was being ingested as Nino
    # correcting the agent — 272 rows, 32% of the correction/rejection corpus
    # as of 2026-08-26, and the single most common "correction" in it. A corpus
    # that feeds the prompt-hook was training the agent on its own voice.
    "Stop hook feedback:",
    "PreToolUse hook feedback:",
    "PostToolUse hook feedback:",
    "UserPromptSubmit hook feedback:",
    "SessionStart hook feedback:",
    # Slash-command / subagent prompt templates that arrive on the user turn.
    "Review a single git commit",
    # Codex wraps a delegated thread's handoff in this envelope and delivers it
    # on the user turn. It carries the parent agent's summary, not Nino's — 10
    # of its 11 rows scored as corrections.
    "<codex_delegation>",
)

# Messages dominated by pasted logs/code/tool output are not user voice.
# Heuristic: high ratio of non-prose characters or very long.
MAX_USER_MSG_LEN = 4000
MIN_USER_MSG_LEN = 2  # lowered from 4 to capture bare "go" / "ok" redirects

# Signal patterns. Each tuple: (signal_type, compiled regex, short label)
def _c(p): return re.compile(p, re.IGNORECASE)

SIGNAL_PATTERNS = [
    # === CORRECTIONS — negative feedback on prior assistant action ===
    ("correction", _c(r"^\s*(no|nope|stop|wait|hold on|don't|do not)\b"), "opening-negative"),
    ("correction", _c(r"\bthat(?:'s| is)\s+(not|wrong|incorrect|bad)\b"), "that-is-wrong"),
    ("correction", _c(r"\byou(?:'re| are)\s+(wrong|incorrect|missing|off)\b"), "you-are-wrong"),
    ("correction", _c(r"\bwhy (did|would) you\b"), "why-did-you"),
    ("correction", _c(r"\b(undo|revert|roll ?back|back out|unwind)\b"), "undo"),
    ("correction", _c(r"\bnot what I (asked|wanted|meant)\b"), "not-what-i-asked"),
    ("correction", _c(r"\b(over[- ]?engineer|over[- ]?complicated|too much|scope creep)\b"), "over-engineered"),

    # === PREFERENCES — explicit rules about how things should be ===
    ("preference", _c(r"\bI (prefer|like|want|hate|dislike|don't (want|like))\b"), "i-prefer"),
    ("preference", _c(r"\bwe (prefer|always|never) (use|write|do|have|go|commit|push|call)\b"), "we-convention"),
    ("preference", _c(r"\bwe (don't|do not) (use|write|do|want|need to|commit|push|call|allow)\b"), "we-dont"),
    ("preference", _c(r"\b(always|never) (use|write|call|do|add|create|commit|push)\b"), "always-never"),
    ("preference", _c(r"\b(make sure|ensure) (you|to|that)\b"), "make-sure"),
    ("preference", _c(r"\bfrom now on\b"), "from-now-on"),
    ("preference", _c(r"\bgoing forward\b"), "going-forward"),

    # === RATIONALE — reasons behind decisions ===
    ("rationale", _c(r"\bbecause\b"), "because"),
    ("rationale", _c(r"\bthe reason (is|we|I)\b"), "the-reason"),
    ("rationale", _c(r"\b(we|I) got burned\b"), "got-burned"),
    ("rationale", _c(r"\blast time\b"), "last-time"),
    ("rationale", _c(r"\botherwise\b"), "otherwise"),
    ("rationale", _c(r"\bthat way\b"), "that-way"),

    # === DECLARATIONS — imperative rules, often first messages ===
    ("declaration", _c(r"^\s*(use|don't|do not|keep|avoid|skip|drop|remove|add)\s+\w"), "imperative-rule"),

    # === APPROVALS — validated choices (short msgs are stronger signal) ===
    ("approval", _c(r"^\s*(perfect|exactly|yes exactly|good call|nice|that's (it|right)|correct)\b"), "short-approval"),
    ("approval", _c(r"\bship it\b"), "ship-it"),
    # redirect-go: short messages that mean "you already have authorization, keep moving".
    # The prior_assistant column captures what Claude was asking — useful for
    # learning which question shapes Nino routinely overrides with "go".
    ("approval", _c(r"^\s*(go|proceed|continue|keep going|do all|all of it|do it|do the rest|move on|next|push|run it|execute)[.!]?\s*$"), "redirect-go"),

    # === REJECTIONS with alternative ===
    ("rejection", _c(r"\binstead\b"), "instead"),
    ("rejection", _c(r"\brather than\b"), "rather-than"),
]


SCHEMA_SQL = """
CREATE TABLE IF NOT EXISTS voice_signals (
    id              INTEGER PRIMARY KEY AUTOINCREMENT,
    session_id      TEXT NOT NULL,
    source_client   TEXT NOT NULL DEFAULT 'claude',
    project         TEXT,
    timestamp       TEXT,
    signal_type     TEXT NOT NULL,
    label           TEXT NOT NULL,
    phrase          TEXT NOT NULL,
    message         TEXT,
    prior_assistant TEXT,
    phrase_hash     TEXT NOT NULL,
    created_at      TEXT NOT NULL DEFAULT (datetime('now')),
    UNIQUE(session_id, signal_type, phrase_hash)
);

CREATE INDEX IF NOT EXISTS voice_signals_signal_idx
    ON voice_signals(signal_type, label);
CREATE INDEX IF NOT EXISTS voice_signals_project_idx
    ON voice_signals(project);
CREATE INDEX IF NOT EXISTS voice_signals_session_idx
    ON voice_signals(session_id);

-- Porter stemmer collapses engineer/engineered/engineering to a common
-- stem so synonym-shaped queries hit. Big recall lift vs default unicode61.
CREATE VIRTUAL TABLE IF NOT EXISTS voice_signals_fts USING fts5(
    phrase, message, signal_type, label, project,
    content=voice_signals, content_rowid=id,
    tokenize='porter unicode61 remove_diacritics 2'
);

CREATE TRIGGER IF NOT EXISTS voice_signals_ai AFTER INSERT ON voice_signals BEGIN
    INSERT INTO voice_signals_fts(rowid, phrase, message, signal_type, label, project)
    VALUES (new.id, new.phrase, new.message, new.signal_type, new.label, new.project);
END;

CREATE TRIGGER IF NOT EXISTS voice_signals_ad AFTER DELETE ON voice_signals BEGIN
    INSERT INTO voice_signals_fts(voice_signals_fts, rowid, phrase, message, signal_type, label, project)
    VALUES ('delete', old.id, old.phrase, old.message, old.signal_type, old.label, old.project);
END;

-- Watermark per session file. Idempotent ingest is driven by comparing
-- on-disk mtime to last_mtime_ns; advancing the watermark is the commit.
CREATE TABLE IF NOT EXISTS ingest_watermark (
    session_path    TEXT PRIMARY KEY,
    source_client   TEXT NOT NULL DEFAULT 'claude',
    last_mtime_ns   INTEGER NOT NULL,
    last_ingested   TEXT NOT NULL DEFAULT (datetime('now'))
);

-- Single-row table tracking the last successful full-sweep timestamp,
-- consulted by read paths (query/assemble) for opportunistic catchup.
CREATE TABLE IF NOT EXISTS ingest_meta (
    key     TEXT PRIMARY KEY,
    value   TEXT NOT NULL
);

-- Reverse Poe: assistant turns followed by a NON-corrective user reply.
-- These are response shapes Nino tolerated — validated cadence/structure
-- exemplars. The shape_signature is a normalized digest of the response
-- structure (length bucket, has_question, has_list, has_code_block) used
-- for dedup. Storing the assistant text lets us mine cadence later.
CREATE TABLE IF NOT EXISTS validated_responses (
    id              INTEGER PRIMARY KEY AUTOINCREMENT,
    session_id      TEXT NOT NULL,
    source_client   TEXT NOT NULL DEFAULT 'claude',
    project         TEXT,
    timestamp       TEXT,
    response_text   TEXT NOT NULL,
    response_chars  INTEGER NOT NULL,
    shape_signature TEXT NOT NULL,
    follow_label    TEXT,           -- e.g. 'redirect-go', 'approval', 'silent'
    response_hash   TEXT NOT NULL,
    created_at      TEXT NOT NULL DEFAULT (datetime('now')),
    UNIQUE(session_id, response_hash)
);

CREATE INDEX IF NOT EXISTS validated_responses_shape_idx
    ON validated_responses(shape_signature);
CREATE INDEX IF NOT EXISTS validated_responses_project_idx
    ON validated_responses(project);
"""


def _migrate_fts_tokenizer(conn: sqlite3.Connection) -> bool:
    """Ensure the FTS5 index uses the porter tokenizer. Returns True if a
    rebuild is needed (caller invokes after schema recreate)."""
    row = conn.execute(
        "SELECT sql FROM sqlite_master WHERE type='table' AND name='voice_signals_fts'"
    ).fetchone()
    if not row:
        return False  # fresh DB — schema will create with porter, empty so no rebuild
    if row[0] and "porter" in row[0].lower():
        # Already correct, but check the internal storage is populated.
        # voice_signals_fts_data is FTS5's internal index table.
        try:
            data_rows = conn.execute("SELECT COUNT(*) FROM voice_signals_fts_data").fetchone()[0]
            base_rows = conn.execute("SELECT COUNT(*) FROM voice_signals").fetchone()[0]
            # FTS5 always has at least 1 row in _data for metadata; empty index has 1.
            return base_rows > 0 and data_rows <= 1
        except sqlite3.OperationalError:
            return False
    # Drop the wrong-tokenizer index; schema script recreates with porter.
    conn.execute("DROP TRIGGER IF EXISTS voice_signals_ai")
    conn.execute("DROP TRIGGER IF EXISTS voice_signals_ad")
    conn.execute("DROP TABLE voice_signals_fts")
    conn.commit()
    return True


def db_connect() -> sqlite3.Connection:
    RECALL_DB.parent.mkdir(parents=True, exist_ok=True)
    conn = sqlite3.connect(str(RECALL_DB))
    needs_rebuild = _migrate_fts_tokenizer(conn)
    conn.executescript(SCHEMA_SQL)
    _migrate_source_provenance(conn)
    if needs_rebuild:
        conn.execute("INSERT INTO voice_signals_fts(voice_signals_fts) VALUES('rebuild')")
        conn.commit()
    return conn


def _migrate_source_provenance(conn: sqlite3.Connection) -> None:
    """Add cross-client provenance to databases created before Codex ingest."""
    for table in ("voice_signals", "validated_responses", "ingest_watermark"):
        columns = {
            row[1] for row in conn.execute(f"PRAGMA table_info({table})").fetchall()
        }
        if "source_client" not in columns:
            conn.execute(
                f"ALTER TABLE {table} ADD COLUMN "
                "source_client TEXT NOT NULL DEFAULT 'claude'"
            )
    conn.commit()


def phrase_hash(phrase: str) -> str:
    """Stable hash for dedup — normalize whitespace and case."""
    norm = re.sub(r"\s+", " ", phrase.lower()).strip()[:200]
    return hashlib.sha1(norm.encode("utf-8")).hexdigest()[:16]


_HOME_PREFIX = str(Path.home()) + "/"
_WORKSPACE_PREFIX = str(Path.home() / "Workspace") + "/"


def _cwd_to_label(cwd: str) -> str:
    """Render a cwd as a short, readable project label.
    /Users/nino/Workspace/dev/wip/aisles-storefront -> wip/aisles-storefront
    /Users/nino/foo -> foo

    Transcript paths may come from another machine, so do not require the
    recorded home directory to match Path.home() on the ingest machine.
    """
    parts = Path(cwd).parts
    if "Workspace" in parts:
        workspace_index = parts.index("Workspace")
        rel_parts = list(parts[workspace_index + 1:])
        if rel_parts and rel_parts[0] == "dev":
            rel_parts = rel_parts[1:]
        if rel_parts:
            return "/".join(rel_parts)
    if cwd.startswith(_WORKSPACE_PREFIX):
        rel = cwd[len(_WORKSPACE_PREFIX):]
        # Drop the 'dev/' segment — it's nearly all of them, adds no information.
        if rel.startswith("dev/"):
            rel = rel[4:]
        return rel
    if cwd.startswith(_HOME_PREFIX):
        return cwd[len(_HOME_PREFIX):]
    if len(parts) >= 4 and parts[0] == "/" and parts[1] in {"Users", "home"}:
        return "/".join(parts[3:])
    return cwd


def _read_cwd(session_file: Path) -> str | None:
    """Read the transcript's project root without scanning tool payloads."""
    if transcript_source(session_file) == "gemini":
        try:
            data = json.loads(session_file.read_text(errors="replace"))
            directories = data.get("directories")
            if isinstance(directories, list) and directories:
                return str(directories[0])
            marker = session_file.parent.parent / ".project_root"
            if marker.exists():
                return marker.read_text(errors="replace").strip() or None
        except (OSError, json.JSONDecodeError):
            return None
        return None
    try:
        with open(session_file, "r", errors="replace") as f:
            for i, line in enumerate(f):
                if i > 20:  # bail if no cwd in early lines
                    return None
                line = line.strip()
                if not line:
                    continue
                try:
                    obj = json.loads(line)
                except json.JSONDecodeError:
                    continue
                payload = obj.get("payload")
                cwd = obj.get("cwd")
                if not cwd and isinstance(payload, dict):
                    cwd = payload.get("cwd")
                if cwd:
                    return cwd
    except OSError:
        return None
    return None


def project_label_for(session_file: Path) -> str:
    """Resolve a session file to its human-readable project label via cwd.
    Falls back to a dirname-derived label if cwd is unavailable."""
    cwd = _read_cwd(session_file)
    if cwd:
        return _cwd_to_label(cwd)
    if transcript_source(session_file) == "gemini":
        project_dir = session_file.parent.parent
        project_key = project_dir.name
        if re.fullmatch(r"[0-9a-f]{64}", project_key, re.IGNORECASE):
            return f"gemini/{project_key[:12]}"
        if project_key and project_key != "tmp":
            return project_key
    # Fallback: best-effort decode of Claude Code's dirname encoding.
    # Leading '-' marker, then path segments joined by '-'. The user name is
    # ambiguous once encoded (for example nino-chavez), so anchor on the
    # Workspace segment instead of hardcoding one machine's home directory.
    name = session_file.parent.name
    for marker in ("-Workspace-dev-", "-Workspace-"):
        if marker in name:
            return name.split(marker, 1)[1] or "unknown-project"
    if name.startswith(("-Users-", "-home-")):
        return "unknown-project"
    return name


def transcript_source(session_file: Path) -> str:
    """Detect the transcript producer without depending only on its location."""
    path = str(session_file)
    if "/.codex/" in path:
        return "codex"
    if "/.gemini/" in path:
        return "gemini"
    if "/.claude/" in path:
        return "claude"
    if session_file.suffix == ".json":
        try:
            data = json.loads(session_file.read_text(errors="replace"))
            if isinstance(data, dict) and isinstance(data.get("messages"), list):
                return "gemini"
        except (OSError, json.JSONDecodeError):
            pass
    try:
        with open(session_file, "r", errors="replace") as stream:
            for index, line in enumerate(stream):
                if index > 20:
                    break
                if '"type":"session_meta"' in line or '"type": "session_meta"' in line:
                    return "codex"
                if '"type":"event_msg"' in line or '"type": "event_msg"' in line:
                    return "codex"
                try:
                    obj = json.loads(line)
                except json.JSONDecodeError:
                    continue
                if obj.get("type") in {"user", "assistant"}:
                    return "claude"
    except OSError:
        pass
    return "unknown"


def session_id_for(session_file: Path) -> str:
    """Return the product session id, not Codex's rollout filename stem."""
    source = transcript_source(session_file)
    if source == "gemini":
        try:
            data = json.loads(session_file.read_text(errors="replace"))
            if data.get("sessionId"):
                return str(data["sessionId"])
        except (OSError, json.JSONDecodeError):
            pass
    if source == "codex":
        try:
            with open(session_file, "r", errors="replace") as stream:
                for index, line in enumerate(stream):
                    if index > 20:
                        break
                    try:
                        obj = json.loads(line)
                    except json.JSONDecodeError:
                        continue
                    if obj.get("type") != "session_meta":
                        continue
                    payload = obj.get("payload")
                    if isinstance(payload, dict):
                        value = payload.get("id") or payload.get("session_id")
                        if value:
                            return str(value)
        except OSError:
            pass
        match = re.search(
            r"([0-9a-f]{8}-[0-9a-f]{4}-[0-9a-f]{4}-[0-9a-f]{4}-[0-9a-f]{12})",
            session_file.stem,
            re.IGNORECASE,
        )
        if match:
            return match.group(1)
    return session_file.stem


# Codex writes one rollout per *agent*, not per conversation. 89% of the files
# under ~/.codex/sessions are subagents: 454 "guardian" permission-classifier
# sessions plus every thread_spawn child. Their `user_message` events are
# written by Codex or by a parent agent — never by Nino — and the guardian's
# prompt embeds the parent transcript verbatim, so ingesting it filed the
# agent's own prose as Nino correcting the agent, replayed once per assessment.
# (2026-08-26: 866 of 1008 codex rows were 40 messages repeated this way.)
#
# session_meta.payload.source says so structurally. Real sessions carry a
# string ("vscode"); subagents carry {"subagent": {...}}.
_CODEX_SUBAGENT_CACHE: dict[str, str | None] = {}


def codex_subagent_kind(session_file: Path) -> str | None:
    """Name of the subagent that owns this rollout, or None for a real session."""
    key = str(session_file)
    if key in _CODEX_SUBAGENT_CACHE:
        return _CODEX_SUBAGENT_CACHE[key]
    kind: str | None = None
    try:
        with open(session_file, "r", errors="replace") as stream:
            for index, line in enumerate(stream):
                if index > 20:
                    break
                try:
                    obj = json.loads(line)
                except json.JSONDecodeError:
                    continue
                if obj.get("type") != "session_meta":
                    continue
                payload = obj.get("payload")
                source = payload.get("source") if isinstance(payload, dict) else None
                if isinstance(source, dict) and "subagent" in source:
                    inner = source.get("subagent")
                    if isinstance(inner, dict):
                        kind = next(iter(inner.keys()), "subagent")
                        if kind == "other" and isinstance(inner.get("other"), str):
                            kind = inner["other"]
                    else:
                        kind = "subagent"
                break
    except OSError:
        kind = None
    _CODEX_SUBAGENT_CACHE[key] = kind
    return kind


def _claude_message_text(obj: dict) -> str | None:
    """Extract prose from a Claude user/assistant event; reject tool results."""
    message = obj.get("message")
    if not isinstance(message, dict):
        return None
    content = message.get("content", "")
    if isinstance(content, str):
        return content
    if not isinstance(content, list):
        return None
    texts: list[str] = []
    for block in content:
        if not isinstance(block, dict):
            continue
        if block.get("type") == "tool_result":
            return None
        if block.get("type") == "text" and block.get("text"):
            texts.append(str(block["text"]))
    return " ".join(texts) if texts else None


def iter_transcript_messages(session_file: Path):
    """Yield normalized `(timestamp, role, phase, text)` message events."""
    source = transcript_source(session_file)
    if source == "codex" and codex_subagent_kind(session_file):
        # Not Nino's voice. See codex_subagent_kind.
        return
    if source == "gemini":
        try:
            data = json.loads(session_file.read_text(errors="replace"))
        except (OSError, json.JSONDecodeError):
            return
        for message in data.get("messages", []):
            if not isinstance(message, dict):
                continue
            event_type = message.get("type")
            role = (
                "user"
                if event_type == "user"
                else "assistant"
                if event_type == "gemini"
                else None
            )
            text = message.get("content")
            if role and isinstance(text, str) and text.strip():
                yield message.get("timestamp", ""), role, None, text
        return
    try:
        with open(session_file, "r", errors="replace") as stream:
            for line in stream:
                # Codex tool outputs can be enormous. Only event_msg records contain
                # the human and agent prose this corpus is allowed to ingest.
                if source == "codex" and (
                    '"type":"event_msg"' not in line
                    and '"type": "event_msg"' not in line
                ):
                    continue
                try:
                    obj = json.loads(line)
                except json.JSONDecodeError:
                    continue
                timestamp = obj.get("timestamp", "")
                if source == "codex":
                    payload = obj.get("payload")
                    if obj.get("type") != "event_msg" or not isinstance(payload, dict):
                        continue
                    event_type = payload.get("type")
                    text = payload.get("message")
                    if not isinstance(text, str) or not text.strip():
                        continue
                    if event_type == "user_message":
                        yield timestamp, "user", None, text
                    elif event_type == "agent_message":
                        yield timestamp, "assistant", payload.get("phase"), text
                    continue

                event_type = obj.get("type")
                if event_type not in {"user", "assistant"}:
                    continue
                text = _claude_message_text(obj)
                if text:
                    yield timestamp, event_type, None, text
    except OSError:
        return


def iter_user_messages(session_file: Path):
    """Yield (timestamp, text, prior_assistant_text) for each real user turn.
    Deduplicates messages within a session (sidechain entries duplicate main chain)."""
    prior_assistant = ""
    seen_msgs: set[str] = set()
    for timestamp, role, _phase, text in iter_transcript_messages(session_file):
        if role == "assistant":
            prior_assistant = text[:600]
            continue
        text = text.strip()
        if len(text) < MIN_USER_MSG_LEN or len(text) > MAX_USER_MSG_LEN * 4:
            continue
        if text.startswith(NOISE_PREFIXES):
            continue
        if text.count("<") > 20 or text.count("```") > 6:
            continue
        msg_key = text[:200]
        if msg_key in seen_msgs:
            continue
        seen_msgs.add(msg_key)
        yield (
            timestamp,
            redact_secrets(text[:MAX_USER_MSG_LEN]),
            redact_secrets(prior_assistant),
        )


# Credential-shaped strings, redacted at ingest. Nino pastes real keys into
# prompts ("use this api key: ..."), and those sentences match signal patterns
# like [rejection/instead] — so they land in voice_signals, get mirrored into
# the FTS index, and the prompt-hook re-injects them into model context on any
# keyword match. That is silent egress from a file nobody thinks of as a secret
# store. Redact at the two ingest yields (iter_user_messages, iter_pairs) so
# every downstream path — signals, validated responses, phrase hashes, FTS —
# only ever sees the placeholder. Provider prefixes, not entropy heuristics:
# false positives here cost a mangled phrase, false negatives leak a live key.
SECRET_PATTERNS = re.compile(
    r"""(
        sk-ant-api\d{2}-[A-Za-z0-9_\-]{20,}     # Anthropic
      | sk-proj-[A-Za-z0-9_\-]{20,}             # OpenAI project
      | sk-or-v1-[A-Za-z0-9_\-]{20,}            # OpenRouter
      | sk-[A-Za-z0-9]{32,}                     # generic OpenAI-style
      | cfk_[A-Za-z0-9_\-]{24,}                 # Cloudflare
      | sbp_[A-Za-z0-9]{20,}                    # Supabase personal token
      | sb(?:p|s)_[A-Za-z0-9_\-]{20,}           # Supabase service keys
      | gh[pousr]_[A-Za-z0-9]{20,}              # GitHub tokens
      | AKIA[0-9A-Z]{16}                        # AWS access key id
      | xox[baprs]-[A-Za-z0-9\-]{10,}           # Slack
      | ey[A-Za-z0-9_\-]{10,}\.ey[A-Za-z0-9_\-]{10,}\.[A-Za-z0-9_\-]{10,}  # JWT
    )""",
    re.VERBOSE,
)

REDACTION = "[redacted-secret]"


def redact_secrets(text: str) -> str:
    """Replace credential-shaped substrings with a fixed placeholder."""
    if not text:
        return text
    return SECRET_PATTERNS.sub(REDACTION, text)


# Markers that suggest a regex hit landed inside pasted content, not Nino's voice
PASTE_MARKERS = re.compile(
    r'(\*\*[^*]+\*\*|`[^`]+`|\{"|"\}|://|\\n|\\\"|"detail":|^\s*[-*]\s|^\s*\d+\.\s)',
    re.MULTILINE,
)

# If these markers appear in the raw message, restrict scanning to the intro only
HEAVY_PASTE_MARKERS = re.compile(r'(```|^##+ |\n- \*\*|\n\d+\. \*\*)', re.MULTILINE)

# Sentence boundaries: terminator (. ! ?) followed by whitespace+capital/newline,
# or a newline run. Keeping it conservative — over-splitting truncates context.
SENTENCE_SPLIT = re.compile(r'(?<=[.!?])\s+(?=[A-Z"\'(\[])|\n{2,}')


def _bound_to_sentence(scan: str, match_start: int, match_end: int) -> str:
    """Extract the sentence containing the match, plus one preceding sentence
    if the match lands near the start of its own sentence (gives the regex hit
    its run-up — important for matches like 'because' where the rationale is in
    the prior clause). Avoids mid-word truncation."""
    # Walk back to nearest sentence start at or before match_start.
    left = 0
    for m in SENTENCE_SPLIT.finditer(scan, 0, match_start):
        left = m.end()
    # Walk forward to nearest sentence terminator at or after match_end.
    right = len(scan)
    fwd = SENTENCE_SPLIT.search(scan, match_end)
    if fwd:
        right = fwd.start()
    phrase = scan[left:right].strip()
    # If the match is in the first ~40 chars of the bounded sentence and a
    # prior sentence exists, prepend it — gives `because`/`instead` etc. the
    # antecedent they need to make sense.
    if (match_start - left) < 40 and left > 0:
        # Walk back one more sentence.
        prior_left = 0
        for m in SENTENCE_SPLIT.finditer(scan, 0, left - 1):
            prior_left = m.end()
        prior = scan[prior_left:left].strip()
        if prior:
            phrase = (prior + " " + phrase).strip()
    return phrase


def extract_signals(text: str):
    """Return list of (signal_type, label, matched_phrase) for a user message."""
    hits = []
    seen = set()

    # If the message looks like it contains pasted blocks, only scan the intro
    if HEAVY_PASTE_MARKERS.search(text):
        scan = text[:300]
    else:
        scan = text[:800]

    for stype, pat, label in SIGNAL_PATTERNS:
        m = pat.search(scan)
        if not m:
            continue
        key = (stype, label)
        if key in seen:
            continue

        phrase = _bound_to_sentence(scan, m.start(), m.end())
        # Cap pathological-length sentences (legal/run-on prose).
        if len(phrase) > 400:
            phrase = phrase[:400].rsplit(" ", 1)[0] + "…"

        # Skip if the phrase itself looks like pasted content
        if PASTE_MARKERS.search(phrase):
            continue
        # Skip short or mostly-URL phrases — but redirect-go is intentionally short.
        # The signal IS the brevity ("go" alone after a hesitation question);
        # the context lives in prior_assistant.
        if label != "redirect-go" and len(phrase) < 20:
            continue

        seen.add(key)
        hits.append((stype, label, phrase))
    return hits


CORRECTIVE_LABELS = {
    "opening-negative", "that-is-wrong", "you-are-wrong", "why-did-you",
    "undo", "not-what-i-asked", "over-engineered",
}


def _shape_signature(text: str) -> str:
    """Compact signature of an assistant response shape — used for dedup.
    Captures: length bucket, ends-with-question, has bullet list, has code block,
    sentence count bucket. Two responses with the same signature are roughly
    structurally equivalent."""
    n = len(text)
    if n < 200:
        bucket = "xs"
    elif n < 600:
        bucket = "s"
    elif n < 1500:
        bucket = "m"
    elif n < 4000:
        bucket = "l"
    else:
        bucket = "xl"
    sent = len(re.findall(r"[.!?](?:\s|$)", text))
    sb = min(sent // 5, 6)  # bucketed sentence count
    q = "Q" if text.rstrip().endswith("?") else "."
    lst = "L" if re.search(r"(?m)^\s*[-*]\s|\n\d+\.\s", text) else "-"
    code = "C" if "```" in text else "-"
    return f"{bucket}/{sb}/{q}{lst}{code}"


def _classify_follow(user_text: str) -> str | None:
    """Given the user reply that followed an assistant turn, classify it.
    Returns one of: 'corrective', 'redirect-go', 'approval', 'neutral',
    or None for empty/skip."""
    text = user_text.strip()
    if not text:
        return None
    # Run the signal patterns; if any corrective label fires, this is corrective.
    hits = extract_signals(text)
    labels = {label for _, label, _ in hits}
    if labels & CORRECTIVE_LABELS:
        return "corrective"
    if "redirect-go" in labels:
        return "redirect-go"
    if "short-approval" in labels or "ship-it" in labels:
        return "approval"
    return "neutral"


def iter_pairs(session_file: Path):
    """Yield (assistant_text, follow_user_text, ts) for each adjacent
    assistant→user pair in the JSONL."""
    pending_assistant: str | None = None
    pending_ts = ""
    source = transcript_source(session_file)
    for timestamp, role, phase, text in iter_transcript_messages(session_file):
        if role == "assistant":
            # Commentary is useful as correction context, but it is not a
            # completed response shape and must not become a positive exemplar.
            if source == "codex" and phase != "final_answer":
                continue
            pending_assistant = text.strip()
            pending_ts = timestamp
            continue
        if role == "user" and pending_assistant:
            yield (
                redact_secrets(pending_assistant),
                redact_secrets(text.strip()),
                pending_ts,
            )
            pending_assistant = None


def _extract_validated_from_file(jf: Path) -> list[dict]:
    """Pair-walk pass: find assistant turns followed by non-corrective replies.
    Excludes turns where the assistant text is dominated by tool-use markers
    or is trivially short (no behavioral signal)."""
    project = project_label_for(jf)
    source_client = transcript_source(jf)
    session_id = session_id_for(jf)
    out: list[dict] = []
    for assistant_text, follow_text, ts in iter_pairs(jf):
        # Filter: skip very short or near-empty assistant turns.
        if len(assistant_text) < 80:
            continue
        # Skip turns dominated by tool-call narration (lots of backticks/paths).
        if assistant_text.count("`") > 30:
            continue
        follow_class = _classify_follow(follow_text)
        if follow_class is None or follow_class == "corrective":
            continue
        signature = _shape_signature(assistant_text)
        digest = hashlib.sha1(assistant_text[:600].encode("utf-8")).hexdigest()[:16]
        out.append({
            "project": project,
            "session_id": session_id,
            "source_client": source_client,
            "timestamp": ts,
            "response_text": assistant_text[:2000],
            "response_chars": len(assistant_text),
            "shape_signature": signature,
            "follow_label": follow_class,
            "response_hash": digest,
        })
    return out


def _upsert_validated(conn: sqlite3.Connection, records: list[dict]) -> int:
    inserted = 0
    for r in records:
        try:
            cur = conn.execute(
                """
                INSERT OR IGNORE INTO validated_responses
                    (session_id, source_client, project, timestamp, response_text, response_chars,
                     shape_signature, follow_label, response_hash)
                VALUES (?, ?, ?, ?, ?, ?, ?, ?, ?)
                """,
                (
                    r["session_id"], r.get("source_client", "claude"),
                    r.get("project"), r.get("timestamp") or "",
                    r["response_text"], r["response_chars"],
                    r["shape_signature"], r.get("follow_label"), r["response_hash"],
                ),
            )
            if cur.rowcount > 0:
                inserted += 1
        except sqlite3.Error as e:
            print(f"  validated insert error: {e}", file=sys.stderr)
    conn.commit()
    return inserted


def _extract_from_file(jf: Path) -> list[dict]:
    """Extract all signal records from a single JSONL file."""
    project = project_label_for(jf)
    source_client = transcript_source(jf)
    session_id = session_id_for(jf)
    records: list[dict] = []
    for ts, text, prior in iter_user_messages(jf):
        hits = extract_signals(text)
        for stype, label, phrase in hits:
            records.append({
                "project": project,
                "session_id": session_id,
                "source_client": source_client,
                "timestamp": ts,
                "signal": stype,
                "label": label,
                "phrase": phrase,
                "message": text[:1200],
                "prior_assistant": prior[:400],
            })
    return records


def _upsert_signals(conn: sqlite3.Connection, records: list[dict]) -> int:
    """Insert records into voice_signals, skipping duplicates. Returns inserted count."""
    inserted = 0
    for r in records:
        try:
            cur = conn.execute(
                """
                INSERT OR IGNORE INTO voice_signals
                    (session_id, source_client, project, timestamp, signal_type, label,
                     phrase, message, prior_assistant, phrase_hash)
                VALUES (?, ?, ?, ?, ?, ?, ?, ?, ?, ?)
                """,
                (
                    r["session_id"],
                    r.get("source_client", "claude"),
                    r.get("project"),
                    r.get("timestamp") or "",
                    r["signal"],
                    r["label"],
                    r["phrase"],
                    r.get("message", ""),
                    r.get("prior_assistant", ""),
                    phrase_hash(r["phrase"]),
                ),
            )
            if cur.rowcount > 0:
                inserted += 1
        except sqlite3.Error as e:
            print(f"  db error: {e}", file=sys.stderr)
    conn.commit()
    return inserted


def _watermark_get(conn: sqlite3.Connection, path: str) -> int:
    row = conn.execute(
        "SELECT last_mtime_ns FROM ingest_watermark WHERE session_path = ?",
        (path,),
    ).fetchone()
    return row[0] if row else 0


def _watermark_set(
    conn: sqlite3.Connection, path: str, mtime_ns: int, source_client: str
) -> None:
    conn.execute(
        """
        INSERT INTO ingest_watermark (session_path, source_client, last_mtime_ns)
        VALUES (?, ?, ?)
        ON CONFLICT(session_path) DO UPDATE SET
            source_client = excluded.source_client,
            last_mtime_ns = excluded.last_mtime_ns,
            last_ingested = datetime('now')
        """,
        (path, source_client, mtime_ns),
    )


def _meta_get(conn: sqlite3.Connection, key: str) -> str | None:
    row = conn.execute("SELECT value FROM ingest_meta WHERE key = ?", (key,)).fetchone()
    return row[0] if row else None


def _meta_set(conn: sqlite3.Connection, key: str, value: str) -> None:
    conn.execute(
        "INSERT INTO ingest_meta (key, value) VALUES (?, ?) "
        "ON CONFLICT(key) DO UPDATE SET value = excluded.value",
        (key, value),
    )


def _ingest_file(conn: sqlite3.Connection, jf: Path) -> tuple[int, int]:
    """Ingest one session file if its mtime exceeds the watermark.
    Returns (signals_seen, signals_or_validated_inserted). No-op if current.
    Runs both the user-signal extractor AND the validated-response pair walker
    so both corpora stay in sync under one watermark."""
    try:
        mtime_ns = jf.stat().st_mtime_ns
    except FileNotFoundError:
        return (0, 0)
    path_str = str(jf)
    source_client = transcript_source(jf)
    if _watermark_get(conn, path_str) >= mtime_ns:
        return (0, 0)
    records = _extract_from_file(jf)
    inserted = _upsert_signals(conn, records)
    validated = _extract_validated_from_file(jf)
    v_inserted = _upsert_validated(conn, validated)
    _watermark_set(conn, path_str, mtime_ns, source_client)
    conn.commit()
    # Roll validated inserts into the "anything changed?" count so catchup
    # rebuilds stack.md when only reverse-Poe data is new.
    return (len(records) + len(validated), inserted + v_inserted)


def _iter_session_files(
    include_codex: bool = False, include_gemini: bool = False
) -> list[Path]:
    files: list[Path] = []
    if PROJECTS_DIR.exists():
        for proj_dir in sorted(PROJECTS_DIR.iterdir()):
            if proj_dir.is_dir():
                files.extend(proj_dir.glob("*.jsonl"))
    if include_codex:
        if CODEX_SESSIONS_DIR.exists():
            files.extend(CODEX_SESSIONS_DIR.rglob("*.jsonl"))
        if CODEX_ARCHIVED_SESSIONS_DIR.exists():
            files.extend(CODEX_ARCHIVED_SESSIONS_DIR.glob("*.jsonl"))
    if include_gemini and GEMINI_SESSIONS_DIR.exists():
        files.extend(GEMINI_SESSIONS_DIR.glob("*/chats/session-*.json"))
    return sorted(set(files))


def cmd_catchup(
    verbose: bool = False,
    include_codex: bool = False,
    include_gemini: bool = False,
) -> None:
    """Ingest every session file with mtime newer than its watermark.

    Idempotent: re-running with no new data is near-zero cost (one stat
    per file, no extraction, no DB writes beyond the meta timestamp).
    Safe to invoke from any trigger — hook drain, schedule, read path."""
    conn = db_connect()
    files = _iter_session_files(
        include_codex=include_codex, include_gemini=include_gemini
    )
    scanned = 0
    ingested_files = 0
    total_signals = 0
    total_inserted = 0
    for jf in files:
        scanned += 1
        signals, inserted = _ingest_file(conn, jf)
        if signals:
            ingested_files += 1
            total_signals += signals
            total_inserted += inserted
    _meta_set(conn, "last_catchup", datetime.now(timezone.utc).isoformat(timespec="seconds"))
    conn.commit()
    conn.close()
    if verbose or ingested_files:
        print(
            f"catchup: {scanned} scanned, {ingested_files} ingested, "
            f"{total_inserted}/{total_signals} new mined records",
            file=sys.stderr,
        )
    # Stack.md is the human/LLM-facing artifact. Rebuild it when the corpus
    # changed so the consumer never reads stale signals.
    if total_inserted > 0:
        cmd_assemble(_skip_catchup=True)


def build_retention_report(
    conn: sqlite3.Connection,
    archive_dir: Path,
    grace_days: int = 7,
    now: datetime | None = None,
    list_covered: bool = False,
) -> dict:
    """Measure watermark-covered archived Codex transcripts without deleting them.

    Watermark coverage proves ingestion, not semantic closeout or promotion, so
    this report never declares a file safe to delete.
    """
    if grace_days < 0:
        raise ValueError("grace_days must be zero or greater")
    archive_exists = archive_dir.is_dir()

    reference = now or datetime.now(timezone.utc)
    if reference.tzinfo is None:
        reference = reference.replace(tzinfo=timezone.utc)
    grace_seconds = grace_days * 86400
    totals = {
        "watermark_covered": {"files": 0, "bytes": 0},
        "too_recent": {"files": 0, "bytes": 0},
        "uncovered": {"files": 0, "bytes": 0},
        "changed_after_ingest": {"files": 0, "bytes": 0},
        "errors": {"files": 0, "bytes": 0},
    }
    covered: list[dict] = []

    transcripts = sorted(archive_dir.glob("*.jsonl")) if archive_exists else []
    for transcript in transcripts:
        try:
            stat = transcript.stat()
        except OSError:
            totals["errors"]["files"] += 1
            continue

        row = conn.execute(
            "SELECT last_mtime_ns FROM ingest_watermark WHERE session_path = ?",
            (str(transcript),),
        ).fetchone()
        watermark_ns = int(row[0]) if row else 0
        age_seconds = max(0.0, reference.timestamp() - stat.st_mtime)

        if not watermark_ns:
            bucket = "uncovered"
        elif watermark_ns < stat.st_mtime_ns:
            bucket = "changed_after_ingest"
        elif age_seconds < grace_seconds:
            bucket = "too_recent"
        else:
            bucket = "watermark_covered"

        totals[bucket]["files"] += 1
        totals[bucket]["bytes"] += stat.st_size
        if bucket == "watermark_covered" and list_covered:
            covered.append(
                {
                    "path": str(transcript),
                    "bytes": stat.st_size,
                    "mtime_ns": stat.st_mtime_ns,
                    "watermark_ns": watermark_ns,
                    "age_days": round(age_seconds / 86400, 2),
                }
            )

    report = {
        "source_client": "codex",
        "archive_dir": str(archive_dir),
        "archive_exists": archive_exists,
        "grace_days": grace_days,
        "scanned_files": sum(bucket["files"] for bucket in totals.values()),
        **totals,
        "deletion_authorized": False,
        "note": (
            "Watermark coverage proves ingestion only. Delete nothing until "
            "human closeout confirms durable lessons and project truth were promoted."
        ),
    }
    if list_covered:
        report["covered_files"] = covered
    return report


def cmd_retention_report(grace_days: int = 7, list_covered: bool = False) -> None:
    conn = db_connect()
    try:
        report = build_retention_report(
            conn,
            CODEX_ARCHIVED_SESSIONS_DIR,
            grace_days=grace_days,
            list_covered=list_covered,
        )
    finally:
        conn.close()
    print(json.dumps(report, indent=2, sort_keys=True))


def _resolve_queued_transcript(entry: dict) -> Path | None:
    """Resolve a queued transcript after Codex may have archived/moved it."""
    raw_path = entry.get("transcript_path") or entry.get("session_file") or ""
    if raw_path:
        path = Path(str(raw_path)).expanduser()
        if path.exists():
            return path
    source_client = entry.get("source_client") or entry.get("source")
    session_id = str(entry.get("session_id") or "").strip()
    if source_client != "codex" or not session_id:
        return None
    candidates: list[Path] = []
    if CODEX_SESSIONS_DIR.exists():
        candidates.extend(CODEX_SESSIONS_DIR.rglob(f"*{session_id}*.jsonl"))
    if CODEX_ARCHIVED_SESSIONS_DIR.exists():
        candidates.extend(CODEX_ARCHIVED_SESSIONS_DIR.glob(f"*{session_id}*.jsonl"))
    return max(candidates, key=lambda item: item.stat().st_mtime_ns) if candidates else None


def cmd_drain_queue(
    verbose: bool = False,
    include_codex: bool = False,
    include_gemini: bool = False,
) -> None:
    """Drain ~/.claude/poe/queue, ingesting each listed transcript path.

    The queue is a newline-delimited file of transcript paths written by
    the SessionEnd hook. Drains atomically: rename the queue aside, then
    ingest entries. Files not in the queue are still picked up by the
    next catchup sweep — the queue is an optimization, not the source
    of truth."""
    conn = db_connect()
    if not QUEUE_PATH.exists():
        # Nothing queued, but still run a watermark sweep so the worker
        # is self-healing if WatchPaths missed an event.
        conn.close()
        cmd_catchup(
            verbose=verbose,
            include_codex=include_codex,
            include_gemini=include_gemini,
        )
        return
    tmp = QUEUE_PATH.with_suffix(".draining")
    try:
        QUEUE_PATH.rename(tmp)
    except FileNotFoundError:
        conn.close()
        cmd_catchup(
            verbose=verbose,
            include_codex=include_codex,
            include_gemini=include_gemini,
        )
        return

    paths: list[Path] = []
    seen: set[str] = set()
    with open(tmp, "r", errors="replace") as f:
        for line in f:
            value = line.strip()
            if not value:
                continue
            if value.startswith("{"):
                try:
                    entry = json.loads(value)
                except json.JSONDecodeError:
                    continue
            else:
                entry = {"transcript_path": value}
            path = _resolve_queued_transcript(entry)
            if path is None:
                continue
            key = str(path)
            if key in seen:
                continue
            seen.add(key)
            paths.append(path)
    tmp.unlink(missing_ok=True)

    ingested = 0
    inserted_total = 0
    for jf in paths:
        if not jf.exists():
            continue
        signals, inserted = _ingest_file(conn, jf)
        if signals:
            ingested += 1
            inserted_total += inserted
    conn.close()
    if verbose or ingested:
        print(
            f"drain-queue: {len(paths)} queued, {ingested} ingested, "
            f"{inserted_total} new signals",
            file=sys.stderr,
        )
    # Belt-and-suspenders: catch any sessions the queue missed.
    cmd_catchup(
        verbose=False,
        include_codex=include_codex,
        include_gemini=include_gemini,
    )


HEDGE_WORDS = {
    "maybe", "perhaps", "possibly", "might", "could", "seems", "somewhat",
    "kind", "sort", "fairly", "rather", "pretty", "i think", "i guess",
    "i suppose", "probably", "arguably", "potentially", "presumably",
}
CHEERLEAD_WORDS = {
    "great", "awesome", "fantastic", "amazing", "perfect", "excellent",
    "love", "absolutely", "definitely", "totally", "wonderful",
}
PROFANITY = {"fuck", "shit", "damn", "hell", "crap", "wtf", "bs"}


def _tone_stats(messages: list[str]) -> dict:
    """Compute tone fingerprint from a list of raw user-turn texts."""
    if not messages:
        return {}
    sentence_lens: list[int] = []
    word_count = 0
    hedge_hits = 0
    cheerlead_hits = 0
    profanity_hits = 0
    question_count = 0
    imperative_starts = 0
    lowercase_starts = 0
    opening_verbs: Counter = Counter()
    msg_count = 0

    for text in messages:
        text = text.strip()
        if not text:
            continue
        msg_count += 1
        sentences = [s.strip() for s in re.split(r"(?<=[.!?])\s+", text) if s.strip()]
        for s in sentences:
            words = re.findall(r"\b\w+\b", s)
            if not words:
                continue
            sentence_lens.append(len(words))
            word_count += len(words)
            if s.rstrip().endswith("?"):
                question_count += 1
            first = words[0].lower()
            if first[:1].isalpha() and not s[0].isupper():
                lowercase_starts += 1
            # Imperative heuristic: starts with a bare verb (no subject)
            if first in {
                "do", "don't", "use", "stop", "drop", "remove", "add",
                "make", "keep", "let", "go", "skip", "fix", "check",
                "build", "ship", "push", "merge", "delete", "rename",
                "move", "rewrite", "rework",
            }:
                imperative_starts += 1
                opening_verbs[first] += 1
        low = text.lower()
        for h in HEDGE_WORDS:
            if h in low:
                hedge_hits += 1
                break  # one hit per message
        for c in CHEERLEAD_WORDS:
            if re.search(r"\b" + re.escape(c) + r"\b", low):
                cheerlead_hits += 1
                break
        for p in PROFANITY:
            if re.search(r"\b" + re.escape(p) + r"\b", low):
                profanity_hits += 1
                break

    if not sentence_lens:
        return {}
    sentence_lens.sort()
    median_len = sentence_lens[len(sentence_lens) // 2]
    p90_len = sentence_lens[int(len(sentence_lens) * 0.9)]

    return {
        "messages": msg_count,
        "sentences": len(sentence_lens),
        "median_sentence_words": median_len,
        "p90_sentence_words": p90_len,
        "hedge_rate_pct": round(100 * hedge_hits / msg_count, 1),
        "cheerlead_rate_pct": round(100 * cheerlead_hits / msg_count, 1),
        "profanity_rate_pct": round(100 * profanity_hits / msg_count, 1),
        "question_rate_pct": round(100 * question_count / len(sentence_lens), 1),
        "imperative_start_rate_pct": round(100 * imperative_starts / len(sentence_lens), 1),
        "lowercase_start_rate_pct": round(100 * lowercase_starts / len(sentence_lens), 1),
        "top_imperative_openers": opening_verbs.most_common(10),
    }


def _signal_age_days(ts: str) -> float | None:
    """Days between a signal's recorded timestamp and now. Returns None for
    unparseable timestamps (legacy rows)."""
    if not ts:
        return None
    try:
        dt = datetime.fromisoformat(ts.replace("Z", "+00:00"))
    except ValueError:
        return None
    if dt.tzinfo is None:
        dt = dt.replace(tzinfo=timezone.utc)
    return (datetime.now(timezone.utc) - dt).total_seconds() / 86400.0


def _decay_weight(age_days: float | None) -> float:
    """Recency weight in [0.1, 1.0]. Decays linearly from 1.0 at 0d to
    0.1 at 365d, floor at 0.1 thereafter. Unknown-age rows get 0.5 — they
    exist but should not dominate fresh signals."""
    if age_days is None:
        return 0.5
    if age_days <= 0:
        return 1.0
    if age_days >= 365:
        return 0.1
    return 1.0 - (age_days / 365.0) * 0.9


def classify_prompt_intent(prompt: str) -> list[tuple[str, str]]:
    """Predict failure modes a user PROMPT is likely to elicit from Claude.
    Different from classify_situation: that operates on drafts (does this
    response contain a failure?), this operates on prompts (does this prompt
    invite a failure?). Designed for the UserPromptSubmit hook.

    Pattern catalog calibrated against the 10-prompt adversarial set —
    elicitation shapes Nino's corpus shows Claude routinely falls into."""
    hits: list[tuple[str, str]] = []
    t = prompt.strip()
    if not t:
        return hits
    low = t.lower()

    # User asks Claude to break work into steps with check-ins.
    # Strong predictor of mid-task hesitation questions.
    if re.search(r"\b(walk me through|lay out (each|the) step|step by step|"
                 r"let me know (when|if) (you|to|i)|check in (with me|along)|"
                 r"each step|ready to (continue|proceed|move))\b", low):
        hits.append(("invites-hesitation", "step-by-step + check-in language"))

    # User uses hedge words. Claude tends to mirror — hedge in = hedge out.
    user_hedge_count = sum(
        1 for h in HEDGE_WORDS if re.search(r"\b" + re.escape(h) + r"\b", low)
    )
    if user_hedge_count >= 2:
        hits.append(("invites-hedging", f"{user_hedge_count} hedge words in prompt"))

    # User invites evaluation / asks for praise-shaped response.
    if re.search(r"\b(honest thoughts|honest opinion|honest review|what do you think|"
                 r"how (does it|do you) look|review (my|the|this)|give me your|"
                 r"thoughts\?)\b", low):
        hits.append(("invites-cheerleading", "evaluation request shape"))

    # User asks open-ended "design / architect / build" with no constraints.
    # Predicts over-engineering — Claude enumerates every edge case.
    # Matches "design an auth system", "build a payment service", etc. —
    # an optional qualifier word between determiner and the structural noun
    # widens coverage beyond bare "design an app".
    if re.search(
        r"\b(design|architect|build|create) (an?|the) (\w+ )?"
        r"(system|app|service|api|platform|tool|architecture|framework|"
        r"flow|pipeline|workflow|module|component|library|scheme)\b",
        low,
    ):
        if not re.search(r"\b(only|just|simple|minimal|small|tiny|quick|stub|sketch)\b", low):
            hits.append(("invites-over-engineering", "open-ended design ask"))

    # User asks for an "explain" with no audience or depth constraint.
    # Predicts vague rationale / generic textbook prose.
    if re.search(r"^\s*(explain|describe|walk me through)\b", low):
        if not re.search(r"\b(why|because|so that|for the purpose|in (one|two) "
                         r"(sentence|paragraph|line)|short(ly)?|brief)\b", low):
            hits.append(("invites-vague-rationale", "explain without depth/audience constraint"))

    # User explicitly mentions destructive ops.
    if re.search(r"\b(delete|remove|drop|reset|force[ -]push|truncate|"
                 r"clean ?up (my|the) (git|repo|branches|database))\b", low):
        # Strong destructive language — pause regardless of prior context.
        hits.append(("invites-destructive-action", "user requested destructive op"))

    # User asks "what should I do?" / "what's the right approach?" — open-ended
    # vague rationale invitation, and combined with hedge often produces churn.
    if re.search(r"\b(what (should|do) (i|we)|what'?s the right (approach|way)|"
                 r"how should (we|i)|where (to|should i) start)\b", low):
        hits.append(("invites-vague-rationale", "open-ended 'what should we' framing"))

    return hits


PROMPT_GUIDANCE = {
    "invites-hesitation": (
        "Prompt invites step-by-step check-ins. Nino's corpus has 293 cases "
        "of overriding hesitation questions with a single 'go'. Lay out the "
        "full plan in one pass; do not ask for permission between steps."
    ),
    "invites-hedging": (
        "Prompt contains hedge words. Do NOT mirror — Nino's tone is "
        "concrete, not hedged. Replace 'maybe'/'might' with 'X if Y, "
        "otherwise Z'."
    ),
    "invites-cheerleading": (
        "Prompt invites evaluation. Skip praise words. Lead with the "
        "load-bearing critique or the load-bearing affirmation, in that "
        "order. No 'great', 'amazing', 'absolutely'."
    ),
    "invites-over-engineering": (
        "Open-ended design ask. Nino has 14 documented pushbacks on "
        "over-engineering. Start with the minimum viable shape for the "
        "stated case. Do NOT pre-emptively enumerate edge cases."
    ),
    "invites-vague-rationale": (
        "Open 'explain' / 'what should we do'. Anchor the response in the "
        "specific situation rather than generic theory. If you cannot tell "
        "the situation, ask ONE clarifying question — not three."
    ),
    "invites-destructive-action": (
        "User mentioned a destructive op. Confirm scope before executing "
        "even if authorization seems implicit. The 'still ask when' clause "
        "in the decision-bias rule applies."
    ),
}


def classify_situation(text: str) -> list[tuple[str, str]]:
    """Classify a draft response or prompt into Poe-relevant situations.
    Returns list of (situation_id, evidence) tuples — one text can match
    multiple situations. Designed to be cheap (regex-only) so it can run
    in hooks and tight loops."""
    hits: list[tuple[str, str]] = []
    t = text.strip()
    if not t:
        return hits
    low = t.lower()
    tail = t[-400:]

    # 1) Hesitation — the highest-volume failure mode. Two shapes:
    #    a) Explicit question form ("want me to...?", "should I...?")
    #    b) Statement-form soft closer ("ready when you are", "say the word")
    #    Both functionally request permission; the second is harder to spot
    #    because it isn't grammatically a question. Both live here so the
    #    post-response Stop hook (anti-hesitation.py) can share this catalog.
    hesitation_patterns = [
        r"\b(want me to|should I|do you want|shall I|would you like|let me know)\b[^.]*\?",
        r"\b(proceed|continue|keep going|go ahead|move on)\b[^.]*\?",
        r"\b(stop here|pause|hold|wait)\b[^.]*\?",
        r"\bor (should|do|stop)\b[^.]*\?",
        # Statement-form soft closers — anchored to end-of-text/sentence so
        # mid-prose mentions don't false-positive. \s+ (not \s) tolerates
        # blank lines between the prior sentence and the closer.
        r"(?:^|[.!]\s+)(ready when you are|say the word|let me know when|"
        r"when you'?re ready|on your signal|whenever you'?re ready|"
        r"flag me when|ping me when)\b[^.!?]{0,80}[.!?]?\s*$",
    ]
    for p in hesitation_patterns:
        m = re.search(p, tail, re.IGNORECASE)
        if m:
            hits.append(("hesitation", m.group(0).strip()))
            break

    # 2) Over-explanation / hedge density.
    hedge_count = sum(1 for h in HEDGE_WORDS if re.search(r"\b" + re.escape(h) + r"\b", low))
    if hedge_count >= 3:
        hits.append(("hedge-dense", f"{hedge_count} hedge words"))

    # 3) Cheerleading.
    cheer = [c for c in CHEERLEAD_WORDS if re.search(r"\b" + re.escape(c) + r"\b", low)]
    if cheer:
        hits.append(("cheerleading", ", ".join(cheer[:3])))

    # 4) Destructive-action signals (the rule's "still ask when").
    # Note: patterns starting with `--` can't use \b before the dashes since
    # `--` is two non-word chars — \b requires a word/non-word boundary.
    destruct = re.search(
        r"(?:\b(?:force[ -]push|rm -rf|drop (?:table|database)|delete branch|"
        r"reset --hard|amend (?:the )?published|truncate (?:table|database))\b"
        r"|(?:^|\s)--(?:no-verify|force|hard))",
        low,
    )
    if destruct:
        hits.append(("destructive-action", destruct.group(0).strip()))

    # 5) Vague rationale — assertions with no "because" or concrete grounding.
    # Threshold of 200 chars: shorter than that, terseness is fine; longer,
    # absence of any causal connective is suspicious. Calibrated against the
    # golden negative cases — technical explanations naturally use "because"
    # / "since" / etc., so the false-positive risk is low.
    if len(t) > 200 and not re.search(r"\b(because|since|due to|the reason|otherwise|so that)\b", low):
        hits.append(("vague-rationale", f"no causal connective in {len(t)}-char draft"))

    # 6) Over-engineering tell: enumerating many "what if" branches or future
    #    needs in a single response.
    whatif = len(re.findall(r"\bwhat if\b", low))
    if whatif >= 2:
        hits.append(("over-engineered", f"{whatif} 'what if' branches"))

    # 7) Trailing summary: closing with "Summary:" or "To summarize" or "In short" —
    #    Nino explicitly said don't do this.
    if re.search(r"\b(in summary|to summarize|in short|tldr|tl;dr|to recap)\b", tail, re.IGNORECASE):
        hits.append(("trailing-summary", "closing recap pattern"))

    return hits


SITUATION_GUIDANCE = {
    "hesitation": (
        "**Hesitation question detected.** The CLAUDE.md decision-bias rule "
        "prohibits this. The corpus has 293 cases of Claude asking exactly this "
        "shape of question and Nino answering with a single 'go'/'proceed'. "
        "Restate as a status sentence: 'Doing X next — flag if you want to stop.'"
    ),
    "hedge-dense": (
        "**Hedge density above tolerance.** Nino's corpus shows ~11% hedge "
        "rate; this draft is higher. Replace 'maybe', 'might', 'I think' with "
        "concrete assertions or explicit qualifiers ('with caveat X')."
    ),
    "cheerleading": (
        "**Cheerleading word detected.** Nino's corpus has <2% praise-word "
        "rate. Replace with neutral evaluation: 'great' → 'works', "
        "'perfect' → 'matches', 'absolutely' → drop."
    ),
    "destructive-action": (
        "**Destructive action mentioned.** The decision-bias rule's "
        "'still ask when' clause applies — confirm before executing even if "
        "the broader thread was authorized."
    ),
    "vague-rationale": (
        "**Long draft with no causal connective.** Nino's rationale signals "
        "use 'because', 'otherwise', 'the reason is' liberally. Add the "
        "load-bearing 'why' or trim the assertion."
    ),
    "over-engineered": (
        "**Multiple 'what if' branches.** Nino has 14 documented pushbacks on "
        "over-engineering. State the case the user actually has; defer "
        "hypothetical branches until they arise."
    ),
    "trailing-summary": (
        "**Trailing summary closing.** Nino has a saved memory: don't "
        "summarize what you just did — the diff is visible. Cut the recap."
    ),
}


def cmd_poe_check(text: str | None, limit: int) -> None:
    """Classify a draft against Poe situations and surface relevant signals.
    Reads draft from stdin if --text not provided. Output is markdown."""
    if text is None:
        text = sys.stdin.read()
    if not text.strip():
        print("poe-check: empty input. Pass text via stdin or --text.", file=sys.stderr)
        sys.exit(2)

    situations = classify_situation(text)
    print("# Poe check")
    print()
    if not situations:
        print("_No Poe red flags detected in this draft._")
        return

    print(f"_{len(situations)} situation(s) detected._")
    print()
    for sit_id, evidence in situations:
        guidance = SITUATION_GUIDANCE.get(sit_id, "")
        print(f"## `{sit_id}`")
        print()
        print(f"**Evidence:** `{evidence}`")
        print()
        if guidance:
            print(guidance)
            print()

    # Pull representative corpus signals to ground the warnings.
    if not RECALL_DB.exists():
        return
    conn = db_connect()
    sit_to_labels = {
        "hesitation": ["redirect-go"],
        "hedge-dense": ["i-prefer"],
        "cheerleading": [],
        "destructive-action": ["undo"],
        "vague-rationale": ["because"],
        "over-engineered": ["over-engineered"],
        "trailing-summary": [],
    }
    relevant_labels: set[str] = set()
    for sit_id, _ in situations:
        relevant_labels.update(sit_to_labels.get(sit_id, []))
    if relevant_labels:
        print("## Grounding signals from corpus")
        print()
        placeholders = ",".join("?" for _ in relevant_labels)
        rows = conn.execute(
            f"""
            SELECT signal_type, label, phrase, project, prior_assistant
            FROM voice_signals
            WHERE label IN ({placeholders})
            ORDER BY timestamp DESC
            LIMIT ?
            """,
            (*relevant_labels, limit),
        ).fetchall()
        for stype, label, phrase, project, prior in rows:
            phrase_clean = re.sub(r"\s+", " ", phrase).strip()[:200]
            proj_short = (project or "?").split("/")[-1]
            if label == "redirect-go" and prior:
                tail = re.sub(r"\s+", " ", prior).strip()[-180:]
                print(f"- Claude: \"…{tail}\" → Nino: **\"{phrase_clean}\"** _({proj_short})_")
            else:
                print(f"- \"{phrase_clean}\" _({proj_short}, `{label}`)_")
        print()
    conn.close()


def _collect_memory_indexes() -> list[tuple[Path, str]]:
    """Find all MEMORY.md indexes Claude Code uses for auto-memory.
    Returns list of (path, content) tuples."""
    out = []
    base = Path.home() / ".claude" / "projects"
    if not base.exists():
        return out
    for memdir in base.glob("*/memory/MEMORY.md"):
        try:
            content = memdir.read_text(errors="replace")
            out.append((memdir, content))
        except OSError:
            continue
    return out


def _memory_topics(indexes: list[tuple[Path, str]]) -> set[str]:
    """Extract memory topics (the file slugs and titles from index lines)."""
    topics: set[str] = set()
    for path, content in indexes:
        for line in content.splitlines():
            # Index lines look like: - [Title](file.md) — one-line hook
            m = re.match(r"-\s*\[([^\]]+)\]\(([^)]+)\)", line)
            if not m:
                continue
            title, slug = m.group(1), m.group(2)
            topics.add(title.lower())
            topics.add(slug.lower().replace(".md", "").replace("_", " ").replace("-", " "))
    return topics


def cmd_memory_link(promote_threshold: int = 5, verbose: bool = False) -> None:
    """Cross-reference voice corpus with auto-memory:
      - Promotion candidates: signal labels that fire ≥N times across multiple
        projects but don't appear in any MEMORY.md index — implicit rules
        worth codifying explicitly.
      - Stale memory candidates: memory entries whose topic terms don't
        match any recent voice signal — possibly outdated.
    """
    if not RECALL_DB.exists():
        print("No DB.", file=sys.stderr)
        return
    indexes = _collect_memory_indexes()
    if not indexes:
        print("No MEMORY.md indexes found.", file=sys.stderr)
    memory_topics = _memory_topics(indexes)

    conn = db_connect()
    label_rows = conn.execute(
        """
        SELECT signal_type, label,
               COUNT(*) AS total,
               COUNT(DISTINCT project) AS proj_count,
               MAX(timestamp) AS last_seen
        FROM voice_signals
        WHERE timestamp != ''
        GROUP BY signal_type, label
        HAVING total >= ?
        ORDER BY total DESC
        """,
        (promote_threshold,),
    ).fetchall()

    print("# Poe ↔ MEMORY cross-link report")
    print()
    print(f"_Memory indexes scanned: {len(indexes)}_")
    print(f"_Memory topic terms: {len(memory_topics)}_")
    print()

    print(f"## Promotion candidates (labels firing ≥{promote_threshold}× without explicit memory)")
    print()
    print("_These are implicit rules. If you find one valuable, codify it as an explicit memory._")
    print()
    promo = []
    for stype, label, total, proj_count, last_seen in label_rows:
        # Generate fuzzy keys to test against memory topics.
        keys = {label.replace("-", " "), label.replace("_", " "), label}
        if any(k.lower() in memory_topics or
               any(k.lower() in t for t in memory_topics) for k in keys):
            continue
        # Require cross-project recurrence for promotion-worthiness.
        if proj_count < 2:
            continue
        promo.append((stype, label, total, proj_count, last_seen))
    for stype, label, total, proj_count, last_seen in promo[:20]:
        age = _signal_age_days(last_seen) or 0
        print(f"- `{stype}/{label}` — {total} signals across {proj_count} projects, last {int(age)}d ago")
    if not promo:
        print("- _(none — all recurring labels have memory coverage)_")
    print()

    # Stale memory: memories whose slug terms don't appear in any *recent* signal.
    print("## Memory entries with no recent voice reinforcement")
    print()
    print("_Memory topics that don't appear in voice signals from the last 90 days. May be stale; verify before relying on them._")
    print()
    recent_phrases = conn.execute(
        "SELECT phrase, message FROM voice_signals "
        "WHERE timestamp >= ? ",
        ((datetime.now(timezone.utc) - timedelta(days=90)).isoformat(),),
    ).fetchall()
    haystack = " ".join(
        (p or "").lower() + " " + (m or "").lower() for p, m in recent_phrases
    )
    stale = []
    for path, content in indexes:
        for line in content.splitlines():
            m = re.match(r"-\s*\[([^\]]+)\]\(([^)]+)\)\s*[—-]+\s*(.*)", line)
            if not m:
                continue
            title, slug, hook = m.group(1), m.group(2), m.group(3)
            slug_terms = [
                t for t in re.split(r"[_\-\s]+", slug.replace(".md", "").lower())
                if len(t) >= 4
            ]
            if not slug_terms:
                continue
            if not any(term in haystack for term in slug_terms):
                stale.append((title, slug, str(path.parent.parent.name)))
    for title, slug, proj in stale[:20]:
        print(f"- **{title}** (`{slug}`) — _{proj}_")
    if not stale:
        print("- _(none — every memory has recent voice reinforcement)_")
    print()

    conn.close()


def cmd_drift_labels(verbose: bool = False) -> None:
    """Report preference labels that haven't been reinforced lately.
    A 'drift candidate' is a label that:
      - has historical signals (≥3 total occurrences)
      - has not seen a new signal in 90+ days
    These may be stale rules to review or remove."""
    if not RECALL_DB.exists():
        print("No DB.", file=sys.stderr)
        return
    conn = db_connect()
    rows = conn.execute(
        """
        SELECT signal_type, label,
               COUNT(*) AS total,
               MAX(timestamp) AS last_seen
        FROM voice_signals
        WHERE timestamp != ''
        GROUP BY signal_type, label
        HAVING total >= 3
        ORDER BY last_seen ASC
        """
    ).fetchall()
    conn.close()
    if not rows:
        print("No drift data — corpus is empty or missing timestamps.", file=sys.stderr)
        return

    drift: list[tuple[str, str, int, float]] = []
    fresh: list[tuple[str, str, int, float]] = []
    for stype, label, total, last_seen in rows:
        age = _signal_age_days(last_seen)
        if age is None:
            continue
        if age >= 90:
            drift.append((stype, label, total, age))
        else:
            fresh.append((stype, label, total, age))

    print("# Poe label-drift report")
    print()
    print(f"_Labels with ≥3 historical signals, sorted by staleness._")
    print()
    print(f"## Drift candidates ({len(drift)})")
    print()
    print("_No reinforcement in 90+ days — review whether the rule still applies._")
    print()
    for stype, label, total, age in drift[:25]:
        print(f"- `{stype}/{label}` — {total} signals, last seen {int(age)}d ago")
    if not drift:
        print("- _(none — all active labels reinforced within 90 days)_")
    print()
    if verbose:
        print(f"## Active labels ({len(fresh)})")
        print()
        for stype, label, total, age in fresh[:20]:
            print(f"- `{stype}/{label}` — {total} signals, last seen {int(age)}d ago")
        print()


# --- Rule drift -------------------------------------------------------------
#
# A "rule" is a heading in a governing instruction doc. Reinforcement is
# evidence the rule is still live: a mechanical enforcer names it, Nino
# restated it in the corpus, or its section was edited recently.
#
# The demotion path this exists for: a promoted rule with no reinforcement is
# a candidate for removal. Without one, the instruction set only grows — and
# Codex truncates the merged AGENTS.md chain at 32 KiB. (2026-08-26: the 630
# browser-profile rules were BOTH superseded and nothing surfaced them.)

RULE_DOCS_DEFAULT = (
    "~/.dotfiles/ways-of-working/*.md",
    "~/.claude/CLAUDE.md",
    "~/.codex/AGENTS.md",
)

# Vague heading words that would match almost any transcript.
RULE_STOPWORDS = {
    "about", "after", "again", "against", "agent", "agents", "always", "another",
    "because", "before", "being", "below", "better", "between", "build", "check",
    "claim", "claude", "codex", "default", "defaults", "every", "first", "index",
    "instead", "learned", "level", "measured", "never", "notes", "other",
    "prefer", "reference", "rules", "second", "should", "small", "still", "their",
    "there", "these", "thing", "things", "third", "those", "under", "using",
    "verified", "watch", "where", "which", "while", "would", "write", "writing",
}

# Something that mechanically enforces a rule. A rule with one of these is
# alive whether or not anyone talks about it.
ENFORCER_RE = re.compile(r"`?([a-z][a-z0-9-]*(?:-guard|-reaper|-hook)\.py|[a-z][a-z0-9-]*\.py)`?")
IDENT_RE = re.compile(r"`([^`\n]{3,40})`")


def _rule_docs() -> list[Path]:
    """Governing docs to scan. Override with POE_RULE_DOCS (colon-separated)."""
    raw = os.environ.get("POE_RULE_DOCS")
    if raw:
        # An explicit override is exhaustive; do not silently widen it.
        globs = raw.split(":")
    else:
        globs = list(RULE_DOCS_DEFAULT)
        # A repo's own governing docs count when run inside one.
        root = _git_root(Path.cwd())
        for name in ("CLAUDE.md", "AGENTS.md"):
            if root and (root / name).exists():
                globs.append(str(root / name))
    import glob as _glob
    out: list[Path] = []
    seen: set[Path] = set()
    for g in globs:
        g = os.path.expanduser(g.strip())
        matches = [Path(m) for m in sorted(_glob.glob(g))] if "*" in g else [Path(g)]
        for m in matches:
            if not m.is_file():
                continue
            key = m.resolve()
            if key in seen:
                continue
            seen.add(key)
            out.append(m)
    return out


def _git_root(start: Path) -> Path | None:
    try:
        r = subprocess.run(
            ["git", "rev-parse", "--show-toplevel"],
            cwd=str(start), capture_output=True, text=True, timeout=4,
        )
        return Path(r.stdout.strip()) if r.returncode == 0 and r.stdout.strip() else None
    except Exception:
        return None


def _rule_sections(path: Path) -> list[dict]:
    """Split a doc into heading-delimited rules. One heading == one rule."""
    try:
        lines = path.read_text(errors="ignore").splitlines()
    except Exception:
        return []
    heads = [
        (i, len(m.group(1)), m.group(2).strip())
        for i, ln in enumerate(lines, 1)
        for m in [re.match(r"^(#{2,3})\s+(.*)", ln)]
        if m
    ]
    out = []
    for n, (start, level, title) in enumerate(heads):
        # A rule owns its sub-rules: run to the next heading at the same or a
        # higher level, not merely the next heading. Otherwise a `##` rule with
        # `###` children scores on its intro paragraph alone — which flagged
        # "Never fabricate Nino's interior state" as drift while its own
        # sub-rule was the most-reinforced section in the file.
        end = len(lines)
        for m in range(n + 1, len(heads)):
            if heads[m][1] <= level:
                end = heads[m][0] - 1
                break
        body = "\n".join(lines[start:end])
        out.append(
            {"doc": path, "title": title, "level": level,
             "start": start, "end": max(start, end), "body": body}
        )
    return out


def _rule_terms(rule: dict) -> list[str]:
    """Distinctive strings whose presence in the corpus means the rule was invoked.

    Backticked identifiers in the body are far better evidence than heading
    words — `browse-tool` or `op://` only appear when the rule is in play,
    while "discipline" appears everywhere.
    """
    terms: list[str] = []
    for ident in IDENT_RE.findall(rule["body"])[:60]:
        ident = ident.strip().lower()
        if not ident or ident.isdigit() or " " in ident:
            continue
        # Distinctive = looks like an identifier/path, or is simply long. A
        # bare `git` or `main` matches every transcript and proves nothing.
        if any(ch in ident for ch in "-._/:") or len(ident) >= 8:
            terms.append(ident)
    for w in re.findall(r"[a-zA-Z][a-zA-Z-]{6,}", rule["title"]):
        w = w.lower()
        if w not in RULE_STOPWORDS:
            terms.append(w)
    seen, uniq = set(), []
    for t in terms:
        if t not in seen:
            seen.add(t)
            uniq.append(t)
    return uniq[:25]


def _rule_enforcers(rule: dict) -> list[str]:
    hits = {m for m in ENFORCER_RE.findall(rule["body"])}
    return sorted(h for h in hits if h.endswith(".py"))


def _section_edit_age(rule: dict) -> float | None:
    """Days since these exact lines last changed. None if not in git."""
    doc = rule["doc"]
    root = _git_root(doc.parent)
    if not root:
        return None
    try:
        rel = doc.resolve().relative_to(root.resolve())
    except Exception:
        return None
    try:
        r = subprocess.run(
            ["git", "log", "-n1", "--format=%cI", "-s",
             "-L", f"{rule['start']},{rule['end']}:{rel}"],
            cwd=str(root), capture_output=True, text=True, timeout=10,
        )
        stamp = r.stdout.strip().splitlines()[0] if r.stdout.strip() else ""
    except Exception:
        return None
    return _signal_age_days(stamp) if stamp else None


def cmd_drift(days: int = 90, verbose: bool = False, as_json: bool = False) -> None:
    """Report rules in the governing docs with no recent reinforcement.

    A rule is alive if a hook enforces it, if Nino restated it in the corpus
    within the window, or if its section was edited within the window.
    Everything else is a demotion candidate."""
    docs = _rule_docs()
    if not docs:
        print("No rule docs found. Set POE_RULE_DOCS.", file=sys.stderr)
        return
    haystack = ""
    if RECALL_DB.exists():
        conn = db_connect()
        since = (datetime.now(timezone.utc) - timedelta(days=days)).isoformat()
        rows = conn.execute(
            "SELECT phrase, message FROM voice_signals WHERE timestamp >= ?", (since,)
        ).fetchall()
        conn.close()
        haystack = " ".join(
            (p or "").lower() + " " + (m or "").lower() for p, m in rows
        )

    results = []
    for doc in docs:
        for rule in _rule_sections(doc):
            terms = _rule_terms(rule)
            enforcers = _rule_enforcers(rule)
            matched = [t for t in terms if len(t) >= 5 and t in haystack][:3] if haystack else []
            edit_age = _section_edit_age(rule)
            if enforcers:
                verdict = "enforced"
            elif matched:
                verdict = "reinforced"
            elif len(terms) < 2:
                # One generic term is not enough to call a rule dead. "## Preferences"
                # scores on the word "preferences" alone; absence of that word proves
                # nothing. Unscorable is the honest verdict, and it names its own fix:
                # reword the rule so it contains something distinctive.
                verdict = "unscorable"
            elif edit_age is not None and edit_age <= days:
                verdict = "unproven"
            else:
                verdict = "drift"
            results.append({
                "doc": str(doc).replace(str(Path.home()), "~"),
                "rule": rule["title"],
                "lines": f"{rule['start']}-{rule['end']}",
                "verdict": verdict,
                "enforcers": enforcers,
                "matched_terms": matched,
                "edit_age_days": None if edit_age is None else int(edit_age),
            })

    if as_json:
        print(json.dumps({"window_days": days, "rules": results}, indent=2))
        return

    by = defaultdict(list)
    for r in results:
        by[r["verdict"]].append(r)
    drift = sorted(by["drift"], key=lambda r: -(r["edit_age_days"] or 0))

    print("# Rule drift report")
    print()
    print(f"_{len(results)} rules across {len(docs)} governing docs. "
          f"Reinforcement window: {days} days._")
    print()
    print(f"| verdict | count | meaning |")
    print(f"|---|---|---|")
    print(f"| enforced | {len(by['enforced'])} | a hook enforces it; alive regardless of talk |")
    print(f"| reinforced | {len(by['reinforced'])} | its terms appear in the corpus this window |")
    print(f"| unproven | {len(by['unproven'])} | edited recently, not yet reinforced |")
    print(f"| drift | {len(drift)} | **demotion candidates** |")
    print(f"| unscorable | {len(by['unscorable'])} | too generically worded to track — reword or accept |")
    print()
    print(f"## Demotion candidates ({len(drift)})")
    print()
    print("_No enforcer, no mention in the window, no recent edit. "
          "Verify at the source before removing — a quiet rule may still be true._")
    print()
    for r in drift[:30]:
        age = f"{r['edit_age_days']}d" if r["edit_age_days"] is not None else "untracked"
        print(f"- **{r['rule']}** — `{r['doc']}:{r['lines']}`, last edited {age}")
    if not drift:
        print("- _(none)_")
    print()
    if verbose:
        for name in ("unproven", "reinforced", "enforced"):
            print(f"## {name.capitalize()} ({len(by[name])})")
            print()
            for r in by[name][:25]:
                ev = ", ".join(r["enforcers"] or r["matched_terms"]) or "-"
                print(f"- {r['rule']} — `{ev}`")
            print()


def _render_validated_section() -> list[str]:
    """Render a 'response shapes Nino tolerated' section using the
    validated_responses corpus. Highlights:
      - distribution of response sizes that didn't draw correction
      - shape signatures with the highest pass rate
    Read directly from DB to keep the assemble path linear."""
    if not RECALL_DB.exists():
        return []
    conn = sqlite3.connect(str(RECALL_DB))
    try:
        total = conn.execute("SELECT COUNT(*) FROM validated_responses").fetchone()[0]
    except sqlite3.OperationalError:
        conn.close()
        return []
    if total == 0:
        conn.close()
        return []

    size_rows = conn.execute(
        """
        SELECT substr(shape_signature, 1, instr(shape_signature, '/') - 1) AS bucket,
               COUNT(*) c
        FROM validated_responses
        GROUP BY bucket
        ORDER BY c DESC
        """
    ).fetchall()
    follow_rows = conn.execute(
        "SELECT follow_label, COUNT(*) FROM validated_responses GROUP BY follow_label ORDER BY 2 DESC"
    ).fetchall()
    top_shapes = conn.execute(
        """
        SELECT shape_signature, COUNT(*) c
        FROM validated_responses
        GROUP BY shape_signature
        ORDER BY c DESC
        LIMIT 4
        """
    ).fetchall()
    # Pull one short exemplar per top shape for human readability.
    exemplars: list[tuple[str, str, int]] = []
    for sig, _ in top_shapes:
        row = conn.execute(
            "SELECT response_text, response_chars FROM validated_responses "
            "WHERE shape_signature = ? ORDER BY response_chars ASC LIMIT 1",
            (sig,),
        ).fetchone()
        if row:
            exemplars.append((sig, row[0], row[1]))
    conn.close()

    lines = []
    lines.append("## Tolerated response shapes (reverse Poe)")
    lines.append("")
    lines.append(
        "_Mined from assistant turns Nino did NOT correct. These are response "
        "structures that survived contact — Claude can mirror them without "
        "triggering a pushback. Inverse of the Red Lines section: those say "
        "what fails, these say what works._"
    )
    lines.append("")
    lines.append(f"- **Validated turns**: {total}")
    if size_rows:
        size_summary = ", ".join(f"{bucket}={c}" for bucket, c in size_rows)
        lines.append(f"- **Size distribution**: {size_summary} _(xs<200ch, s<600, m<1500, l<4000, xl≥4000)_")
    if follow_rows:
        follow_summary = ", ".join(f"{(l or 'neutral')}={c}" for l, c in follow_rows)
        lines.append(f"- **Follow-up classification**: {follow_summary}")
    lines.append("")
    if exemplars:
        lines.append("### Most common shape signatures")
        lines.append("")
        lines.append("_Signature legend: `size/sentence-bucket/ends-with-Q-or-period + L=list + C=code`_")
        lines.append("")
        for sig, text, chars in exemplars:
            preview = re.sub(r"\s+", " ", text[:160]).strip()
            if len(text) > 160:
                preview += "…"
            lines.append(f"- **`{sig}`** ({chars} chars): \"{preview}\"")
        lines.append("")
    return lines


def _render_tone_section(stats: dict) -> list[str]:
    """Return markdown lines for the tone card section of stack.md."""
    if not stats:
        return []
    lines = []
    lines.append("## Tone fingerprint")
    lines.append("")
    lines.append(
        "_The canonical tone card lives in `~/.dotfiles/ways-of-working/voice.md` "
        "(recalibrated 2026-08-03 over 3,850 decontaminated hand-typed messages). "
        "On any conflict, that card wins._"
    )
    lines.append("")
    lines.append(
        "_The numbers below are computed over signal-bearing messages only — "
        "messages that fired a correction/hedge/preference regex — so hedge and "
        "question rates run high by construction. Treat them as corpus "
        "diagnostics, not cadence targets._"
    )
    lines.append("")
    lines.append(f"- **Corpus**: {stats['messages']} user messages, {stats['sentences']} sentences")
    lines.append(f"- **Median sentence length**: {stats['median_sentence_words']} words (p90: {stats['p90_sentence_words']})")
    lines.append(f"- **Hedge rate**: {stats['hedge_rate_pct']}% of messages contain hedge words (\"maybe\", \"might\", \"I think\")")
    lines.append(f"- **Cheerleading rate**: {stats['cheerlead_rate_pct']}% contain praise words (\"great\", \"awesome\", \"perfect\")")
    lines.append(f"- **Profanity rate**: {stats['profanity_rate_pct']}%")
    lines.append(f"- **Question rate**: {stats['question_rate_pct']}% of sentences end with '?'")
    lines.append(f"- **Imperative-opener rate**: {stats['imperative_start_rate_pct']}% of sentences start with a bare verb")
    lines.append(f"- **Lowercase-first-letter rate**: {stats['lowercase_start_rate_pct']}% (informal/typing-style)")
    if stats["top_imperative_openers"]:
        top = ", ".join(f"`{v}` ({c})" for v, c in stats["top_imperative_openers"][:8])
        lines.append(f"- **Top imperative verbs**: {top}")
    lines.append("")
    lines.append("**Style implications when responding as Poe:**")
    lines.append("- Sentences average ~8–12 words; cap at 25 unless quoting (his p90 is 20).")
    lines.append("- No \"I think\" / \"perhaps\" / \"maybe\" — assert or qualify with a concrete reason.")
    lines.append("- No \"great\" / \"perfect\" / \"absolutely\" — replace with neutral evaluation.")
    lines.append("- Start instructions with the verb, not the subject.")
    lines.append("")
    return lines


def cmd_hook_stats(days: int = 7) -> None:
    """Summarize hook.log over the last N days. Reports fire rate, situation
    distribution, top surfaced signals, and silent-rate."""
    if not HOOK_LOG_PATH.exists():
        print(f"No hook log at {HOOK_LOG_PATH} yet.", file=sys.stderr)
        return
    cutoff = datetime.now(timezone.utc) - timedelta(days=days)
    total = 0
    emitted = 0
    intent_counts: Counter = Counter()
    situation_counts: Counter = Counter()
    signal_counts: Counter = Counter()
    with open(HOOK_LOG_PATH, "r", errors="replace") as f:
        for line in f:
            try:
                entry = json.loads(line)
            except json.JSONDecodeError:
                continue
            try:
                ts = datetime.fromisoformat(entry["ts"])
            except (KeyError, ValueError):
                continue
            if ts < cutoff:
                continue
            total += 1
            if entry.get("emitted"):
                emitted += 1
            for i in entry.get("intents", []):
                intent_counts[i] += 1
            for s in entry.get("situations", []):
                situation_counts[s] += 1
            for sig in entry.get("signals", []):
                signal_counts[sig] += 1
    if total == 0:
        print(f"No hook activity in the last {days} days.", file=sys.stderr)
        return
    print(f"# Poe hook stats — last {days} days")
    print()
    print(f"- **Total invocations**: {total}")
    print(f"- **Emitted context**: {emitted} ({round(100*emitted/total,1)}%)")
    print(f"- **Silent (no signal)**: {total - emitted} ({round(100*(total-emitted)/total,1)}%)")
    print()
    if intent_counts:
        print("## Prompt intents detected")
        print()
        for intent, count in intent_counts.most_common():
            print(f"- `{intent}` — {count}")
        print()
    if situation_counts:
        print("## Situations detected (in-draft patterns)")
        print()
        for sit, count in situation_counts.most_common():
            print(f"- `{sit}` — {count}")
        print()
    if signal_counts:
        print("## Top surfaced signals")
        print()
        for sig, count in signal_counts.most_common(15):
            print(f"- `{sig}` — {count}")
        print()


# Retrieval bar. The hook's contract is "silence is the default — noise on every
# prompt is worse than no hook at all", but measured emission was 99.2% over
# 1244 invocations (30d to 2026-07-24). Two causes, both fixed below:
#   1. The FTS index covers `message` — the whole user turn, up to 4000 chars —
#      so one token landing anywhere inside a long paste surfaced the signal.
#      Matching is now scoped to `phrase`, the extracted sentence itself.
#   2. The query was OR across tokens, so a single common word was enough.
#      A candidate must now share MIN_TOKEN_OVERLAP distinct prompt tokens with
#      the phrase (or one long, specific token), and clear a bm25 floor.
# Overlap is checked on word-prefixes because the FTS tokenizer is porter-stemmed
# ("retrieval" must still count against "retrieve").
# Threshold picked by replaying 3639 real prompts from hook.log, not guessed.
# Emission: overlap>=3 -> 34.4%, >=4 -> 6.7%, >=5 -> 1.3%. Four is the knee.
# At 3 the survivors are word coincidence ("migrating our backend to TypeScript"
# pulled up "bc migraiton is out"); at 4 they're on topic ("urvil wants me to add
# stripe" pulled up "defer stripe config for now").
#
# Deliberately NOT thresholding on bm25. bm25 scores depend on corpus-wide IDF,
# so any absolute floor tuned against this 650-signal corpus would mute a fresh
# or small one entirely — it broke the in-memory test DB immediately. Token
# overlap is corpus-size independent and does the semantic work anyway.
#
# Consequence worth knowing: a prompt with fewer than MIN_TOKEN_OVERLAP content
# words can never surface a prior. That is intended — short prompts carry too
# little topic to match on.
MIN_TOKEN_OVERLAP = 4
OVERLAP_PREFIX = 6          # word-prefix length; FTS is porter-stemmed
NEAR_DUP_RATIO = 0.75       # candidate is ~the prompt restated: no information


def _phrase_overlap(phrase: str, tokens: list[str]) -> int:
    """Count distinct prompt tokens appearing as word-prefixes in the phrase."""
    words = [w for w in re.split(r"\W+", phrase.lower()) if w]
    return sum(
        1 for t in tokens
        if any(w.startswith(t[:OVERLAP_PREFIX]) for w in words)
    )


def _is_near_duplicate(phrase: str, prompt: str) -> bool:
    """True when the candidate is essentially the prompt said again.

    A prior that restates what Nino just typed carries no information — it
    reads as insight but is an echo. Word-set containment rather than string
    similarity, so reordering and light edits still count as the same thing.
    """
    a = {w for w in re.split(r"\W+", phrase.lower()) if len(w) >= 4}
    b = {w for w in re.split(r"\W+", prompt.lower()) if len(w) >= 4}
    if not a or not b:
        return False
    return len(a & b) / min(len(a), len(b)) >= NEAR_DUP_RATIO


def _relevant_signals(
    conn: sqlite3.Connection,
    tokens: list[str],
    floor_iso: str,
    current_session: str,
    limit: int = 4,
    prompt: str = "",
) -> list[tuple]:
    """FTS-match prompt tokens against SETTLED voice signals, deduped by label.

    Two guards keep one session's live context from leaking into another's as a
    "prior" (the 2026-05-29 cross-session-leak class):
      - recency floor: skip signals whose timestamp is newer than floor_iso, so
        a fresh message from a concurrent in-flight session is never surfaced;
      - self-echo: skip signals from current_session.
    Timestamps are compared on their first 19 chars (YYYY-MM-DDTHH:MM:SS) so the
    UTC 'Z' suffix doesn't break lexical ordering. Dedupe by label so a
    high-volume label (e.g. 'instead') can't dominate the top-K.

    Relevance bar: see MIN_TOKEN_OVERLAP above. A candidate that merely matched
    the FTS query is not enough — it has to actually be about the same thing.
    """
    if not tokens:
        return []
    # Scope the match to `phrase`; `message` carries pasted content and is noise.
    fts_query = "phrase : (" + " OR ".join(tokens[:5]) + ")"
    try:
        rows = conn.execute(
            """
            SELECT v.signal_type, v.label, v.phrase, v.project,
                   bm25(voice_signals_fts) AS score
            FROM voice_signals_fts f
            JOIN voice_signals v ON v.id = f.rowid
            WHERE voice_signals_fts MATCH ?
              AND v.signal_type IN ('correction', 'preference', 'rejection')
              AND (v.timestamp = '' OR substr(v.timestamp, 1, 19) < ?)
              AND v.session_id != ?
            ORDER BY score
            LIMIT 50
            """,
            (fts_query, floor_iso, current_session),
        ).fetchall()
    except sqlite3.OperationalError:
        return []

    scored = []
    for stype, label, phrase, project, _score in rows:
        if "[Image #" in phrase:
            continue
        if _phrase_overlap(phrase, tokens) < MIN_TOKEN_OVERLAP:
            continue
        if prompt and _is_near_duplicate(phrase, prompt):
            continue
        scored.append((stype, label, phrase, project))
    rows = scored
    out: list[tuple] = []
    seen_labels: set[str] = set()
    for row in rows:
        label = row[1]
        if label in seen_labels:
            continue
        seen_labels.add(label)
        out.append(row)
        if len(out) >= limit:
            break
    return out


def cmd_prompt_hook() -> None:
    """UserPromptSubmit hook entry point. Reads Claude Code hook JSON from
    stdin, surfaces a compact Poe context block on stdout that gets injected
    into the assistant's view of the prompt. Must be fast (<200ms typical)
    since it runs on every user prompt.

    Design: only emit output when there's a load-bearing signal. Silence is
    the default — noise on every prompt is worse than no hook at all."""
    try:
        payload = json.load(sys.stdin)
    except (json.JSONDecodeError, ValueError):
        return
    prompt = payload.get("prompt") or payload.get("user_message") or ""
    if not prompt or len(prompt) < 20:
        return
    # Agent-generated prompts (task notifications, teammate messages) are not
    # Nino's voice — don't classify, retrieve, or log them. Same catalog the
    # bulk extractor uses, so both ingestion paths stay in sync.
    if prompt.lstrip().startswith(NOISE_PREFIXES):
        return

    # Prompt-intent classification predicts elicitation shapes; situation
    # classification catches drafts containing failure patterns directly
    # (rare in user prompts, but cheap to also check).
    prompt_intents = classify_prompt_intent(prompt)
    situations = classify_situation(prompt)

    # Topic-driven retrieval: extract content words from the prompt, query Poe.
    tokens = [
        t for t in re.split(r"\W+", prompt.lower())
        if len(t) >= 4 and t not in {
            "this", "that", "with", "from", "have", "will", "would", "should",
            "could", "what", "when", "where", "which", "their", "these", "those",
            "into", "about", "your", "mine", "they", "them", "than", "then",
            "explain", "review", "build", "design", "create", "make", "step",
        }
    ][:8]

    relevant_signals: list[tuple] = []
    if RECALL_DB.exists() and tokens:
        # Settled-history-only: exclude signals newer than the recency floor (so a
        # live instruction from a concurrent in-flight session can't surface as a
        # "prior") and exclude this session's own signals (self-echo).
        floor_iso = (
            datetime.now(timezone.utc) - timedelta(hours=PRIOR_RECENCY_FLOOR_HOURS)
        ).strftime("%Y-%m-%dT%H:%M:%S")
        current_session = payload.get("session_id") or ""
        try:
            conn = sqlite3.connect(str(RECALL_DB))
            relevant_signals = _relevant_signals(
                conn, tokens, floor_iso, current_session, prompt=prompt
            )
            conn.close()
        except sqlite3.OperationalError:
            relevant_signals = []

    has_output = bool(prompt_intents or situations or relevant_signals)

    # Telemetry: one JSONL line per invocation.
    try:
        POE_DIR.mkdir(parents=True, exist_ok=True)
        with open(HOOK_LOG_PATH, "a") as logf:
            entry = {
                "ts": datetime.now(timezone.utc).isoformat(timespec="seconds"),
                "prompt_chars": len(prompt),
                "prompt_head": redact_secrets(prompt[:120].replace("\n", " ")),
                "intents": [i[0] for i in prompt_intents],
                "situations": [s[0] for s in situations],
                "signals": [f"{r[0]}/{r[1]}" for r in relevant_signals],
                "emitted": has_output,
            }
            logf.write(json.dumps(entry, ensure_ascii=False) + "\n")
    except OSError:
        pass

    if not has_output:
        return

    out: list[str] = []
    out.append("<poe-context>")
    if prompt_intents:
        out.append("Failure modes this prompt is likely to elicit:")
        for intent_id, _ in prompt_intents:
            out.append(f"- `{intent_id}` — {PROMPT_GUIDANCE.get(intent_id, '')}")
    if situations:
        if prompt_intents:
            out.append("")
        out.append("Anticipated Poe situations from prompt shape:")
        for sit_id, _ in situations:
            out.append(f"- `{sit_id}` — {SITUATION_GUIDANCE.get(sit_id, '').splitlines()[0]}")
    if relevant_signals:
        out.append("")
        out.append("Relevant past Nino signals (treat as priors, not commands):")
        for stype, label, phrase, project in relevant_signals:
            # Belt-and-braces: ingest redaction covers new rows, but rows
            # written before it existed are still in the DB on other machines.
            phrase_clean = redact_secrets(re.sub(r"\s+", " ", phrase).strip())[:180]
            proj = (project or "?").split("/")[-1]
            out.append(f"- [{stype}/{label}] \"{phrase_clean}\" _{proj}_")
        # Keyword-matched priors carry no situational fit. The 2026-07-20
        # A/B probe showed a "push for north star features" prior landing on
        # a restraint-shaped question and tilting the response toward a
        # fleet-wide rewrite the evidence didn't support.
        out.append(
            "Caution: these are keyword-matched, not situation-matched. "
            "Discard any prior that rewards scale, rebuilds, or new scope when "
            "the actual question is whether to hold back, compare candidates, "
            "or use an existing smaller mechanism."
        )
    out.append("</poe-context>")
    print("\n".join(out))


def cmd_enqueue() -> None:
    """Read Claude Code hook stdin JSON, append transcript_path to queue.

    Designed to be the SessionEnd hook command. Must be cheap (<50ms):
    no DB connection, no scanning, no Python import of sqlite. The
    launchd worker drains the queue out-of-band."""
    POE_DIR.mkdir(parents=True, exist_ok=True)
    try:
        payload = json.load(sys.stdin)
    except (json.JSONDecodeError, ValueError):
        return  # malformed stdin → silent no-op; catchup will pick it up later
    path = payload.get("transcript_path") or payload.get("session_file") or ""
    if not path:
        return
    source_client = payload.get("source_client")
    if not source_client:
        if "/.codex/" in str(path):
            source_client = "codex"
        elif "/.gemini/" in str(path):
            source_client = "gemini"
        else:
            source_client = "claude"
    entry = {
        "source_client": source_client,
        "session_id": payload.get("session_id") or "",
        "transcript_path": str(path).strip(),
        "cwd": payload.get("cwd") or "",
    }
    with open(QUEUE_PATH, "a") as f:
        f.write(json.dumps(entry, separators=(",", ":")) + "\n")


def _maybe_opportunistic_catchup() -> None:
    """Called from query/assemble. Runs catchup if watermark is stale."""
    if not RECALL_DB.exists():
        cmd_catchup(verbose=False)
        return
    conn = sqlite3.connect(str(RECALL_DB))
    try:
        last = conn.execute(
            "SELECT value FROM ingest_meta WHERE key = 'last_catchup'"
        ).fetchone()
    except sqlite3.OperationalError:
        last = None
    conn.close()
    if not last:
        cmd_catchup(verbose=False)
        return
    try:
        last_dt = datetime.fromisoformat(last[0])
        age = (datetime.now(timezone.utc) - last_dt).total_seconds()
    except ValueError:
        age = float("inf")
    if age > READ_PATH_STALE_SECONDS:
        cmd_catchup(verbose=False)


def cmd_extract(limit: int | None, since_days: int | None, session: str | None) -> None:
    POE_DIR.mkdir(parents=True, exist_ok=True)

    # Single-session mode: parse one JSONL, upsert to DB, advance watermark.
    # `session is not None` is the gate — empty string is an explicit error,
    # not a fall-through to expensive full-rebuild.
    if session is not None:
        if not session.strip():
            print(
                "extract --session given empty path. Use 'catchup' for a full sweep "
                "or pass a real transcript path.",
                file=sys.stderr,
            )
            sys.exit(2)
        jf = Path(session).expanduser().resolve()
        if not jf.exists():
            print(f"Session file not found: {jf}", file=sys.stderr)
            sys.exit(1)
        conn = db_connect()
        signals, inserted = _ingest_file(conn, jf)
        conn.close()
        print(
            f"Session {jf.stem}: {signals} mined records, {inserted} new "
            "(watermark advanced)",
            file=sys.stderr,
        )
        return

    cutoff = None
    if since_days is not None:
        cutoff = datetime.now(tz=timezone.utc) - timedelta(days=since_days)

    files = []
    for proj_dir in sorted(PROJECTS_DIR.iterdir()):
        if not proj_dir.is_dir():
            continue
        for jf in proj_dir.glob("*.jsonl"):
            if cutoff:
                mtime = datetime.fromtimestamp(jf.stat().st_mtime, tz=timezone.utc)
                if mtime < cutoff:
                    continue
            files.append(jf)

    if limit:
        files = files[:limit]

    stats = Counter()
    written = 0

    with open(CORPUS_PATH, "w") as out:
        for i, jf in enumerate(files, 1):
            if i % 200 == 0:
                print(f"  [{i}/{len(files)}] scanned, {written} signals...", file=sys.stderr)

            stats["files_scanned"] += 1
            records = _extract_from_file(jf)
            for rec in records:
                out.write(json.dumps(rec, ensure_ascii=False) + "\n")
                stats[f"signal:{rec['signal']}"] += 1
                written += 1
            stats["messages_scanned"] += 0  # message stats collapsed into records path

    print(f"\nExtraction complete:", file=sys.stderr)
    print(f"  files scanned:    {stats['files_scanned']}", file=sys.stderr)
    print(f"  signals written:  {written}", file=sys.stderr)
    for k in sorted(stats):
        if k.startswith("signal:"):
            print(f"    {k[7:]:12} {stats[k]}", file=sys.stderr)
    print(f"  corpus: {CORPUS_PATH}", file=sys.stderr)


def cmd_publish() -> None:
    """Load corpus.jsonl into the DB."""
    if not CORPUS_PATH.exists():
        print(f"No corpus at {CORPUS_PATH} — run extract first.", file=sys.stderr)
        sys.exit(1)
    records: list[dict] = []
    with open(CORPUS_PATH) as f:
        for line in f:
            try:
                records.append(json.loads(line))
            except json.JSONDecodeError:
                continue
    conn = db_connect()
    inserted = _upsert_signals(conn, records)
    total = conn.execute("SELECT COUNT(*) FROM voice_signals").fetchone()[0]
    conn.close()
    print(
        f"Published: {len(records)} records, {inserted} new inserts, {total} total in DB",
        file=sys.stderr,
    )


def cmd_init() -> None:
    conn = db_connect()
    count = conn.execute("SELECT COUNT(*) FROM voice_signals").fetchone()[0]
    conn.close()
    print(f"Schema ready at {RECALL_DB} — voice_signals has {count} rows", file=sys.stderr)


def _resolve_project_filter(spec: str) -> str | None:
    """Translate --project value into a SQL LIKE pattern (None if no filter).
    'auto' resolves the current shell cwd. Anything else is matched as a
    case-insensitive suffix on the stored project label."""
    if not spec:
        return None
    if spec.lower() == "auto":
        cwd = str(Path.cwd())
        label = _cwd_to_label(cwd)
        # Match anywhere within the path so /Users/nino/Workspace/dev/wip/foo
        # matches both 'wip/foo' and 'wip/foo/subdir' rows.
        return f"%{label}%"
    return f"%{spec}%"


def cmd_query(terms: list[str], limit: int, project: str | None = None) -> None:
    """FTS5 search voice_signals, emit markdown block ready to paste."""
    _maybe_opportunistic_catchup()
    if not RECALL_DB.exists():
        print(f"No DB at {RECALL_DB} — run publish first.", file=sys.stderr)
        sys.exit(1)
    conn = db_connect()
    raw_query = " ".join(terms).strip()
    if not raw_query:
        print("Query terms required.", file=sys.stderr)
        sys.exit(1)

    # Build an FTS5 expression: tokenize on non-alphanumeric, drop short stops,
    # OR them together. Porter tokenizer handles morphological variation
    # (engineering ↔ engineered ↔ engineer) at index AND query time, so no
    # prefix-asterisk needed — and asterisk would actually bypass stemming.
    tokens = [t for t in re.split(r"\W+", raw_query.lower()) if len(t) >= 3]
    if tokens:
        query = " OR ".join(tokens)
    else:
        # Single short token (e.g. "go") — pass as-is.
        query = raw_query

    proj_filter = _resolve_project_filter(project)

    # FTS5 MATCH with phrase-first ranking
    try:
        if proj_filter:
            rows = conn.execute(
                """
                SELECT v.signal_type, v.label, v.phrase, v.project, v.session_id, v.timestamp, v.prior_assistant
                FROM voice_signals_fts f
                JOIN voice_signals v ON v.id = f.rowid
                WHERE voice_signals_fts MATCH ? AND v.project LIKE ?
                ORDER BY rank
                LIMIT ?
                """,
                (query, proj_filter, limit),
            ).fetchall()
        else:
            rows = conn.execute(
                """
                SELECT v.signal_type, v.label, v.phrase, v.project, v.session_id, v.timestamp, v.prior_assistant
                FROM voice_signals_fts f
                JOIN voice_signals v ON v.id = f.rowid
                WHERE voice_signals_fts MATCH ?
                ORDER BY rank
                LIMIT ?
                """,
                (query, limit),
            ).fetchall()
    except sqlite3.OperationalError:
        # Fall back to LIKE if FTS5 syntax rejects the query
        like = f"%{raw_query}%"
        if proj_filter:
            rows = conn.execute(
                """
                SELECT signal_type, label, phrase, project, session_id, timestamp, prior_assistant
                FROM voice_signals
                WHERE (phrase LIKE ? OR message LIKE ?) AND project LIKE ?
                ORDER BY created_at DESC
                LIMIT ?
                """,
                (like, like, proj_filter, limit),
            ).fetchall()
        else:
            rows = conn.execute(
                """
                SELECT signal_type, label, phrase, project, session_id, timestamp, prior_assistant
                FROM voice_signals
                WHERE phrase LIKE ? OR message LIKE ?
                ORDER BY created_at DESC
                LIMIT ?
                """,
                (like, like, limit),
            ).fetchall()

    conn.close()

    if not rows:
        print(f"No matches for: {raw_query}", file=sys.stderr)
        return

    # Header uses the raw query, not the FTS-encoded form.
    query = raw_query

    by_type: dict[str, list[tuple]] = defaultdict(list)
    for r in rows:
        by_type[r[0]].append(r)

    print(f"# Poe on: {query}")
    print()
    print(f"_{len(rows)} matching signals from Nino's past sessions._")
    print()
    type_order = ["correction", "preference", "rationale", "rejection", "declaration", "approval"]
    headers = {
        "correction": "## Corrections (what Nino pushed back on)",
        "preference": "## Preferences (stated rules)",
        "rationale": "## Rationale (reasoning given)",
        "rejection": "## Alternatives (what Nino picked instead)",
        "declaration": "## Imperatives",
        "approval": "## Validated calls",
    }
    for t in type_order:
        if t not in by_type:
            continue
        print(headers[t])
        print()
        for stype, label, phrase, project, session_id, ts, prior in by_type[t]:
            phrase_clean = re.sub(r"\s+", " ", phrase).strip()
            proj_short = (project or "?").split("/")[-1] if project else "?"
            if label == "redirect-go" and prior:
                tail = re.sub(r"\s+", " ", prior).strip()[-200:]
                print(f"- Claude: \"…{tail}\" → Nino: **\"{phrase_clean}\"** _({proj_short})_")
            else:
                print(f"- \"{phrase_clean}\" _({proj_short}, `{label}`)_")
        print()


def cmd_assemble(_skip_catchup: bool = False) -> None:
    if not _skip_catchup:
        _maybe_opportunistic_catchup()
    by_signal: dict[str, list[dict]] = defaultdict(list)
    by_signal_label: dict[tuple[str, str], list[dict]] = defaultdict(list)
    projects = Counter()

    # Prefer DB as source of truth; fall back to corpus.jsonl
    if RECALL_DB.exists():
        conn = db_connect()
        db_count = conn.execute("SELECT COUNT(*) FROM voice_signals").fetchone()[0]
    else:
        db_count = 0
        conn = None

    tone_messages: list[str] = []
    if db_count > 0 and conn is not None:
        rows = conn.execute(
            "SELECT signal_type, label, phrase, project, prior_assistant, timestamp FROM voice_signals"
        ).fetchall()
        # Pull a deduped sample of raw messages for tone stats.
        msg_rows = conn.execute(
            "SELECT DISTINCT message FROM voice_signals WHERE message IS NOT NULL AND length(message) > 10"
        ).fetchall()
        tone_messages = [m[0] for m in msg_rows]
        conn.close()
        for stype, label, phrase, project, prior, ts in rows:
            age = _signal_age_days(ts)
            rec = {
                "signal": stype, "label": label, "phrase": phrase,
                "project": project or "?", "prior_assistant": prior or "",
                "age_days": age, "weight": _decay_weight(age),
            }
            by_signal[stype].append(rec)
            by_signal_label[(stype, label)].append(rec)
            projects[rec["project"]] += 1
    else:
        if conn is not None:
            conn.close()
        if not CORPUS_PATH.exists():
            print(f"No DB rows and no corpus at {CORPUS_PATH} — run extract first.", file=sys.stderr)
            sys.exit(1)
        with open(CORPUS_PATH) as f:
            for line in f:
                try:
                    rec = json.loads(line)
                except json.JSONDecodeError:
                    continue
                by_signal[rec["signal"]].append(rec)
                by_signal_label[(rec["signal"], rec["label"])].append(rec)
                projects[rec.get("project", "?")] += 1

    total = sum(len(v) for v in by_signal.values())

    def dedupe_by_phrase(recs: list[dict], limit: int = 20) -> list[dict]:
        """Keep one rep per near-duplicate phrase. Sort by recency weight so
        the freshest exemplar wins when duplicates exist."""
        recs_sorted = sorted(recs, key=lambda r: r.get("weight", 0.5), reverse=True)
        seen: set[str] = set()
        out = []
        for r in recs_sorted:
            key = re.sub(r"\s+", " ", r["phrase"].lower()).strip()[:120]
            if key in seen:
                continue
            seen.add(key)
            out.append(r)
            if len(out) >= limit:
                break
        return out

    lines: list[str] = []
    lines.append("# Poe — A Serialized Nino")
    lines.append("")
    lines.append(
        "A character stack extracted from prior Claude Code sessions. Load this as "
        "system-prompt context when you want the assistant to vet ideas the way Nino "
        "would — with the same red lines, rationale, and taste."
    )
    lines.append("")
    lines.append(f"- **Corpus size**: {total} signals across {len(projects)} projects")
    lines.append(f"- **Generated**: {datetime.now(timezone.utc).isoformat(timespec='seconds')}")
    lines.append("")

    tone_stats = _tone_stats(tone_messages)
    lines.extend(_render_tone_section(tone_stats))
    lines.extend(_render_validated_section())

    section_order = [
        ("correction", "## Red lines — what Nino rejects", "These are patterns where Nino pushed back, corrected, or called something wrong. Treat them as non-negotiables unless the context clearly differs."),
        ("preference", "## Rules — how Nino wants things done", "Explicit conventions Nino has declared. Follow them by default."),
        ("rationale", "## Rationale — the 'because' behind decisions", "Reasons Nino has given for choices. Use these to explain trade-offs the way Nino would."),
        ("rejection", "## Alternatives — what Nino picks instead", "When Nino rejects an approach, these show what he reaches for instead."),
        ("declaration", "## Imperatives — first-move instructions", "Common opening rules Nino issues at the start of a task."),
    ]

    for stype, header, blurb in section_order:
        recs = by_signal.get(stype, [])
        if not recs:
            continue
        lines.append(header)
        lines.append("")
        lines.append(f"_{blurb}_")
        lines.append("")
        lines.append(f"**Signal count**: {len(recs)}")
        lines.append("")

        # Group by label, rank by recency-weighted score so old stale labels
        # sink below freshly-reinforced ones even at similar raw counts.
        label_scores: dict[str, tuple[float, int]] = {}
        for r in recs:
            cur = label_scores.get(r["label"], (0.0, 0))
            label_scores[r["label"]] = (cur[0] + r.get("weight", 0.5), cur[1] + 1)
        for label, (score, count) in sorted(
            label_scores.items(), key=lambda kv: kv[1][0], reverse=True
        ):
            label_recs = by_signal_label[(stype, label)]
            reps = dedupe_by_phrase(label_recs, limit=3)
            lines.append(f"### `{label}` ({count} occurrences, weight {score:.1f})")
            lines.append("")
            for r in reps:
                phrase = re.sub(r"\s+", " ", r["phrase"]).strip()
                if len(phrase) > 200:
                    phrase = phrase[:200].rsplit(" ", 1)[0] + "…"
                proj = r.get("project", "?")
                lines.append(f"- \"{phrase}\" — _{proj}_")
            lines.append("")

    # === Approvals: redirect-go gets its own section with prior_assistant context ===
    # This is the highest-signal pattern in the corpus: which question shapes from
    # Claude routinely get overridden with a single "go"/"continue". The phrase
    # alone is meaningless ("go"); the load-bearing data is what Claude asked.
    redirect_recs = by_signal_label.get(("approval", "redirect-go"), [])
    other_approvals = [
        r for r in by_signal.get("approval", []) if r["label"] != "redirect-go"
    ]

    if redirect_recs:
        lines.append("## Hesitation overrides — questions Nino said 'go' to")
        lines.append("")
        lines.append(
            "_Each entry pairs a question Claude asked with Nino's one-word "
            "override. Use these to recognize the shape of questions Nino "
            "considers unnecessary — and skip asking them._"
        )
        lines.append("")
        lines.append(f"**Signal count**: {len(redirect_recs)}")
        lines.append("")

        # Dedupe by prior_assistant tail (the actual question shape).
        seen_q: set[str] = set()
        shown = 0
        for r in redirect_recs:
            prior = re.sub(r"\s+", " ", (r.get("prior_assistant") or "")).strip()
            if not prior:
                continue
            # Use the last sentence of prior_assistant — usually the actual question.
            tail = prior[-180:]
            key = re.sub(r"\W+", " ", tail.lower())[:160]
            if key in seen_q:
                continue
            seen_q.add(key)
            phrase = re.sub(r"\s+", " ", r["phrase"]).strip()
            proj = r.get("project", "?")
            lines.append(f"- Claude asked: \"…{tail}\"")
            lines.append(f"  Nino replied: **\"{phrase}\"** — _{proj}_")
            lines.append("")
            shown += 1
            if shown >= 6:
                break
        lines.append("")

    if other_approvals:
        lines.append("## Validated judgment calls")
        lines.append("")
        lines.append("_Non-obvious approaches Nino confirmed worked. Don't re-litigate these._")
        lines.append("")
        lines.append(f"**Signal count**: {len(other_approvals)}")
        lines.append("")
        label_counts = Counter(r["label"] for r in other_approvals)
        for label, count in label_counts.most_common():
            label_recs = [r for r in other_approvals if r["label"] == label]
            reps = dedupe_by_phrase(label_recs, limit=3)
            lines.append(f"### `{label}` ({count} occurrences)")
            lines.append("")
            for r in reps:
                phrase = re.sub(r"\s+", " ", r["phrase"]).strip()
                if len(phrase) > 200:
                    phrase = phrase[:200].rsplit(" ", 1)[0] + "…"
                proj = r.get("project", "?")
                lines.append(f"- \"{phrase}\" — _{proj}_")
            lines.append("")

    # Project breakdown
    lines.append("## Project footprint")
    lines.append("")
    lines.append("Where these signals came from (top 20):")
    lines.append("")
    for proj, count in projects.most_common(20):
        lines.append(f"- `{proj}` — {count}")
    lines.append("")

    POE_DIR.mkdir(parents=True, exist_ok=True)
    STACK_PATH.write_text("\n".join(lines))
    print(f"Stack written: {STACK_PATH} ({total} signals)", file=sys.stderr)


def main() -> None:
    p = argparse.ArgumentParser(description=__doc__.splitlines()[0] if __doc__ else "")
    sub = p.add_subparsers(dest="cmd", required=True)

    e = sub.add_parser("extract", help="scan sessions and write corpus.jsonl (or DB for --session)")
    e.add_argument("--limit", type=int, default=None, help="max number of session files")
    e.add_argument("--since", type=int, default=None, help="only sessions newer than N days")
    e.add_argument("--session", type=str, default=None, help="single JSONL file -> DB (hook mode)")

    sub.add_parser("init", help="ensure DB schema exists")
    sub.add_parser("publish", help="load corpus.jsonl -> recall.db")
    sub.add_parser("assemble", help="build stack.md from DB (or corpus.jsonl)")

    c = sub.add_parser("catchup", help="watermark-driven idempotent sweep of all sessions")
    c.add_argument("--verbose", action="store_true", help="log even when nothing changed")
    c.add_argument(
        "--include-codex", action="store_true",
        help="also sweep active and archived Codex transcripts",
    )
    c.add_argument(
        "--include-gemini", action="store_true",
        help="also sweep retained Gemini CLI transcripts",
    )

    d = sub.add_parser("drain-queue", help="drain ~/.claude/poe/queue then catchup-sweep")
    d.add_argument("--verbose", action="store_true", help="log even when nothing changed")
    d.add_argument(
        "--include-codex", action="store_true",
        help="include Codex transcripts in the fallback catchup sweep",
    )
    d.add_argument(
        "--include-gemini", action="store_true",
        help="include Gemini transcripts in the fallback catchup sweep",
    )

    rr = sub.add_parser(
        "retention-report",
        help="dry-run watermark coverage for archived Codex transcripts; never deletes",
    )
    rr.add_argument(
        "--grace-days", type=int, default=7,
        help="minimum archive age before reporting a covered file (default: 7)",
    )
    rr.add_argument(
        "--list-covered", action="store_true",
        help="include paths and watermark evidence for covered archived files",
    )

    sub.add_parser("enqueue", help="hook command: read stdin JSON, append transcript_path to queue")
    sub.add_parser("prompt-hook", help="UserPromptSubmit hook: emit Poe context for the prompt")

    hs = sub.add_parser("hook-stats", help="summarize prompt-hook telemetry")
    hs.add_argument("--days", type=int, default=7)

    df = sub.add_parser("drift", help="report rules with no recent reinforcement")
    df.add_argument("--days", type=int, default=90, help="reinforcement window")
    df.add_argument("--labels", action="store_true", help="old behavior: stale voice labels")
    df.add_argument("--json", action="store_true", dest="as_json")
    df.add_argument("--verbose", action="store_true", help="also show live rules")

    ml = sub.add_parser("memory-link", help="cross-reference voice corpus with MEMORY.md indexes")
    ml.add_argument("--threshold", type=int, default=5, help="min signal count for promotion candidate")
    ml.add_argument("--verbose", action="store_true")

    pc = sub.add_parser("poe-check", help="classify a draft against Poe situations")
    pc.add_argument("--text", type=str, default=None, help="draft text (default: stdin)")
    pc.add_argument("--limit", type=int, default=6, help="max grounding signals")

    q = sub.add_parser("query", help="FTS5 search Poe -> markdown block")
    q.add_argument("terms", nargs="+", help="search terms")
    q.add_argument("--limit", type=int, default=25, help="max results")
    q.add_argument("--project", type=str, default=None,
                   help="filter by project (label substring) or 'auto' for cwd-derived")

    sub.add_parser("run", help="extract + publish + assemble")

    args = p.parse_args()

    if args.cmd == "extract":
        cmd_extract(args.limit, args.since, args.session)
    elif args.cmd == "init":
        cmd_init()
    elif args.cmd == "publish":
        cmd_publish()
    elif args.cmd == "assemble":
        cmd_assemble()
    elif args.cmd == "catchup":
        cmd_catchup(
            verbose=args.verbose,
            include_codex=args.include_codex,
            include_gemini=args.include_gemini,
        )
    elif args.cmd == "drain-queue":
        cmd_drain_queue(
            verbose=args.verbose,
            include_codex=args.include_codex,
            include_gemini=args.include_gemini,
        )
    elif args.cmd == "retention-report":
        cmd_retention_report(
            grace_days=args.grace_days,
            list_covered=args.list_covered,
        )
    elif args.cmd == "enqueue":
        cmd_enqueue()
    elif args.cmd == "prompt-hook":
        cmd_prompt_hook()
    elif args.cmd == "hook-stats":
        cmd_hook_stats(days=args.days)
    elif args.cmd == "drift":
        if args.labels:
            cmd_drift_labels(verbose=args.verbose)
        else:
            cmd_drift(days=args.days, verbose=args.verbose, as_json=args.as_json)
    elif args.cmd == "memory-link":
        cmd_memory_link(promote_threshold=args.threshold, verbose=args.verbose)
    elif args.cmd == "poe-check":
        cmd_poe_check(args.text, args.limit)
    elif args.cmd == "query":
        cmd_query(args.terms, args.limit, project=args.project)
    elif args.cmd == "run":
        cmd_extract(None, None, None)
        cmd_publish()
        cmd_assemble()


if __name__ == "__main__":
    main()
