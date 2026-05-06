#!/usr/bin/env python3

"""
Portable single-file SWE-style coding agent harness.

Contract:
    The validator imports this file and calls:

        solve(
            repo_path="/tmp/task_repo",
            issue="Fix the bug...",
            model="validator-managed-model",
            api_base="http://validator-proxy/v1",
            api_key="per-run-proxy-token"
        )

    It returns:
        {
            "patch": "... unified git diff ...",
            "logs": "...",
            "steps": int,
            "cost": float | None,
            "success": bool,
        }

Design goals:
    - Single file.
    - No external Python dependencies.
    - Validator-provided OpenAI-compatible /v1/chat/completions endpoint.
    - No direct OpenRouter/OpenAI credentials in miner code.
    - Bash-only action interface.
    - Validator owns repo, tests, sandbox, scoring, hidden tasks.
    - Miners only patch this file.

Miner editing guide:
    You are expected to improve this file. Good areas to edit include prompting,
    context gathering, command selection, tool/result parsing, stopping logic,
    patch generation, safety checks, and how the agent uses its step budget.

    Keep these validator-owned boundaries intact:
    - Preserve solve(repo_path, issue, model, api_base, api_key, ...) as the
      public entry point.
    - Return a dict with patch, logs, steps, cost, and success.
    - Use only the validator-provided api_base/api_key for LLM calls.
    - Do not hardcode another LLM endpoint, API key, model, wallet, scorer, test
      path, or validator secret.
    - Do not add third-party package requirements; this file must stay portable.
    - Do not read or exfiltrate host secrets, hidden tests, or evaluator data.
"""

from __future__ import annotations

import json
import os
import re
import subprocess
import sys
import time
import traceback
import urllib.error
import urllib.request
from dataclasses import dataclass
from pathlib import Path
from typing import Any, Dict, List, Optional, Tuple


# -----------------------------
# Config
# -----------------------------

# MINER-EDITABLE: You may tune local budgets like step count, command timeout,
# observation size, and max_tokens. Do not set sampling parameters; the
# validator proxy owns temperature/top-p/etc. and overwrites them server-side.
DEFAULT_MAX_STEPS = int(os.environ.get("AGENT_MAX_STEPS", "30"))
DEFAULT_COMMAND_TIMEOUT = int(os.environ.get("AGENT_COMMAND_TIMEOUT", "15"))

# VALIDATOR CONTRACT: These defaults are only fallbacks for local testing and
# validator wiring. During real validation the validator passes model, api_base,
# and api_key into solve(). Keep this code compatible with that path.
DEFAULT_MODEL = os.environ.get("AGENT_MODEL") or os.environ.get("NINJA_MODEL", "")
DEFAULT_API_BASE = (
    os.environ.get("AGENT_API_BASE")
    or os.environ.get("NINJA_INFERENCE_BASE_URL")
    or os.environ.get("OPENAI_BASE_URL", "")
)
DEFAULT_API_KEY = (
    os.environ.get("AGENT_API_KEY")
    or os.environ.get("NINJA_INFERENCE_API_KEY")
    or os.environ.get("OPENAI_API_KEY", "")
)

# OUTPUT TOKEN CAPS — per call type. Output tokens are the dominant cost and
# the dominant latency component (sequential generation). The previous global
# 8192 cap was rarely needed; most turns either emit a short plan + 1-3 commands
# or a short final summary.
DEFAULT_MAX_TOKENS = int(os.environ.get("AGENT_MAX_TOKENS", "3072"))   # exploration / patch turns
MAX_TOKENS_REFINEMENT = 1200    # polish / self-check / syntax-fix / test-fix
MAX_TOKENS_FINAL = 256          # plain finalisation when we already know it's done

# INPUT BUDGET — trimmed from previous defensive values. The agent rarely
# benefits from a 9KB observation; the model just summarises it back at us.
MAX_OBSERVATION_CHARS = int(os.environ.get("AGENT_MAX_OBSERVATION_CHARS", "6000"))
MAX_TOTAL_LOG_CHARS = int(os.environ.get("AGENT_MAX_TOTAL_LOG_CHARS", "180000"))
MAX_CONVERSATION_CHARS = 60000          # was 80000 — trims older turns more aggressively
MAX_PRELOADED_CONTEXT_CHARS = 22000     # was 28000 — preloaded context was over-budgeted
MAX_PRELOADED_FILES = 8
MAX_NO_COMMAND_REPAIRS = 3
MAX_COMMANDS_PER_RESPONSE = 12

# Refinement-turn budgets: each turn shows the model its draft and asks for one
# specific kind of correction. They are mutually exclusive so the agent never
# loops indefinitely on a borderline patch.
MAX_POLISH_TURNS = 1       # strip whitespace/comment/blank-only hunks
MAX_SELF_CHECK_TURNS = 1   # ensure issue-mentioned paths are covered, no scope creep
MAX_SYNTAX_FIX_TURNS = 1   # repair Python/TypeScript/JavaScript SyntaxError
MAX_TEST_FIX_TURNS = 1     # repair the companion test we ran ourselves

# MINER-EDITABLE: You may make this command filter stricter or smarter. Do not
# weaken it to run destructive host/container operations.
DANGEROUS_PATTERNS = [
    r"\brm\s+-rf\s+/",
    r"\bsudo\b",
    r"\bshutdown\b",
    r"\breboot\b",
    r"\bmkfs\b",
    r"\bdd\s+if=",
    r":\(\)\s*\{\s*:\|:\s*&\s*\};:",
    r"\bmount\b",
    r"\bumount\b",
    r"\biptables\b",
    r"\bnft\b",
    r"\bchown\s+-R\s+/",
    r"\bchmod\s+-R\s+777\s+/",
]


# -----------------------------
# Data structures
# -----------------------------

@dataclass
class CommandResult:
    command: str
    exit_code: int
    stdout: str
    stderr: str
    duration_sec: float
    timed_out: bool = False
    blocked: bool = False


@dataclass
class AgentResult:
    patch: str
    logs: str
    steps: int
    cost: Optional[float]
    success: bool

    def to_dict(self) -> Dict[str, Any]:
        return {
            "patch": self.patch,
            "logs": self.logs,
            "steps": self.steps,
            "cost": self.cost,
            "success": self.success,
        }


# -----------------------------
# Utility
# -----------------------------

def _truncate(text: str, max_chars: int) -> str:
    if len(text) <= max_chars:
        return text
    half = max_chars // 2
    return (
        text[:half]
        + "\n\n...[truncated "
        + str(len(text) - max_chars)
        + " chars]...\n\n"
        + text[-half:]
    )


def _safe_join_logs(logs: List[str]) -> str:
    joined = "\n".join(logs)
    return _truncate(joined, MAX_TOTAL_LOG_CHARS)


def _message_chars(messages: List[Dict[str, str]]) -> int:
    return sum(len(message.get("content") or "") + 32 for message in messages)


def _messages_for_request(messages: List[Dict[str, str]]) -> List[Dict[str, str]]:
    """Compose the request message list, preserving the cacheable prefix.

    IMPORTANT for prompt caching: the head (system prompt + initial user
    prompt) is always preserved verbatim. If we exceed the conversation
    budget, we drop middle messages and keep the recent tail. The cached
    prefix at the start is never modified, so cache hits remain valid.
    """
    if _message_chars(messages) <= MAX_CONVERSATION_CHARS:
        return messages

    head = messages[:2]
    tail: List[Dict[str, str]] = []
    budget = max(8000, MAX_CONVERSATION_CHARS - _message_chars(head) - 400)
    used = 0
    for message in reversed(messages[2:]):
        size = len(message.get("content") or "") + 32
        if tail and used + size > budget:
            break
        tail.append(message)
        used += size
    tail.reverse()

    omitted = max(0, len(messages) - len(head) - len(tail))
    if omitted == 0:
        return messages
    note = {
        "role": "user",
        "content": (
            f"[{omitted} older interaction messages omitted to stay within the "
            "time/token budget. Continue from the recent observations and make "
            "the smallest useful patch.]"
        ),
    }
    return [*head, note, *tail]


def _normalize_api_base(api_base: str) -> str:
    base = api_base.rstrip("/")
    if base.endswith("/chat/completions"):
        return base[: -len("/chat/completions")]
    if base.endswith("/v1"):
        return base
    return base + "/v1"


def _resolve_inference_config(
    model: Optional[str],
    api_base: Optional[str],
    api_key: Optional[str],
) -> Tuple[str, str, str]:
    model_name = (model or DEFAULT_MODEL).strip()
    base = (api_base or DEFAULT_API_BASE).strip()
    key = (api_key if api_key is not None else DEFAULT_API_KEY).strip()

    if not model_name:
        raise ValueError("model is required; validators must pass the centrally managed model id")
    if not base:
        raise ValueError("api_base is required; validators must pass the managed inference proxy URL")
    if not key:
        raise ValueError("api_key is required; validators must pass the per-run proxy token")

    return model_name, _normalize_api_base(base), key


def _is_dangerous_command(command: str) -> Optional[str]:
    lowered = command.strip()
    for pattern in DANGEROUS_PATTERNS:
        if re.search(pattern, lowered):
            return pattern
    return None


def _repo_path(path: str | Path) -> Path:
    p = Path(path).resolve()
    if not p.exists():
        raise FileNotFoundError(f"repo_path does not exist: {p}")
    if not p.is_dir():
        raise NotADirectoryError(f"repo_path is not a directory: {p}")
    return p


# -----------------------------
# OpenAI-compatible client
# -----------------------------

# MINER-EDITABLE WITH BOUNDARIES: You may change request formatting, retry
# behavior, response parsing, or model-message strategy here. Keep all requests
# pointed at the api_base/api_key supplied by solve(); the validator proxy
# rewrites the model and sampling parameters server-side.
def chat_completion(
    messages: List[Dict[str, str]],
    model: str,
    api_base: Optional[str],
    api_key: Optional[str],
    max_tokens: int = DEFAULT_MAX_TOKENS,
    timeout: int = 120,
    max_retries: int = 1,
) -> Tuple[str, Optional[float], Dict[str, Any]]:
    """OpenAI-compatible /v1/chat/completions client.

    Retries once on transient transport failures (timeout, connection reset,
    HTTP 5xx). Client-side errors (4xx) bail out immediately because retrying
    won't change the outcome and burns wall-clock budget that the agent needs
    for actual editing.

    Note on caching: this client sends the messages list as-is. Prompt caching
    (if enabled by the validator proxy) is driven entirely by the stability of
    the message prefix, which the orchestration layer is responsible for. We
    do not need to set any cache-control header here for OpenAI-compatible
    endpoints — the proxy handles cache decisions based on prefix identity.
    """

    model_name, base, key = _resolve_inference_config(model, api_base, api_key)
    url = base + "/chat/completions"

    payload = {
        "model": model_name,
        "messages": messages,
        "max_tokens": max_tokens,
    }

    body = json.dumps(payload).encode("utf-8")
    headers = {
        "Content-Type": "application/json",
        "Authorization": f"Bearer {key}",
    }

    data: Optional[Dict[str, Any]] = None
    last_error: Optional[Exception] = None
    for attempt in range(max_retries + 1):
        req = urllib.request.Request(url=url, data=body, headers=headers, method="POST")
        try:
            with urllib.request.urlopen(req, timeout=timeout) as resp:
                raw = resp.read().decode("utf-8", errors="replace")
                data = json.loads(raw)
            break
        except urllib.error.HTTPError as e:
            err_body = e.read().decode("utf-8", errors="replace")
            if 500 <= e.code < 600 and attempt < max_retries:
                last_error = e
                time.sleep(1.0)
                continue
            raise RuntimeError(f"HTTP {e.code} from model endpoint: {err_body}") from e
        except (urllib.error.URLError, TimeoutError, ConnectionError, OSError) as e:
            if attempt < max_retries:
                last_error = e
                time.sleep(1.0)
                continue
            raise RuntimeError(f"Model request failed: {e}") from e
        except Exception as e:
            raise RuntimeError(f"Model request failed: {e}") from e

    if data is None:
        raise RuntimeError(f"Model request failed after retries: {last_error}")

    try:
        content = data["choices"][0]["message"]["content"] or ""
    except Exception as e:
        raise RuntimeError(f"Unexpected model response shape: {data}") from e

    usage = data.get("usage") or {}
    cost = 0.0 if usage else None
    return content, cost, data


# -----------------------------
# Shell execution
# -----------------------------

# MINER-EDITABLE: This is the bash tool surface your agent uses inside the task
# repo. You may improve command validation, environment handling, timeouts, and
# output shaping. Keep commands scoped to the repo and avoid secrets or network
# access outside the validator inference proxy.
def run_command(command: str, cwd: Path, timeout: int = DEFAULT_COMMAND_TIMEOUT) -> CommandResult:
    command = command.strip()

    if not command:
        return CommandResult(
            command=command,
            exit_code=0,
            stdout="",
            stderr="Empty command ignored.",
            duration_sec=0.0,
        )

    blocked_pattern = _is_dangerous_command(command)
    if blocked_pattern:
        return CommandResult(
            command=command,
            exit_code=126,
            stdout="",
            stderr=f"Blocked potentially dangerous command. Matched pattern: {blocked_pattern}",
            duration_sec=0.0,
            blocked=True,
        )

    start = time.time()

    try:
        proc = subprocess.run(
            command,
            cwd=str(cwd),
            shell=True,
            text=True,
            stdout=subprocess.PIPE,
            stderr=subprocess.PIPE,
            timeout=timeout,
            executable="/bin/bash",
            env=_command_env(),
        )

        return CommandResult(
            command=command,
            exit_code=proc.returncode,
            stdout=_truncate(proc.stdout or "", MAX_OBSERVATION_CHARS),
            stderr=_truncate(proc.stderr or "", MAX_OBSERVATION_CHARS),
            duration_sec=time.time() - start,
        )

    except subprocess.TimeoutExpired as e:
        stdout = e.stdout or ""
        stderr = e.stderr or ""
        if isinstance(stdout, bytes):
            stdout = stdout.decode("utf-8", errors="replace")
        if isinstance(stderr, bytes):
            stderr = stderr.decode("utf-8", errors="replace")

        return CommandResult(
            command=command,
            exit_code=124,
            stdout=_truncate(stdout, MAX_OBSERVATION_CHARS),
            stderr=_truncate(stderr + f"\nCommand timed out after {timeout}s.", MAX_OBSERVATION_CHARS),
            duration_sec=time.time() - start,
            timed_out=True,
        )

    except Exception as e:
        return CommandResult(
            command=command,
            exit_code=1,
            stdout="",
            stderr=f"Command execution failed: {e}",
            duration_sec=time.time() - start,
        )


def _command_env() -> Dict[str, str]:
    return {
        "PATH": os.environ.get("PATH", "/usr/local/bin:/usr/bin:/bin"),
        "HOME": os.environ.get("HOME", "/tmp") or "/tmp",
        "TMPDIR": os.environ.get("TMPDIR", "/tmp") or "/tmp",
        "LANG": os.environ.get("LANG", "C.UTF-8") or "C.UTF-8",
        "PYTHONUNBUFFERED": "1",
        "PIP_DISABLE_PIP_VERSION_CHECK": "1",
        "GIT_PAGER": "cat",
        "PAGER": "cat",
        "CI": "1",
    }


def format_observation(result: CommandResult) -> str:
    """Compact observation format. Skips empty stderr to save input tokens."""
    parts = [
        "COMMAND:",
        result.command,
        "",
        f"EXIT_CODE: {result.exit_code}    DURATION: {result.duration_sec:.2f}s",
        "",
        "STDOUT:",
        result.stdout,
    ]
    if result.stderr.strip():
        parts.extend(["", "STDERR:", result.stderr])
    return "\n".join(parts) + "\n"


# -----------------------------
# Action parsing
# -----------------------------

ACTION_RE = re.compile(r"<command>\s*(.*?)\s*</command>", re.IGNORECASE | re.DOTALL)
FINAL_RE = re.compile(r"<final>\s*(.*?)\s*</final>", re.IGNORECASE | re.DOTALL)


def extract_commands(model_text: str) -> List[str]:
    return [match.group(1).strip() for match in ACTION_RE.finditer(model_text) if match.group(1).strip()]


def extract_command(model_text: str) -> Optional[str]:
    commands = extract_commands(model_text)
    return commands[0] if commands else None


def extract_final(model_text: str) -> Optional[str]:
    match = FINAL_RE.search(model_text)
    if not match:
        return None
    return match.group(1).strip()


# -----------------------------
# Git helpers
# -----------------------------

def ensure_git_repo(repo: Path) -> None:
    git_dir = repo / ".git"
    if git_dir.exists():
        return

    subprocess.run(
        "git init >/dev/null 2>&1 && git add . >/dev/null 2>&1 && git commit -m 'initial task state' >/dev/null 2>&1 || true",
        cwd=str(repo),
        shell=True,
        executable="/bin/bash",
        stdout=subprocess.PIPE,
        stderr=subprocess.PIPE,
        text=True,
        timeout=30,
    )


def get_patch(repo: Path) -> str:
    exclude_pathspecs = [
        ":(exclude,glob)**/*.pyc",
        ":(exclude,glob)**/__pycache__/**",
        ":(exclude,glob)**/.pytest_cache/**",
        ":(exclude,glob)**/node_modules/**",
        ":(exclude).git",
    ]
    proc = subprocess.run(
        ["git", "diff", "--binary", "--", ".", *exclude_pathspecs],
        cwd=str(repo),
        stdout=subprocess.PIPE,
        stderr=subprocess.PIPE,
        text=True,
        timeout=30,
    )
    diff_output = proc.stdout or ""

    untracked = subprocess.run(
        ["git", "ls-files", "--others", "--exclude-standard", "-z"],
        cwd=str(repo),
        stdout=subprocess.PIPE,
        stderr=subprocess.PIPE,
        text=True,
        timeout=30,
    )
    if untracked.returncode != 0:
        return diff_output

    for relative_path in [item for item in untracked.stdout.split("\0") if item]:
        if _should_skip_patch_path(relative_path):
            continue
        file_diff = subprocess.run(
            ["git", "diff", "--binary", "--no-index", "--", "/dev/null", relative_path],
            cwd=str(repo),
            stdout=subprocess.PIPE,
            stderr=subprocess.PIPE,
            text=True,
            timeout=30,
        )
        if file_diff.returncode in (0, 1):
            diff_output += file_diff.stdout or ""

    cleaned = _strip_mode_only_file_diffs(diff_output)
    return _strip_low_signal_hunks(cleaned)


def _strip_mode_only_file_diffs(diff_output: str) -> str:
    if not diff_output.strip():
        return diff_output

    blocks = re.split(r"(?=^diff --git )", diff_output, flags=re.MULTILINE)
    kept: List[str] = []
    for block in blocks:
        if not block:
            continue
        mode_only = (
            block.startswith("diff --git ")
            and "\nold mode " in block
            and "\nnew mode " in block
            and "\n@@ " not in block
            and "\nGIT binary patch" not in block
            and "\nBinary files " not in block
            and "\nnew file mode " not in block
            and "\ndeleted file mode " not in block
        )
        if mode_only:
            continue
        kept.append(block)

    result = "".join(kept)
    if diff_output.endswith("\n") and result and not result.endswith("\n"):
        result += "\n"
    return result


def _should_skip_patch_path(relative_path: str) -> bool:
    path = Path(relative_path)
    if path.suffix == ".pyc":
        return True
    return any(part in {"__pycache__", ".pytest_cache", "node_modules", ".git"} for part in path.parts)


def get_repo_summary(repo: Path) -> str:
    """Compact repo summary. Trimmed to 150 tracked files (was 220)."""
    commands = [
        "pwd",
        "git ls-files | awk 'NR<=150 {print} END {if (NR>150) print \"... \" NR-150 \" more tracked files\"}'",
        "git status --short || true",
    ]

    parts = []
    for cmd in commands:
        res = run_command(cmd, repo, timeout=10)
        parts.append(format_observation(res))

    return "\n\n".join(parts)


TEXT_FILE_EXTENSIONS = {
    ".c", ".cc", ".cpp", ".cs", ".css", ".go", ".h", ".hpp", ".html",
    ".java", ".js", ".jsx", ".json", ".kt", ".md", ".php", ".py", ".rb",
    ".rs", ".scss", ".sh", ".sql", ".svelte", ".swift", ".toml", ".ts",
    ".tsx", ".txt", ".vue", ".xml", ".yaml", ".yml",
}

CONTEXT_SKIP_PARTS = {
    ".git", ".next", ".pytest_cache", ".venv", "__pycache__", "build",
    "coverage", "dist", "node_modules", "target", "vendor",
}

SECRETISH_PARTS = {
    ".env", ".npmrc", ".pypirc", ".netrc",
    "credentials", "secret", "secrets",
}


def build_preloaded_context(repo: Path, issue: str) -> str:
    """Preload the highest-ranked tracked files plus their companion tests.

    Two improvements over a vanilla rank-and-read loop:

      1. Companion test files (tests/test_X.py for X.py, X.test.ts for X.ts,
         X_test.go for X.go, etc.) are slotted in right after their source
         partner. Real GitHub-derived tasks almost always need source+test
         changes together; without the test in context the agent patches only
         the source and bleeds Cursor-similarity score.

      2. Files that match identifier-shaped symbols extracted from the issue
         text get a substantial rank boost via `_symbol_grep_hits`. This
         catches the common case where the bug is described by function or
         class name without mentioning the file path.
    """
    files = _rank_context_files(repo, issue)
    if not files:
        return ""

    tracked_set = set(_tracked_files(repo))
    files = _augment_with_test_partners(files, tracked_set)

    parts: List[str] = []
    used = 0
    per_file_budget = max(1200, MAX_PRELOADED_CONTEXT_CHARS // max(1, min(len(files), MAX_PRELOADED_FILES)))

    for relative_path in files[:MAX_PRELOADED_FILES]:
        snippet = _read_context_file(repo, relative_path, per_file_budget)
        if not snippet.strip():
            continue
        block = f"### {relative_path}\n```\n{snippet}\n```"
        if parts and used + len(block) > MAX_PRELOADED_CONTEXT_CHARS:
            break
        parts.append(block)
        used += len(block)

    return "\n\n".join(parts)


def _rank_context_files(repo: Path, issue: str) -> List[str]:
    tracked = _tracked_files(repo)
    if not tracked:
        return []

    issue_lower = issue.lower()
    path_mentions = _extract_issue_path_mentions(issue)
    mentioned: List[str] = []
    tracked_set = set(tracked)
    for mention in path_mentions:
        normalized = mention.strip("./")
        if normalized in tracked_set and _context_file_allowed(normalized):
            mentioned.append(normalized)

    terms = _issue_terms(issue)
    symbol_hits = _symbol_grep_hits(repo, tracked_set, issue)
    scored: List[Tuple[int, str]] = []
    for relative_path in tracked:
        if not _context_file_allowed(relative_path):
            continue
        path_lower = relative_path.lower()
        name_lower = Path(relative_path).name.lower()
        stem_lower = Path(relative_path).stem.lower()
        score = 0
        if relative_path in mentioned:
            score += 100
        if path_lower in issue_lower:
            score += 35
        if name_lower and name_lower in issue_lower:
            score += 24
        if stem_lower and len(stem_lower) >= 3 and stem_lower in issue_lower:
            score += 16
        score += sum(3 for term in terms if term in path_lower)
        if "/test" in path_lower or "spec." in path_lower or ".test." in path_lower:
            score += sum(2 for term in terms if term in path_lower)
        # Boost files whose contents reference identifiers from the issue.
        if relative_path in symbol_hits:
            score += 60 + min(40, 8 * symbol_hits[relative_path])
        if score > 0:
            scored.append((score, relative_path))

    scored.sort(key=lambda item: (-item[0], len(item[1]), item[1]))
    ranked: List[str] = []
    seen: set[str] = set()
    for relative_path in mentioned + [path for _score, path in scored]:
        if relative_path in seen:
            continue
        seen.add(relative_path)
        ranked.append(relative_path)
    return ranked


def _tracked_files(repo: Path) -> List[str]:
    try:
        proc = subprocess.run(
            ["git", "ls-files"],
            cwd=str(repo),
            stdout=subprocess.PIPE,
            stderr=subprocess.PIPE,
            text=True,
            timeout=10,
        )
    except Exception:
        return []
    if proc.returncode != 0:
        return []
    return [line.strip() for line in proc.stdout.splitlines() if line.strip()]


def _context_file_allowed(relative_path: str) -> bool:
    path = Path(relative_path)
    parts_lower = {part.lower() for part in path.parts}
    name_lower = path.name.lower()
    if parts_lower & CONTEXT_SKIP_PARTS:
        return False
    if name_lower.startswith(".env") or name_lower in SECRETISH_PARTS or parts_lower & SECRETISH_PARTS:
        return False
    if path.suffix.lower() not in TEXT_FILE_EXTENSIONS:
        return False
    return True


def _extract_issue_path_mentions(issue: str) -> List[str]:
    pattern = re.compile(
        r"(?<![\\w.-])([\\w./-]+\\.(?:c|cc|cpp|cs|css|go|h|hpp|html|java|js|jsx|json|kt|md|php|py|rb|rs|scss|sh|sql|svelte|swift|toml|ts|tsx|txt|vue|xml|ya?ml))(?![\\w.-])",
        re.IGNORECASE,
    )
    mentions: List[str] = []
    for match in pattern.finditer(issue):
        value = match.group(1).strip("`'\"()[]{}:,;")
        if value and value not in mentions:
            mentions.append(value)
    return mentions


def _issue_terms(issue: str) -> List[str]:
    stop = {
        "about", "after", "also", "before", "change", "code", "file", "from",
        "have", "issue", "make", "need", "should", "that", "their", "there",
        "this", "update", "using", "when", "with",
    }
    terms: List[str] = []
    for raw in re.findall(r"[A-Za-z_][A-Za-z0-9_-]{2,}", issue.lower()):
        if raw in stop or raw in terms:
            continue
        terms.append(raw)
    return terms[:40]


def _read_context_file(repo: Path, relative_path: str, max_chars: int) -> str:
    path = (repo / relative_path).resolve()
    try:
        path.relative_to(repo.resolve())
    except ValueError:
        return ""
    try:
        data = path.read_bytes()
    except Exception:
        return ""
    if b"\0" in data[:4096]:
        return ""
    text = data.decode("utf-8", errors="replace")
    return _truncate(text, max_chars)


# -----------------------------
# Hunk classifiers + diff hygiene
# -----------------------------

_COMMENT_LINE_PREFIXES: Tuple[str, ...] = ("#", "//", ";", "--", "%")
_BLOCK_COMMENT_RE = re.compile(r"^\s*(\*|/\*|\*/)")


def _line_is_comment(line: str) -> bool:
    stripped = line.strip()
    if not stripped:
        return False
    if any(stripped.startswith(p) for p in _COMMENT_LINE_PREFIXES):
        return True
    if _BLOCK_COMMENT_RE.match(line):
        return True
    if stripped.startswith('"""') or stripped.startswith("'''"):
        return True
    return False


def _hunk_is_blank_only(added: List[str], removed: List[str]) -> bool:
    body = [line for line in added + removed if line.strip()]
    return not body and bool(added or removed)


def _hunk_is_whitespace_only(added: List[str], removed: List[str]) -> bool:
    if not added and not removed:
        return False
    a = sorted(line.strip() for line in added if line.strip())
    r = sorted(line.strip() for line in removed if line.strip())
    if not a and not r:
        return True
    return a == r


def _hunk_is_comment_only(added: List[str], removed: List[str]) -> bool:
    body = [line for line in added + removed if line.strip()]
    if not body:
        return False
    return all(_line_is_comment(line) for line in body)


def _strip_low_signal_hunks(diff_output: str) -> str:
    if not diff_output.strip():
        return diff_output

    blocks = re.split(r"(?=^diff --git )", diff_output, flags=re.MULTILINE)
    out: List[str] = []
    for block in blocks:
        if not block:
            continue
        if not block.startswith("diff --git ") or "\n@@ " not in block:
            out.append(block)
            continue
        parts = re.split(r"(?=^@@ )", block, flags=re.MULTILINE)
        header = parts[0]
        hunks = [chunk for chunk in parts[1:] if chunk]
        substantive: List[str] = []
        for hunk_text in hunks:
            added: List[str] = []
            removed: List[str] = []
            for line in hunk_text.splitlines():
                if line.startswith("+") and not line.startswith("+++"):
                    added.append(line[1:])
                elif line.startswith("-") and not line.startswith("---"):
                    removed.append(line[1:])
            if (
                _hunk_is_blank_only(added, removed)
                or _hunk_is_whitespace_only(added, removed)
                or _hunk_is_comment_only(added, removed)
            ):
                continue
            substantive.append(hunk_text)
        if substantive:
            out.append(header + "".join(substantive))
    result = "".join(out)
    if diff_output.endswith("\n") and result and not result.endswith("\n"):
        result += "\n"
    return result


def _diff_low_signal_summary(patch: str) -> str:
    if not patch.strip():
        return ""

    notes: List[str] = []
    current_file = "?"
    current_added: List[str] = []
    current_removed: List[str] = []

    def flush() -> None:
        if not current_added and not current_removed:
            return
        if _hunk_is_blank_only(current_added, current_removed):
            notes.append(f"{current_file}: blank-line-only hunk")
        elif _hunk_is_whitespace_only(current_added, current_removed):
            notes.append(f"{current_file}: whitespace-only hunk")
        elif _hunk_is_comment_only(current_added, current_removed):
            notes.append(f"{current_file}: comment-only hunk")

    for line in patch.splitlines():
        if line.startswith("diff --git "):
            flush()
            current_added, current_removed = [], []
            tokens = line.split()
            if len(tokens) >= 4 and tokens[3].startswith("b/"):
                current_file = tokens[3][2:]
        elif line.startswith("@@"):
            flush()
            current_added, current_removed = [], []
        elif line.startswith("+") and not line.startswith("+++"):
            current_added.append(line[1:])
        elif line.startswith("-") and not line.startswith("---"):
            current_removed.append(line[1:])

    flush()

    deduped: List[str] = []
    seen: set = set()
    for note in notes:
        if note in seen:
            continue
        seen.add(note)
        deduped.append(note)
    return "; ".join(deduped[:10])


def _patch_changed_files(patch: str) -> List[str]:
    seen: List[str] = []
    for match in re.finditer(r"^diff --git a/(.+?) b/(.+?)$", patch, flags=re.MULTILINE):
        path = match.group(2)
        if path and path not in seen:
            seen.append(path)
    return seen


def _patch_covers_required_paths(patch: str, issue_text: str) -> bool:
    required = _extract_issue_path_mentions(issue_text)
    if not required:
        return True
    changed = set(_patch_changed_files(patch))
    return all(any(req == c or c.endswith("/" + req) for c in changed) for req in required)


# -----------------------------
# Multi-language syntax gate
# -----------------------------

_SYNTAX_TIMEOUT = 6


def _check_python_syntax_one(repo: Path, relative_path: str) -> Optional[str]:
    full = (repo / relative_path).resolve()
    try:
        full.relative_to(repo.resolve())
    except (ValueError, RuntimeError):
        return None
    if not full.exists():
        return None
    try:
        source = full.read_text(encoding="utf-8", errors="replace")
    except Exception:
        return None
    try:
        import ast as _ast
        _ast.parse(source)
        return None
    except SyntaxError as exc:
        return f"{relative_path}:{exc.lineno}: {exc.msg}"
    except Exception as exc:
        return f"{relative_path}: parse failure: {exc}"


def _check_node_syntax_one(repo: Path, relative_path: str) -> Optional[str]:
    if not _has_executable("node"):
        return None
    proc_result = run_command(
        f"node --check {_shell_quote(relative_path)}",
        repo,
        timeout=_SYNTAX_TIMEOUT,
    )
    if proc_result.exit_code == 0:
        return None
    msg = (proc_result.stderr or proc_result.stdout or "").strip().splitlines()[-1] if (proc_result.stderr or proc_result.stdout) else ""
    return f"{relative_path}: {msg or 'node --check failed'}"


def _check_json_syntax_one(repo: Path, relative_path: str) -> Optional[str]:
    full = (repo / relative_path).resolve()
    try:
        full.relative_to(repo.resolve())
    except (ValueError, RuntimeError):
        return None
    if not full.exists():
        return None
    try:
        json.loads(full.read_text(encoding="utf-8", errors="replace"))
        return None
    except json.JSONDecodeError as exc:
        return f"{relative_path}:{exc.lineno}: {exc.msg}"
    except Exception as exc:
        return f"{relative_path}: parse failure: {exc}"


def _check_syntax(repo: Path, patch: str) -> List[str]:
    errors: List[str] = []
    for relative_path in _patch_changed_files(patch):
        suffix = Path(relative_path).suffix.lower()
        result: Optional[str] = None
        if suffix == ".py":
            result = _check_python_syntax_one(repo, relative_path)
        elif suffix in {".js", ".mjs", ".cjs"}:
            result = _check_node_syntax_one(repo, relative_path)
        elif suffix in {".json"}:
            result = _check_json_syntax_one(repo, relative_path)
        if result:
            errors.append(result)
    return errors


def _has_executable(name: str) -> bool:
    try:
        proc = subprocess.run(
            ["command", "-v", name],
            stdout=subprocess.PIPE,
            stderr=subprocess.PIPE,
            text=True,
            timeout=2,
            shell=False,
        )
        return proc.returncode == 0 and bool(proc.stdout.strip())
    except Exception:
        return False


def _shell_quote(value: str) -> str:
    return "'" + value.replace("'", "'\"'\"'") + "'"


# -----------------------------
# Companion-test discovery
# -----------------------------

_TEST_PARTNER_TEMPLATES: Tuple[Tuple[str, str], ...] = (
    ("{stem}.py", "tests/test_{stem}.py"),
    ("{stem}.py", "test_{stem}.py"),
    ("{stem}.py", "{dir}/test_{stem}.py"),
    ("{stem}.py", "{dir}/tests/test_{stem}.py"),
    ("{stem}.py", "tests/{stem}_test.py"),
    ("{stem}.ts", "{dir}/{stem}.test.ts"),
    ("{stem}.ts", "{dir}/__tests__/{stem}.test.ts"),
    ("{stem}.ts", "tests/{stem}.test.ts"),
    ("{stem}.tsx", "{dir}/{stem}.test.tsx"),
    ("{stem}.tsx", "{dir}/__tests__/{stem}.test.tsx"),
    ("{stem}.js", "{dir}/{stem}.test.js"),
    ("{stem}.js", "{dir}/__tests__/{stem}.test.js"),
    ("{stem}.jsx", "{dir}/{stem}.test.jsx"),
    ("{stem}.go", "{dir}/{stem}_test.go"),
    ("{stem}.rs", "{dir}/{stem}_test.rs"),
    ("{stem}.rb", "spec/{stem}_spec.rb"),
)


def _find_test_partner(relative_path: str, tracked: set) -> Optional[str]:
    path = Path(relative_path)
    name_lower = path.name.lower()
    if "test" in name_lower or "spec" in name_lower:
        return None
    stem = path.stem
    suffix = path.suffix
    if not stem or not suffix:
        return None
    parent = str(path.parent) if str(path.parent) not in {".", ""} else ""
    for source_template, test_template in _TEST_PARTNER_TEMPLATES:
        if not source_template.endswith(suffix):
            continue
        candidate = test_template.format(stem=stem, dir=parent).lstrip("/")
        candidate = str(Path(candidate))
        if candidate in tracked and _context_file_allowed(candidate):
            return candidate
    return None


def _augment_with_test_partners(files: List[str], tracked: set) -> List[str]:
    if not tracked:
        return files
    augmented: List[str] = []
    seen: set = set()
    for relative_path in files:
        if relative_path not in seen:
            augmented.append(relative_path)
            seen.add(relative_path)
        partner = _find_test_partner(relative_path, tracked)
        if partner and partner not in seen:
            augmented.append(partner)
            seen.add(partner)
    return augmented


# -----------------------------
# Issue-symbol grep ranking
# -----------------------------

_SYMBOL_RE = re.compile(r"(?<![A-Za-z0-9_])([A-Za-z_][A-Za-z0-9_]{2,})(?![A-Za-z0-9_])")
_SYMBOL_STOP = {
    "about", "after", "alert", "argument", "before", "build", "called", "change",
    "check", "class", "code", "command", "config", "context", "default", "expect",
    "expected", "fail", "false", "field", "fields", "file", "files", "fix",
    "fixed", "function", "given", "global", "header", "headers", "import",
    "issue", "method", "module", "needed", "needs", "object", "params", "parse",
    "path", "patch", "production", "project", "property", "public", "remove",
    "reset", "return", "should", "static", "string", "support", "test", "tests",
    "their", "there", "thing", "this", "true", "type", "types", "update",
    "using", "value", "values", "when", "with", "will", "without", "write",
}


def _extract_issue_symbols(issue_text: str, *, max_symbols: int = 12) -> List[str]:
    seen: set = set()
    out: List[str] = []
    for match in _SYMBOL_RE.finditer(issue_text):
        token = match.group(1)
        if token in seen:
            continue
        lowered = token.lower()
        if lowered in _SYMBOL_STOP:
            continue
        is_compound = any(c.isupper() for c in token[1:]) or "_" in token
        if not is_compound and len(token) < 4:
            continue
        seen.add(token)
        out.append(token)
        if len(out) >= max_symbols:
            break
    return out


def _symbol_grep_hits(
    repo: Path,
    tracked_set: set,
    issue_text: str,
) -> Dict[str, int]:
    symbols = _extract_issue_symbols(issue_text)
    if not symbols:
        return {}
    hits: Dict[str, int] = {}
    for symbol in symbols:
        try:
            proc = subprocess.run(
                ["git", "grep", "-l", "-F", "--", symbol],
                cwd=str(repo),
                stdout=subprocess.PIPE,
                stderr=subprocess.PIPE,
                text=True,
                timeout=4,
            )
        except Exception:
            continue
        if proc.returncode not in (0, 1):
            continue
        for line in proc.stdout.splitlines():
            relative_path = line.strip()
            if not relative_path or relative_path not in tracked_set:
                continue
            if not _context_file_allowed(relative_path):
                continue
            hits[relative_path] = hits.get(relative_path, 0) + 1
    return hits


# -----------------------------
# Prompting
# -----------------------------

# CACHEABLE: This system prompt is identical across every task. It sits at the
# very start of the message list, so a caching proxy will hit it on every
# request after the first. KEEP IT STABLE — any edit invalidates the cache.
#
# Tightened from the previous version to remove redundant phrasing while
# keeping every behavioural rule. Roughly 25% fewer tokens for the same
# effective policy.
SYSTEM_PROMPT = """You are a coding agent inside a repository. Fix the issue with the smallest correct diff. Wall-clock budget is tight — patch quickly, do not over-explore.

Interface (bash only). Run a command:

<command>
your bash command
</command>

Finish:

<final>summary</final>

Plan-first: in your FIRST response, output a brief <plan> listing target files and which acceptance criterion maps to each, THEN issue the first <command>(s) in the same response. Do not split plan and commands across turns.

Rules:
- Smallest diff that meets every criterion. Surplus lines hurt the similarity score.
- If a file is in the preloaded snippets, edit it directly — do NOT re-read it.
- When several files need changes, send every independent edit command in the SAME response. Do not split one patch across turns.
- Match indentation, quotes, semicolons, trailing commas, blank-line and brace style EXACTLY from surrounding code.
- Match identifier and string tokens to existing code.
- The preload includes companion test files. When you patch a source file, update its companion test in the SAME response if affected.
- AVOID: whitespace-only edits, comment-only edits, blank-line shuffling, import reorders, type-annotation drive-bys, dead-code removal, defensive checks, or refactors not required by the task.
- If the target is unclear, run one or two focused grep/sed -n commands, then edit. Do not loop on inspection.
- Verify with one cheap targeted check on a touched file (`python -m py_compile X`, `node --check X`, `pytest -k name X`, `tsc --noEmit X`). Skip full installs, full builds, broad suites.
- If a verification command is slow or deps are missing, keep the patch and finalize.
- Do not dump generated/minified/binary/lock/vendored files.
- No sudo. No repo deletion. No secrets. No network outside the validator inference proxy. Do not modify hidden tests or evaluator files.
- Always actually edit code — do not stop after only explaining.
"""


def build_initial_user_prompt(issue: str, repo_summary: str, preloaded_context: str = "") -> str:
    """Initial user message. Structure is intentional for prompt caching:

    Stable parts come first via SYSTEM_PROMPT. This message is unique per
    task (issue text + repo summary + preloaded files all vary), so it is
    NOT a cache hit — but it sits behind a cached SYSTEM_PROMPT, which is.
    Avoid putting templated boilerplate after the dynamic content; that
    would waste both input tokens and any cache opportunity downstream.
    """
    context_section = ""
    if preloaded_context.strip():
        context_section = (
            "\n\nPreloaded relevant files (already read — patch directly, do not re-read):\n\n"
            f"{preloaded_context}\n"
        )

    return (
        f"Issue:\n{issue}\n\n"
        f"Repo summary:\n{repo_summary}"
        f"{context_section}\n"
        "If the preloaded snippets identify the target, edit them now. Otherwise "
        "run one or two focused searches, then patch. Send every needed file edit "
        "in the same response. After a patch exists, run one cheap verification, "
        "then <final>...</final>."
    )


def build_no_command_repair_prompt() -> str:
    return (
        "Your last response had no <command> or <final> block.\n"
        "If the patch is complete, reply <final>summary</final>.\n"
        "Otherwise issue exactly one command:\n\n<command>\n...\n</command>"
    )


def build_budget_pressure_prompt(step: int) -> str:
    if step < 4:
        return "Budget check: no patch yet. Next command must edit the most likely file(s) using the issue + observed snippets. No more broad exploration."
    return "Hard budget check: still no patch. Next command must create a minimal best-effort change for the clearest acceptance criterion. No more inspection until a patch exists."


def build_polish_prompt(junk_summary: str) -> str:
    return (
        f"Cleanup: your draft has low-signal hunks: {junk_summary}\n\n"
        "Revert ONLY those hunks (sed/cat/python). Do not add edits, refactor, "
        "or touch unrelated lines. Then <final>summary</final>. If you can't "
        "cleanly revert without breaking real edits, finalize as-is."
    )


def build_self_check_prompt(patch: str, issue_text: str) -> str:
    truncated = (
        patch
        if len(patch) <= 3000
        else patch[:1500] + "\n...[truncated]...\n" + patch[-1200:]
    )
    return (
        "Self-check. Review your draft for:\n"
        "- acceptance criteria NOT addressed\n"
        "- companion tests broken or out of sync\n"
        "- unrelated churn (whitespace, comments, refactors, type drive-bys)\n"
        "- new bugs or syntax errors\n\n"
        f"Patch:\n```diff\n{truncated}\n```\n\n"
        f"Task:\n{issue_text[:1500]}\n\n"
        "If good, reply exactly: <final>OK</final>\n"
        "Otherwise emit corrective <command> blocks fixing ONLY the listed issues, "
        "then <final>summary</final>. No new features, no unrelated edits."
    )


def build_syntax_fix_prompt(errors: List[str]) -> str:
    bullets = "\n  ".join(errors[:10]) or "(none)"
    return (
        f"Syntax check failed:\n  {bullets}\n\n"
        "Smallest possible fix command(s) only. No new edits, no refactor. "
        "Then <final>summary</final>."
    )


def build_test_fix_prompt(test_path: str, output: str) -> str:
    tail = output[-2000:] if len(output) > 2000 else output
    return (
        f"Companion test still failing: `{test_path}`.\n\n"
        f"Output (tail):\n```\n{tail}\n```\n\n"
        "Either patch is incomplete or test needs updating. Minimal "
        "<command> blocks, then <final>summary</final>."
    )


# -----------------------------
# Main agent
# -----------------------------

# MINER-EDITABLE CORE: This orchestration loop is the main place to improve the
# agent. You may change planning, memory, context collection, repair behavior,
# test strategy, and stopping criteria. Preserve the solve() signature and
# returned dict shape so validators can run your submission.
def solve(
    repo_path: str,
    issue: str,
    model: Optional[str] = None,
    api_base: Optional[str] = None,
    api_key: Optional[str] = None,
    max_steps: int = DEFAULT_MAX_STEPS,
    command_timeout: int = DEFAULT_COMMAND_TIMEOUT,
    max_tokens: int = DEFAULT_MAX_TOKENS,
) -> Dict[str, Any]:
    """
    Main portable interface for validators.
    """

    repo: Optional[Path] = None
    logs: List[str] = []
    total_cost: Optional[float] = 0.0
    success = False
    consecutive_no_command = 0
    polish_turns_used = 0
    self_check_turns_used = 0
    syntax_fix_turns_used = 0
    # Tracks the max_tokens cap to use for the NEXT model call. Refinement turns
    # set this to a smaller value before queueing, so the corrective response
    # doesn't pay for unused output headroom.
    next_max_tokens = max_tokens

    def queue_refinement_turn(
        assistant_text: str,
        prompt_text: str,
        marker: str,
        cap: int = MAX_TOKENS_REFINEMENT,
    ) -> None:
        """Append assistant + corrective user message and journal it.

        Sets next_max_tokens to `cap` so the next model call uses a smaller
        output budget. Refinement responses are short — wasting 8K of headroom
        on them is pure cost.
        """
        nonlocal next_max_tokens
        logs.append(f"\n{marker}\n")
        messages.append({"role": "assistant", "content": assistant_text})
        messages.append({"role": "user", "content": prompt_text})
        next_max_tokens = cap

    def maybe_queue_refinement(assistant_text: str) -> bool:
        nonlocal polish_turns_used, self_check_turns_used, syntax_fix_turns_used
        patch = get_patch(repo)
        if not patch.strip():
            return False

        if polish_turns_used < MAX_POLISH_TURNS:
            junk = _diff_low_signal_summary(patch)
            if junk:
                polish_turns_used += 1
                queue_refinement_turn(
                    assistant_text,
                    build_polish_prompt(junk),
                    f"POLISH_TURN_QUEUED:\n  {junk}",
                )
                return True

        if syntax_fix_turns_used < MAX_SYNTAX_FIX_TURNS:
            syntax_errors = _check_syntax(repo, patch)
            if syntax_errors:
                syntax_fix_turns_used += 1
                queue_refinement_turn(
                    assistant_text,
                    build_syntax_fix_prompt(syntax_errors),
                    "SYNTAX_FIX_QUEUED:\n  " + "\n  ".join(syntax_errors),
                )
                return True

        if self_check_turns_used < MAX_SELF_CHECK_TURNS:
            self_check_turns_used += 1
            queue_refinement_turn(
                assistant_text,
                build_self_check_prompt(patch, issue),
                "SELF_CHECK_QUEUED",
            )
            return True

        return False

    try:
        repo = _repo_path(repo_path)
        model_name, api_base, api_key = _resolve_inference_config(model, api_base, api_key)
        ensure_git_repo(repo)
        repo_summary = get_repo_summary(repo)
        preloaded_context = build_preloaded_context(repo, issue)

        messages: List[Dict[str, str]] = [
            {"role": "system", "content": SYSTEM_PROMPT},
            {"role": "user", "content": build_initial_user_prompt(issue, repo_summary, preloaded_context)},
        ]

        for step in range(1, max_steps + 1):
            logs.append(f"\n\n===== STEP {step} =====\n")

            # Use the per-turn output cap and reset it back to the default for
            # the turn after this one. Refinement prompts override before
            # queueing; everything else uses `max_tokens`.
            this_call_max_tokens = next_max_tokens
            next_max_tokens = max_tokens

            try:
                response_text, cost, _raw = chat_completion(
                    messages=_messages_for_request(messages),
                    model=model_name,
                    api_base=api_base,
                    api_key=api_key,
                    max_tokens=this_call_max_tokens,
                )
                if cost is not None and total_cost is not None:
                    total_cost += cost
            except Exception:
                logs.append(f"MODEL_ERROR:\n{traceback.format_exc()}")
                break

            logs.append("MODEL_RESPONSE:\n" + response_text)

            commands = extract_commands(response_text)
            final = extract_final(response_text)

            if not commands:
                if final is not None:
                    if maybe_queue_refinement(response_text):
                        continue
                    logs.append("\nFINAL_SUMMARY:\n" + final)
                    success = True
                    break
                consecutive_no_command += 1
                patch = get_patch(repo)
                if patch.strip():
                    if maybe_queue_refinement(response_text):
                        continue
                    logs.append("\nPATCH_READY:\nModel stopped issuing commands after creating a patch.")
                    success = True
                    break
                if consecutive_no_command >= MAX_NO_COMMAND_REPAIRS:
                    logs.append("\nSTOPPED:\nModel repeatedly failed to produce a command or final answer.")
                    break
                messages.append({"role": "assistant", "content": response_text})
                messages.append({"role": "user", "content": build_no_command_repair_prompt()})
                # Repair turns are short — cap output tokens.
                next_max_tokens = MAX_TOKENS_REFINEMENT
                continue

            consecutive_no_command = 0
            messages.append({"role": "assistant", "content": response_text})
            observations: List[str] = []
            command_batch = commands[:MAX_COMMANDS_PER_RESPONSE]

            for command_index, command in enumerate(command_batch, 1):
                result = run_command(command, repo, timeout=command_timeout)
                observation = format_observation(result)
                observations.append(f"OBSERVATION {command_index}/{len(command_batch)}:\n{observation}")
                logs.append(f"\nOBSERVATION {command_index}/{len(command_batch)}:\n" + observation)

                if step >= 4 or command_index > 1:
                    patch = get_patch(repo)
                    if patch.strip() and _looks_like_successful_test_output(observation, command):
                        if maybe_queue_refinement(response_text):
                            break
                        logs.append("\nAUTO_STOP:\nPatch exists and latest command looked like successful tests.")
                        success = True
                        break
                    if patch.strip() and result.timed_out:
                        if maybe_queue_refinement(response_text):
                            break
                        logs.append("\nPATCH_READY:\nPatch exists and latest command exceeded the local command timeout.")
                        success = True
                        break
                    if patch.strip() and step >= 8 and _looks_like_patch_review_command(command, result):
                        if not _patch_covers_required_paths(patch, issue):
                            continue
                        if maybe_queue_refinement(response_text):
                            break
                        logs.append("\nPATCH_READY:\nPatch exists and latest command reviewed the diff/status.")
                        success = True
                        break

            if len(commands) > len(command_batch):
                observations.append(
                    f"NOTE: Only the first {len(command_batch)} commands ran. "
                    "Send remaining commands one at a time if more work is needed."
                )

            if final is not None and get_patch(repo).strip():
                if maybe_queue_refinement(response_text):
                    if success:
                        break
                    continue
                logs.append("\nFINAL_SUMMARY:\n" + final)
                success = True

            if observations:
                observation_text = "\n\n".join(observations)
                if not success and get_patch(repo).strip():
                    observation_text += (
                        "\n\nPatch exists. Send all remaining edits in your next response — "
                        "do not split one patch across turns."
                    )
                elif not success:
                    observation_text += (
                        "\n\nIf snippets are sufficient, send the full set of edit commands now."
                    )
                messages.append({"role": "user", "content": observation_text})

            if success:
                break

            if not get_patch(repo).strip() and step in {2, 4}:
                messages.append({"role": "user", "content": build_budget_pressure_prompt(step)})

        patch = get_patch(repo)
        if patch.strip() and not success:
            logs.append("\nPATCH_RETURN:\nReturning the best patch produced within the step budget.")
            success = True
        step_count = len([x for x in logs if x.startswith("\n\n===== STEP")])
        return AgentResult(
            patch=patch,
            logs=_safe_join_logs(logs),
            steps=min(max_steps, step_count),
            cost=total_cost,
            success=success and bool(patch.strip()),
        ).to_dict()

    except Exception:
        logs.append("FATAL_ERROR:\n" + traceback.format_exc())
        patch = ""
        if repo is not None:
            try:
                patch = get_patch(repo)
            except Exception:
                pass

        return AgentResult(
            patch=patch,
            logs=_safe_join_logs(logs),
            steps=0,
            cost=total_cost,
            success=False,
        ).to_dict()


def _looks_like_successful_test_output(observation: str, command: str = "") -> bool:
    lower = observation.lower()
    exit_code = _extract_observation_exit_code(lower)
    stderr_body = _extract_observation_section(lower, "stderr")

    bad_markers = [
        " failed", " failures", " error", " errors",
        "traceback", "assertionerror", "syntaxerror", "exception",
    ]
    good_markers = [" passed", " all passed", "ok", "success"]

    if exit_code is not None and exit_code != 0:
        return False

    has_good = any(marker in lower for marker in good_markers)
    has_bad = any(marker in lower for marker in bad_markers)
    if stderr_body and any(marker in stderr_body for marker in bad_markers):
        has_bad = True

    if exit_code == 0 and _looks_like_verification_command(command) and not has_bad:
        return True

    return (exit_code == 0 or has_good) and has_good and not has_bad


def _looks_like_verification_command(command: str) -> bool:
    lowered = command.lower()
    patterns = [
        r"\bpython\d*(\.\d+)?\s+-m\s+pytest\b",
        r"\bpytest\b",
        r"\bpython\d*(\.\d+)?\s+-m\s+py_compile\b",
        r"\bnpm\s+(test|run\s+(test|build|lint|typecheck|check))\b",
        r"\bpnpm\s+(test|run\s+(test|build|lint|typecheck|check)|exec\s+tsc)\b",
        r"\byarn\s+(test|run\s+(test|build|lint|typecheck|check))\b",
        r"\bnpx\s+tsc\b",
        r"\btsc\b",
        r"\bgo\s+test\b",
        r"\bcargo\s+(test|check|clippy|build)\b",
        r"\bmvn\s+test\b",
        r"\bgradle(w)?\s+test\b",
        r"\bmake\s+(test|check|lint)\b",
        r"\bruff\b",
        r"\beslint\b",
    ]
    return any(re.search(pattern, lowered) for pattern in patterns)


def _looks_like_patch_review_command(command: str, result: CommandResult) -> bool:
    if result.exit_code != 0:
        return False
    lowered = command.lower().strip()
    return bool(
        re.search(r"\bgit\s+(diff|status)\b", lowered)
        or re.search(r"\bgit\s+show\s+--stat\b", lowered)
    )


def _extract_observation_exit_code(observation_lower: str) -> Optional[int]:
    # Updated to match the new compact observation format:
    # "EXIT_CODE: <n>    DURATION: <d>s"
    match = re.search(r"(?m)^exit_code:\s*(-?\d+)", observation_lower)
    if not match:
        return None
    try:
        return int(match.group(1))
    except ValueError:
        return None


def _extract_observation_section(observation_lower: str, section: str) -> str:
    match = re.search(
        rf"(?ms)^{re.escape(section.lower())}:\n(.*?)(?:\n[a-z_]+:|\Z)",
        observation_lower,
    )
    return match.group(1).strip() if match else ""


# -----------------------------
# CLI for local testing
# -----------------------------

def _parse_args(argv: List[str]) -> Dict[str, Any]:
    import argparse

    parser = argparse.ArgumentParser(description="Run portable single-file coding agent.")
    parser.add_argument("--repo", required=True, help="Path to repo/task directory.")
    parser.add_argument("--issue", required=False, help="Issue text.")
    parser.add_argument("--issue-file", required=False, help="File containing issue text.")
    parser.add_argument("--model", default=DEFAULT_MODEL, help="Model name.")
    parser.add_argument("--api-base", default=DEFAULT_API_BASE, help="OpenAI-compatible API base.")
    parser.add_argument("--api-key", default=DEFAULT_API_KEY, help="API key.")
    parser.add_argument("--max-steps", type=int, default=DEFAULT_MAX_STEPS)
    parser.add_argument("--command-timeout", type=int, default=DEFAULT_COMMAND_TIMEOUT)
    parser.add_argument("--max-tokens", type=int, default=DEFAULT_MAX_TOKENS)
    parser.add_argument("--json-out", default="", help="Optional path to write result JSON.")
    return vars(parser.parse_args(argv))


def main(argv: List[str]) -> int:
    args = _parse_args(argv)

    issue = args.get("issue") or ""
    if args.get("issue_file"):
        issue = Path(args["issue_file"]).read_text(encoding="utf-8")

    if not issue.strip():
        print("ERROR: provide --issue or --issue-file", file=sys.stderr)
        return 2

    result = solve(
        repo_path=args["repo"],
        issue=issue,
        model=args["model"],
        api_base=args["api_base"],
        api_key=args["api_key"],
        max_steps=args["max_steps"],
        command_timeout=args["command_timeout"],
        max_tokens=args["max_tokens"],
    )

    output = json.dumps(result, indent=2)

    if args.get("json_out"):
        Path(args["json_out"]).write_text(output, encoding="utf-8")

    print(output)
    return 0 if result.get("success") else 1


if __name__ == "__main__":
    raise SystemExit(main(sys.argv[1:]))
