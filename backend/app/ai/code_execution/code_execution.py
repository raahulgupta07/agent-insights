import asyncio
import contextvars
import inspect
import io
import os
import sys
import ast
import re
import threading
import time as _time
import pandas as pd
import numpy as np
import datetime
import json
import uuid
from concurrent.futures import ThreadPoolExecutor
from contextlib import redirect_stdout
from typing import Dict, Any, Tuple, List, Optional, Callable, Coroutine

from app.ai.http.safe_client import SafeHttpClient

# `redirect_stdout` mutates the *global* sys.stdout. When the code-exec
# thread pool runs N executions concurrently, the enter/exit ordering
# can leave sys.stdout pointing at a sibling thread's already-closed
# StringIO buffer. The next print/df.info()/etc. inside ANY thread then
# raises ValueError("I/O operation on closed file"). Serializing the
# redirect_stdout window with a lock keeps the (very brief) duration of
# the redirect race-free; user code executes inside the lock but it's
# already CPU-bound by the GIL, so wall-clock impact is negligible.
_STDOUT_REDIRECT_LOCK = threading.Lock()
from app.schemas.organization_settings_schema import OrganizationSettingsConfig, FeatureState
from app.services.usage_policy_service import UsageLimitContext, usage_policy_service
from typing import TYPE_CHECKING
if TYPE_CHECKING:
    from app.ai.context.builders.code_context_builder import CodeContextBuilder
from app.ai.schemas.codegen import CodeGenContext, CodeGenRequest
from app.ai.code_execution.loadables import extract_loadable_refs
from app.settings.hybrid_flags import flags
from app.core.otel import get_tracer
from opentelemetry.trace import StatusCode
from app.errors.app_error import AppError
from app.errors.codes import ErrorCode

# Hard fallback when neither connection nor org settings define a value.
DEFAULT_QUERY_TIMEOUT_SECONDS = 60

_tracer = get_tracer(__name__)

# Dedicated thread pool for user code execution.
# Keeps code-exec threads isolated from the default asyncio executor so that
# stuck DB/network calls in generated code cannot starve other server operations.
# When all workers are occupied, new submissions queue; the idle-timeout in the
# tool runner will cancel queued futures (via Future.cancel()) before they start,
# preventing unbounded queue growth.
_CODE_EXEC_POOL = ThreadPoolExecutor(
    max_workers=min(8, (os.cpu_count() or 4) * 2),
    thread_name_prefix="dash_code_exec",
)


# On-by-default address-space cap (MB) for code exec. Overridable via env
# ``SANDBOX_MEM_LIMIT_MB``; set to 0 (or negative) to disable. The legacy
# ``SKILL_EXEC_MEM_CAP_MB`` still works and, when present, takes precedence.
DEFAULT_SANDBOX_MEM_LIMIT_MB = 2048


def _resolve_mem_cap_mb() -> int:
    """Resolve the address-space cap in MB. <= 0 means disabled.

    Precedence: legacy ``SKILL_EXEC_MEM_CAP_MB`` (explicit opt-in/override) >
    ``SANDBOX_MEM_LIMIT_MB`` (the on-by-default knob) > built-in default. An
    unparseable value for a var is skipped in favor of the next source.
    """
    for var in ("SKILL_EXEC_MEM_CAP_MB", "SANDBOX_MEM_LIMIT_MB"):
        raw = os.environ.get(var)
        if raw is None or not raw.strip():
            continue
        try:
            return int(raw.strip())
        except (TypeError, ValueError):
            continue
    return DEFAULT_SANDBOX_MEM_LIMIT_MB


def _maybe_apply_memory_cap(logger=None) -> None:
    """Best-effort, ON-by-default address-space cap for code exec.

    Resolves the cap via :func:`_resolve_mem_cap_mb` (default
    ``DEFAULT_SANDBOX_MEM_LIMIT_MB``). A cap <= 0 (env set to 0) is a pure no-op.

    IMPORTANT LIMITATION — ``resource.setrlimit(RLIMIT_AS, ...)`` is **per
    PROCESS, not per thread**. Our code-exec runs on a shared ThreadPool inside
    the API process, so this lowers the address-space ceiling for the WHOLE
    process (all sibling threads + the server itself), not just the one
    execution. It is therefore a coarse, best-effort guard — not isolation.
    Real per-execution isolation would need a subprocess/container/cgroup.
    Because it is process-wide, tune ``SANDBOX_MEM_LIMIT_MB`` to sit safely above
    the server's steady-state virtual footprint (glibc arenas + thread stacks +
    pandas/duckdb can reserve a lot of VIRTUAL address space on many-core boxes),
    or set it to 0 to disable if it proves too tight.

    Safety rules (deliberately conservative — unchanged):
      - Non-POSIX / no ``resource`` module (e.g. Windows) -> silent no-op.
      - Only RAISE the soft limit toward the requested cap when the current
        soft limit is unlimited or already HIGHER than the cap. We never lower
        the process below a ceiling a sibling thread may have already set, and
        never touch the hard limit. (RLIMIT_AS is process-wide and risky.)
      - Any failure is caught, logged as a warning, and execution continues.
    """
    cap_mb = _resolve_mem_cap_mb()
    if cap_mb <= 0:
        return

    try:
        import resource  # POSIX-only; degrade to no-op if unavailable.
    except Exception:
        return

    cap_bytes = cap_mb * 1024 * 1024
    try:
        soft, hard = resource.getrlimit(resource.RLIMIT_AS)
        # Only tighten toward the cap when the existing soft limit is unlimited
        # or strictly higher than what we want. If a sibling already set a
        # tighter (lower) soft limit, leave it alone — never raise it.
        if soft == resource.RLIM_INFINITY or soft > cap_bytes:
            # Respect the hard limit: don't request a soft above the hard cap.
            new_soft = cap_bytes
            if hard != resource.RLIM_INFINITY and new_soft > hard:
                new_soft = hard
            resource.setrlimit(resource.RLIMIT_AS, (new_soft, hard))
    except Exception as exc:  # pragma: no cover - platform dependent
        if logger:
            try:
                logger.warning(f"sandbox mem cap: failed to apply RLIMIT_AS cap ({cap_mb}MB): {exc}")
            except Exception:
                pass
        # Continue regardless — the cap is best-effort, never fatal.


# =============================================================================
# Security Exceptions
# =============================================================================

class CodeSecurityError(Exception):
    """Base exception for code security violations."""
    pass


class UnsafePythonError(CodeSecurityError):
    """Raised when Python code contains dangerous constructs."""
    pass


class UnsafeSQLError(CodeSecurityError):
    """Raised when SQL query contains dangerous operations."""
    pass


class ReadOnlyViolationError(UnsafeSQLError):
    """Raised when structural read-only enforcement (flags.READONLY_ENFORCE) rejects
    a write/DDL statement on the AGENT query path at runtime.

    Distinct from UnsafeSQLError's AST-time scan: this fires on the ACTUAL string
    passed to client.execute_query(), so a query assembled dynamically (concat,
    a variable, an f-string with interpolated parts) can't slip a DROP/DELETE past
    the compile-time scanner. Defense-in-depth beside the connection-level read-only
    transaction (Postgres default_transaction_read_only)."""
    pass


class QueryTimeoutError(AppError):
    """Raised when a wrapped client.execute_query exceeds its wall-clock budget.

    Caught by the surrounding exception handler in generate_and_execute_stream_v2
    and surfaced to the planner via captured_timings -> observation.db_message.
    The underlying DB query may keep running on the server until the connection
    is closed; we just stop waiting for it.
    """

    def __init__(self, timeout_seconds: int, sql: Optional[str] = None) -> None:
        message = (
            f"Query exceeded {timeout_seconds}s timeout. "
            f"Run multiple smaller queries instead of one large scan — "
            f"each execute_query call gets its own {timeout_seconds}s budget. "
            "Use LIMIT, narrower filters, or aggregation."
        )
        super().__init__(
            ErrorCode.QUERY_TIMEOUT,
            message,
            status_code=408,
            params={"timeout_seconds": int(timeout_seconds)},
        )
        self.timeout_seconds = int(timeout_seconds)
        self.sql = sql


def resolve_query_timeout(client, organization_settings) -> int:
    """Per-connection timeout resolution.

    Connection.config['query_timeout_seconds'] (stashed onto the client as
    `_bow_connection_query_timeout`) wins. Otherwise the org default; otherwise
    the hard fallback. A connection setting can only tighten the budget — values
    <= 0 are ignored at every layer.
    """
    conn_value = getattr(client, "_bow_connection_query_timeout", None)
    if isinstance(conn_value, (int, float)) and conn_value > 0:
        return int(conn_value)
    if organization_settings is not None:
        try:
            org_cfg = organization_settings.get_config("query_timeout_seconds")
            org_value = org_cfg.value if hasattr(org_cfg, "value") else org_cfg
            if isinstance(org_value, (int, float)) and org_value > 0:
                return int(org_value)
        except Exception:
            pass
    return DEFAULT_QUERY_TIMEOUT_SECONDS


# =============================================================================
# AST-based Python Code Validation
# =============================================================================

# Modules that should never be imported
FORBIDDEN_MODULES = frozenset({
    'os', 'subprocess', 'sys', 'shutil', 'importlib', 'builtins',
    'code', 'pty', 'socket', 'requests', 'urllib', 'urllib3', 'http',
    'httpx', 'aiohttp', 'httplib2', 'curl_cffi', 'ftplib',
    'telnetlib', 'smtplib', 'poplib', 'imaplib', 'nntplib',
    'multiprocessing', 'threading', 'concurrent', 'asyncio',
    'ctypes', 'cffi', 'pickle', 'shelve', 'marshal',
    'tempfile', 'pathlib', 'glob', 'fnmatch',
    'signal', 'resource', 'sysconfig', 'platform',
    'webbrowser', 'antigravity', 'this',
})

# Built-in functions that should never be called
FORBIDDEN_BUILTINS = frozenset({
    'eval', 'exec', 'compile', 'open', 'input',
    '__import__', 'globals', 'locals', 'vars',
    'getattr', 'setattr', 'delattr', 'hasattr',
    'breakpoint', 'exit', 'quit',
    'memoryview', 'bytearray',
})

# Curated safe builtins injected as the exec namespace's __builtins__.
# Without this, exec() with a namespace that has no __builtins__ key auto-injects
# the FULL builtins module — leaking open/eval/exec/__import__/getattr/... into
# generated code (the AST deny-list is only an early scan, not a runtime fence).
# We instead hand exec an explicit dict of pure-computational builtins + exception
# classes: everything the model's generate_df() legitimately uses (pandas/numpy
# helpers, comprehensions, math, try/except) still works, while capability-bearing
# names are simply absent at runtime.
#
# NOTE: this restriction only governs NAME RESOLUTION inside the exec'd user code.
# pandas/numpy were imported at module load with the real full builtins and keep
# their own module globals, so their internals are unaffected — typical
# generate_df pandas/numpy code runs unchanged.
import builtins as _builtins_module

_SAFE_BUILTIN_NAMES = frozenset({
    # constructors / core types
    'bool', 'int', 'float', 'complex', 'str', 'bytes', 'list', 'tuple',
    'dict', 'set', 'frozenset', 'type', 'object', 'slice',
    # numeric / math
    'abs', 'round', 'min', 'max', 'sum', 'pow', 'divmod', 'len',
    # iteration / functional
    'range', 'enumerate', 'zip', 'sorted', 'reversed', 'iter', 'next',
    'map', 'filter', 'any', 'all',
    # safe reflection-lite / formatting
    'isinstance', 'issubclass', 'callable', 'repr', 'format', 'hash', 'id',
    'ord', 'chr', 'bin', 'hex', 'oct', 'ascii',
    # output
    'print',
    # exception classes (generated code routinely uses try/except)
    'BaseException', 'Exception', 'ArithmeticError', 'AssertionError',
    'AttributeError', 'FloatingPointError', 'IndexError', 'KeyError',
    'LookupError', 'NameError', 'NotImplementedError', 'OverflowError',
    'RuntimeError', 'StopIteration', 'TypeError', 'ValueError',
    'ZeroDivisionError', 'UnicodeError', 'ImportError', 'ModuleNotFoundError',
    'RecursionError', 'MemoryError',
})

# Sanity: never let a forbidden builtin sneak into the allow-list.
_SAFE_BUILTINS = {
    name: getattr(_builtins_module, name)
    for name in _SAFE_BUILTIN_NAMES
    if hasattr(_builtins_module, name) and name not in FORBIDDEN_BUILTINS
}
# `__build_class__` is needed for any `class ...:` the model defines as a helper;
# it is not itself an escape vector, so include it to avoid breaking legit codegen.
_SAFE_BUILTINS['__build_class__'] = _builtins_module.__build_class__


def _guarded_import(name, globals=None, locals=None, fromlist=(), level=0):
    """Runtime import fence that mirrors the AST import allow-list.

    Every generated `generate_df()` legitimately starts with `import pandas as pd`
    (even the coder's own fallback stub does). The `import` statement compiles to
    an implicit `__import__` call, so without this name in `__builtins__` that
    statement dies at runtime with "__import__ not found" — silently breaking
    EVERY create_data / inspect_data run. We expose an `__import__` that delegates
    to the real one but blocks the same roots the static `CodeSecurityVisitor`
    already rejects (FORBIDDEN_MODULES: os/sys/subprocess/socket/...). This keeps
    runtime name-resolution consistent with the static scan: safe modules
    (pandas/numpy/math/datetime/json/re/...) import; capability modules do not.
    Direct `__import__(...)` CALLS remain AST-forbidden (visit_Call), so this is
    only reachable via a normal `import`/`from ... import` statement.
    """
    root = (name or '').split('.')[0]
    if root in FORBIDDEN_MODULES:
        raise ImportError(f"Import of '{name}' is not allowed in the sandbox")
    return _builtins_module.__import__(name, globals, locals, fromlist, level)


_SAFE_BUILTINS['__import__'] = _guarded_import


def _fresh_safe_builtins() -> Dict[str, Any]:
    """Return a fresh copy of the curated builtins for one exec namespace.

    A copy (not the shared dict) so user code that rebinds a builtin name can't
    mutate the module-level template for sibling executions.
    """
    return dict(_SAFE_BUILTINS)


# Attribute access patterns that indicate sandbox escape attempts
FORBIDDEN_ATTRIBUTES = frozenset({
    '__class__', '__bases__', '__mro__', '__subclasses__',
    '__globals__', '__code__', '__closure__', '__func__',
    '__self__', '__dict__', '__builtins__', '__import__',
    '__loader__', '__spec__', '__path__', '__file__',
    '__cached__', '__annotations__',
})


# Call-site names that actually execute SQL. SQL-write scanning is restricted
# to the string arguments of THESE calls — never to arbitrary string literals.
# Covers BaseClient.execute_query and the federation engine, plus the common
# DB-API / pandas / DuckDB execution surfaces a generated generate_df() might use.
SQL_EXECUTOR_CALLS = frozenset({
    'execute_query', 'execute', 'executemany', 'executescript',
    'sql', 'query', 'read_sql', 'read_sql_query', 'read_sql_table',
    'run_federated_sql',
})


class CodeSecurityVisitor(ast.NodeVisitor):
    """AST visitor that checks for dangerous code patterns."""

    def __init__(self):
        self.errors: List[str] = []

    def visit_Import(self, node: ast.Import):
        for alias in node.names:
            module_name = alias.name.split('.')[0]
            if module_name in FORBIDDEN_MODULES:
                self.errors.append(f"Forbidden import: '{alias.name}'")
        self.generic_visit(node)

    def visit_ImportFrom(self, node: ast.ImportFrom):
        if node.module:
            module_name = node.module.split('.')[0]
            if module_name in FORBIDDEN_MODULES:
                self.errors.append(f"Forbidden import: 'from {node.module}'")
        self.generic_visit(node)

    def visit_Call(self, node: ast.Call):
        # Check for forbidden built-in calls like eval(), exec(), open()
        if isinstance(node.func, ast.Name):
            if node.func.id in FORBIDDEN_BUILTINS:
                self.errors.append(f"Forbidden function call: '{node.func.id}()'")

        # Check for __import__('os') style calls
        if isinstance(node.func, ast.Name) and node.func.id == '__import__':
            self.errors.append("Forbidden function call: '__import__()'")

        # SQL-write detection is SCOPED to SQL executor call-sites only.
        # We deliberately do NOT scan free-floating string literals (column
        # aliases, chart titles, dict keys, comments-as-strings) — a name like
        # "Successful Call Rate (%)" or "Load Time" is data, never an executed
        # statement, and blanket text-matching on it is an unbounded source of
        # false positives. The real write-blocking guarantee lives at the data
        # boundary (read-only DuckDB attach / read-only DB sessions); this scan
        # is a best-effort early warning for SQL that is *actually handed to an
        # executor*. See visit_Attribute (sandbox-escape) for the bounded,
        # capability-style checks that remain a true blacklist.
        method = None
        if isinstance(node.func, ast.Attribute):
            method = node.func.attr
        elif isinstance(node.func, ast.Name):
            method = node.func.id
        if method in SQL_EXECUTOR_CALLS:
            for arg in list(node.args) + [kw.value for kw in node.keywords]:
                self._scan_sql_arg(arg)

        self.generic_visit(node)

    def _scan_sql_arg(self, arg: ast.AST):
        """Scan a single executor argument (string literal or f-string) for
        write-SQL. Only invoked for args passed to a known SQL executor."""
        if isinstance(arg, ast.Constant) and isinstance(arg.value, str):
            self._match_sql(arg.value, kind="string")
        elif isinstance(arg, ast.JoinedStr):
            for part in arg.values:
                if isinstance(part, ast.Constant) and isinstance(part.value, str):
                    self._match_sql(part.value, kind="f-string")

    def _match_sql(self, value: str, *, kind: str):
        if len(value) <= 5:
            return
        match = _FORBIDDEN_SQL_IN_STRING_REGEX.search(value)
        if match:
            snippet = value[:50].replace('\n', ' ')
            self.errors.append(
                f"Forbidden SQL operation '{match.group()}' in {kind}: \"{snippet}...\""
            )

    def visit_Attribute(self, node: ast.Attribute):
        # Check for direct access to forbidden attributes like obj.__class__
        if node.attr in FORBIDDEN_ATTRIBUTES:
            self.errors.append(f"Forbidden attribute access: '{node.attr}'")
        self.generic_visit(node)


def validate_python_code(code: str) -> None:
    """
    Validate Python code for security issues using AST analysis.

    Raises:
        UnsafePythonError: If the code contains dangerous constructs.
    """
    try:
        tree = ast.parse(code)
    except SyntaxError as e:
        # HARD FAILURE — reject, never pass through. A SyntaxError means the
        # AST security scan below could not run at all, so silently returning
        # would let unscanned code reach exec(). Fail closed instead: unparseable
        # code is not eligible for execution (the model's retry loop regenerates
        # cleaner code from this message).
        raise UnsafePythonError(
            f"Code could not be parsed (SyntaxError: {e.msg} at line {e.lineno}); "
            "it cannot be security-validated and will not be executed."
        ) from e

    visitor = CodeSecurityVisitor()
    visitor.visit(tree)

    if visitor.errors:
        raise UnsafePythonError(
            f"Code contains forbidden constructs: {'; '.join(visitor.errors)}"
        )


# =============================================================================
# SQL Query Validation
# =============================================================================

# SQL keywords that indicate write/modify operations
FORBIDDEN_SQL_PATTERNS = [
    r'\bINSERT\b',
    r'\bUPDATE\b',
    r'\bDELETE\b',
    r'\bDROP\b',
    r'\bTRUNCATE\b',
    r'\bALTER\b',
    r'\bCREATE\b',
    r'\bGRANT\b',
    r'\bREVOKE\b',
    r'\bEXEC\b',
    r'\bEXECUTE\b',
    r'\bMERGE\b',
    r'\bCALL\b',
    r'\bREPLACE\b',
    r'\bLOAD\b',
    r'\bINTO\s+OUTFILE\b',
    r'\bINTO\s+DUMPFILE\b',
]

# Pre-compile regex for performance
_FORBIDDEN_SQL_REGEX = re.compile(
    '|'.join(FORBIDDEN_SQL_PATTERNS),
    re.IGNORECASE
)

# Structural SQL-write patterns — used when scanning Python string literals so
# prose like "the user wants to create a chart" or "delete outdated rows from
# the description" doesn't trigger the bare-verb match above. Each pattern
# requires the keyword to sit next to a syntactic partner that real SQL always
# has (TABLE/VIEW/INTO/FROM/SET/...), which prose basically never does.
_FORBIDDEN_SQL_IN_STRING_PATTERNS = [
    r'\bCREATE\s+(OR\s+REPLACE\s+)?(TEMP(ORARY)?\s+)?(TABLE|VIEW|INDEX|DATABASE|SCHEMA|FUNCTION|PROCEDURE|TRIGGER|SEQUENCE|ROLE|USER|MATERIALIZED)\b',
    r'\bDROP\s+(TABLE|VIEW|INDEX|DATABASE|SCHEMA|FUNCTION|PROCEDURE|TRIGGER|SEQUENCE|COLUMN|CONSTRAINT|ROLE|USER)\b',
    r'\bALTER\s+(TABLE|VIEW|INDEX|DATABASE|SCHEMA|COLUMN|SEQUENCE|ROLE|USER)\b',
    r'\bTRUNCATE\s+(TABLE\s+)?\w+',
    r'\bINSERT\s+INTO\b',
    r'\bUPDATE\s+[\w.`"\[\]]+(\s+AS\s+\w+|\s+\w+)?\s+SET\b',
    r'\bDELETE\s+FROM\b',
    r'\bMERGE\s+INTO\b',
    r'\bREPLACE\s+INTO\b',
    r'\bGRANT\s+[\w,\s*]+\s+ON\b',
    r'\bREVOKE\s+[\w,\s*]+\s+(ON|FROM)\b',
    r'\bEXEC(UTE)?\s+(\w+\.)*\w+',
    r'(?:^|;)\s*CALL\s+\w+\s*\(',
    r'\bLOAD\s+DATA\b',
    r'\bINTO\s+OUTFILE\b',
    r'\bINTO\s+DUMPFILE\b',
]
_FORBIDDEN_SQL_IN_STRING_REGEX = re.compile(
    '|'.join(_FORBIDDEN_SQL_IN_STRING_PATTERNS),
    re.IGNORECASE,
)


def estimate_result_size_bytes(result: Any) -> int:
    """Best-effort size of the result payload exposed to generated code."""
    if result is None:
        return 0
    if isinstance(result, bytes):
        return len(result)
    if isinstance(result, str):
        return len(result.encode("utf-8"))
    if isinstance(result, pd.DataFrame):
        try:
            return len(result.to_json(orient="records", date_format="iso").encode("utf-8"))
        except Exception:
            return int(result.memory_usage(deep=True).sum())
    try:
        return len(json.dumps(result, ensure_ascii=False, default=str).encode("utf-8"))
    except Exception:
        return sys.getsizeof(result)


def validate_sql_query(query: str) -> None:
    """
    Validate SQL query to ensure it's read-only.

    Raises:
        UnsafeSQLError: If the query contains write/modify operations.
    """
    if not isinstance(query, str):
        return

    match = _FORBIDDEN_SQL_REGEX.search(query)
    if match:
        raise UnsafeSQLError(
            f"SQL query contains forbidden operation: '{match.group()}'. "
            "Only SELECT queries are allowed."
        )


def _enforce_readonly_query(query: Any) -> None:
    """Structural read-only guard for the AGENT query path (flags.READONLY_ENFORCE).

    Runs on the ACTUAL runtime string (not a compile-time literal), so a
    dynamically-built write can't slip past the AST scanner. Reuses the precise
    _FORBIDDEN_SQL_IN_STRING_REGEX — it requires the write keyword next to its
    syntactic partner (TABLE/INTO/SET/...), so a column literally named "call" or
    "update_date" in a plain SELECT is NOT flagged (no regression of the old
    blocked-word landmine). Fail-soft: OFF or non-str => no-op.

    Raises:
        ReadOnlyViolationError: on a write/DDL statement while the flag is ON.
    """
    if not isinstance(query, str):
        return
    try:
        if not flags.READONLY_ENFORCE:
            return
    except Exception:
        return
    m = _FORBIDDEN_SQL_IN_STRING_REGEX.search(query)
    if m:
        snippet = query.strip()[:120].replace("\n", " ")
        raise ReadOnlyViolationError(
            f"Read-only enforcement blocked a write/DDL statement "
            f"('{m.group().strip()}'). The agent query path may only run "
            f"read-only SELECT/WITH queries. Offending SQL: \"{snippet}...\""
        )


# =============================================================================
# Query Capturing Wrapper (captures queries passed to execute_query)
# =============================================================================

class QueryCapturingClientWrapper:
    """Wrapper around a database client that captures all queries passed to execute_query.

    Works with any client that has an execute_query method (SQL, MongoDB, etc.).
    Optionally accumulates per-query wall-clock timing into captured_timings.
    Enforces a per-query wall-clock timeout: if the underlying call doesn't return
    in `query_timeout_seconds`, raises QueryTimeoutError. The orphan thread is left
    daemon so it doesn't block process exit; the DB-side query may continue until
    the connection is closed.
    """

    def __init__(
        self,
        original_client,
        captured_queries: List[str],
        captured_timings: List[dict],
        usage_context: Optional[UsageLimitContext] = None,
        client_key: Optional[str] = None,
        query_timeout_seconds: int = DEFAULT_QUERY_TIMEOUT_SECONDS,
    ):
        self._original = original_client
        self._captured_queries = captured_queries
        self._captured_timings = captured_timings
        self._usage_context = usage_context
        self._client_key = client_key
        self._query_timeout_seconds = (
            int(query_timeout_seconds)
            if isinstance(query_timeout_seconds, (int, float)) and query_timeout_seconds > 0
            else DEFAULT_QUERY_TIMEOUT_SECONDS
        )

    def execute_query(self, query: str, *args, **kwargs):
        """Intercept execute_query calls to capture the query string and wall-clock duration."""
        # Structural read-only enforcement (flags.READONLY_ENFORCE, default OFF).
        # This is the runtime chokepoint every generated SQL passes through, so it
        # catches write/DDL even when the string was assembled dynamically (a var,
        # concat, or f-string with interpolated parts) — the AST-time scanner only
        # sees literal args and would miss those. OFF => byte-identical (no check).
        _enforce_readonly_query(query)
        if isinstance(query, str):
            self._captured_queries.append(query)
        idx = len(self._captured_timings)
        _q_start = _time.monotonic()
        with _tracer.start_as_current_span("datasource.execute_query") as span:
            span.set_attribute("datasource.type", type(self._original).__name__)
            span.set_attribute("datasource.query_timeout_seconds", self._query_timeout_seconds)
            try:
                self._consume_query_quota(query)
                result = self._call_with_timeout(query, args, kwargs)
                _q_ms = (_time.monotonic() - _q_start) * 1000.0
                rows = len(result) if hasattr(result, '__len__') else None
                result_bytes = estimate_result_size_bytes(result)
                self._consume_data_bytes_quota(query, result_bytes, rows)
                if rows is not None:
                    span.set_attribute("datasource.result_rows", rows)
                span.set_attribute("datasource.result_bytes", result_bytes)
                self._captured_timings.append({
                    "index": idx,
                    "query_ms": round(_q_ms, 1),
                    "rows": rows,
                    "result_bytes": result_bytes,
                    "sql": query[:500] if isinstance(query, str) else None,
                })
                return result
            except QueryTimeoutError as e:
                _q_ms = (_time.monotonic() - _q_start) * 1000.0
                self._captured_timings.append({
                    "index": idx,
                    "query_ms": round(_q_ms, 1),
                    "rows": None,
                    "sql": query[:500] if isinstance(query, str) else None,
                    "error": str(e)[:200],
                    "error_type": "timeout",
                    "timeout_seconds": self._query_timeout_seconds,
                })
                span.set_status(StatusCode.ERROR, str(e))
                span.record_exception(e)
                raise
            except Exception as e:
                _q_ms = (_time.monotonic() - _q_start) * 1000.0
                self._captured_timings.append({
                    "index": idx,
                    "query_ms": round(_q_ms, 1),
                    "rows": None,
                    "sql": query[:500] if isinstance(query, str) else None,
                    "error": str(e)[:200],
                })
                span.set_status(StatusCode.ERROR, str(e))
                span.record_exception(e)
                raise

    def _call_with_timeout(self, query, args, kwargs):
        """Run original.execute_query in a daemon thread; abandon it on timeout.

        Threading is intentional rather than asyncio.wait_for: we're already
        inside a sync code-exec worker (user code is run via exec()), so we
        cannot await. ThreadPoolExecutor would risk pool exhaustion when many
        long queries pile up, hence a fresh per-call daemon thread.
        """
        holder: Dict[str, Any] = {}

        def runner():
            try:
                holder["value"] = self._original.execute_query(query, *args, **kwargs)
            except BaseException as exc:
                holder["exc"] = exc

        t = threading.Thread(
            target=runner,
            name="dash_query_timeout_guard",
            daemon=True,
        )
        t.start()
        t.join(self._query_timeout_seconds)
        if t.is_alive():
            raise QueryTimeoutError(
                self._query_timeout_seconds,
                sql=query if isinstance(query, str) else None,
            )
        if "exc" in holder:
            raise holder["exc"]
        return holder.get("value")

    def _consume_query_quota(self, query: str) -> None:
        context = self._usage_context
        if context is None or context.session_maker is None:
            return
        connection_id = self._connection_id()
        if not connection_id:
            return
        metadata = self._usage_metadata(query)
        context.run_blocking(
            usage_policy_service.consume_data_query_with_context(
                context,
                connection_id=str(connection_id),
                metadata=metadata,
            )
        )

    def _consume_data_bytes_quota(self, query: str, result_bytes: int, rows: Optional[int]) -> None:
        context = self._usage_context
        if context is None or context.session_maker is None or result_bytes <= 0:
            return
        connection_id = self._connection_id()
        if not connection_id:
            return
        metadata = {
            **self._usage_metadata(query),
            "rows": rows,
            "result_bytes": result_bytes,
        }
        context.run_blocking(
            usage_policy_service.consume_data_bytes_with_context(
                context,
                connection_id=str(connection_id),
                amount=result_bytes,
                metadata=metadata,
            )
        )

    def _connection_id(self) -> Optional[str]:
        connection_id = getattr(self._original, "_bow_connection_id", None)
        return str(connection_id) if connection_id else None

    def _usage_metadata(self, query: str) -> dict:
        return {
            "client_key": self._client_key or getattr(self._original, "_bow_client_key", None),
            "connection_name": getattr(self._original, "_bow_connection_name", None),
            "data_source_id": getattr(self._original, "_bow_data_source_id", None),
            "data_source_name": getattr(self._original, "_bow_data_source_name", None),
            "sql": query[:500] if isinstance(query, str) else None,
        }

    def __getattr__(self, name):
        """Delegate all other attributes to the original client."""
        return getattr(self._original, name)


def wrap_clients_for_capture(
    ds_clients: Dict,
    captured_queries: List[str],
    captured_timings: List[dict],
    usage_context: Optional[UsageLimitContext] = None,
    organization_settings: Optional[OrganizationSettingsConfig] = None,
) -> Dict:
    """Wrap all database clients to capture queries and per-query timing.

    The per-query timeout is resolved per-client so that a single tool
    invocation hitting multiple connections gets the right value for each
    underlying database.
    """
    wrapped = {}
    for key, client in (ds_clients or {}).items():
        if client is not None and hasattr(client, 'execute_query'):
            wrapped[key] = QueryCapturingClientWrapper(
                client,
                captured_queries,
                captured_timings,
                usage_context=usage_context,
                client_key=str(key),
                query_timeout_seconds=resolve_query_timeout(client, organization_settings),
            )
        else:
            wrapped[key] = client
    return wrapped


class CodeExecutionManager:
    """
    Deprecated shim. Use StreamingCodeExecutor instead.
    Provides only minimal helpers to preserve imports.
    """
    def __init__(self, logger=None, project_manager=None, db=None, report=None, head_completion=None, widget=None, step=None, organization_settings: OrganizationSettingsConfig = None):
        self.logger = logger
        self.organization_settings = organization_settings
        # Other params are ignored; legacy API compatibility only

    async def generate_and_execute_with_retries(self, *args, **kwargs):
        raise RuntimeError("CodeExecutionManager.generate_and_execute_with_retries is deprecated. Use StreamingCodeExecutor.generate_and_execute_stream.")

    def execute_code(self, code: str, db_clients: Dict, excel_files: List, loadables: Optional[Dict] = None):
        executor = StreamingCodeExecutor(organization_settings=self.organization_settings, logger=self.logger)
        return executor.execute_code(code=code, ds_clients=db_clients, excel_files=excel_files, loadables=loadables)

    def format_df_for_widget(self, df: pd.DataFrame, max_rows: Optional[int] = None) -> Dict:
        executor = StreamingCodeExecutor(organization_settings=self.organization_settings, logger=self.logger)
        return executor.format_df_for_widget(df=df, max_rows=max_rows)


class StreamingCodeExecutor:
    """
    Pure, tool-first streaming executor with retries. No project_manager/DB side-effects.
    """
    def __init__(
        self,
        organization_settings: OrganizationSettingsConfig = None,
        logger=None,
        context_hub=None,
        usage_context: Optional[UsageLimitContext] = None,
    ):
        self.organization_settings = organization_settings
        self.logger = logger
        self.context_hub = context_hub
        self.usage_context = usage_context

    def execute_code(self, *, code: str, ds_clients: Dict, excel_files: List,
                     captured_timings: Optional[List[dict]] = None,
                     captured_queries: Optional[List[str]] = None,
                     loadables: Optional[Dict] = None,
                     enforce_limits: bool = False,
                     input_df: Optional[Any] = None) -> Tuple[pd.DataFrame, str, List[str]]:
        """Execute Python code and return the resulting DataFrame, captured stdout log, and executed queries.

        captured_timings: if provided, per-query wall-clock timings are appended to this list.

        Security:
            - Validates Python code via AST analysis before execution
            - Checks all string literals for dangerous SQL operations (INSERT, DELETE, DROP, etc.)

        Returns:
            Tuple of (DataFrame, stdout_log, executed_queries) where executed_queries
            contains all query strings passed to client.execute_query() during execution.

        Raises:
            UnsafePythonError: If code contains forbidden imports, calls, or attributes
            UnsafeSQLError: If code contains SQL strings with write/modify operations
        """
        with _tracer.start_as_current_span("code_execution.execute_code") as span:
            span.set_attribute("code_execution.code_chars", len(code or ""))
            span.set_attribute("code_execution.clients", len(ds_clients or {}))
            span.set_attribute("code_execution.excel_files", len(excel_files or []))

            # Security: Validate Python code and SQL strings before execution
            validate_python_code(code)

            output_log = ""
            executed_queries: List[str] = captured_queries if captured_queries is not None else []
            _timings: List[dict] = captured_timings if captured_timings is not None else []

            # Wrap clients to capture all queries passed to execute_query
            wrapped_clients = wrap_clients_for_capture(
                ds_clients,
                executed_queries,
                _timings,
                self.usage_context,
                organization_settings=self.organization_settings,
            )

            # Inject a sync HTTP client when the org has web fetch enabled. The
            # client owns concurrency internally so model code never imports
            # asyncio/threading/socket (all of which are AST-forbidden).
            http_client = self._build_http_client()

            # Pre-resolved loadables (see loadables.py). Build pure in-memory
            # lookup closures — no DB/I/O happens inside the sandbox thread.
            load_step, load_entity = self._build_loadable_closures(loadables)

            local_namespace = {
                # Explicit curated builtins — prevents exec() from auto-injecting
                # the FULL builtins module (which would leak open/eval/exec/
                # __import__/getattr/...). See _SAFE_BUILTINS above.
                '__builtins__': _fresh_safe_builtins(),
                # A module name so a `class ...:` helper the model defines can
                # resolve __module__ (class bodies read __name__ from globals);
                # without it any helper class def raises NameError at exec.
                '__name__': 'dash_sandbox_exec',
                'pd': pd,
                'np': np,
                'db_clients': wrapped_clients,
                'excel_files': excel_files,
                'load_step': load_step,
                'load_entity': load_entity,
            }
            if http_client is not None:
                local_namespace['http'] = http_client

            # DuckDB cross-source federation. Flag-gated AND only engaged when
            # the run genuinely spans >1 source — single-source stays on the
            # existing engine. When OFF the namespace is byte-identical (the
            # `federate` key is simply absent and duckdb is never imported).
            federate = self._build_federate_closure(wrapped_clients, excel_files)
            if federate is not None:
                local_namespace['federate'] = federate

            if self.logger:
                self.logger.debug(f"Executing code:\n{code}")
            wait_started = _time.monotonic()
            _STDOUT_REDIRECT_LOCK.acquire()
            lock_acquired_at = _time.monotonic()
            try:
                with _tracer.start_as_current_span("code_execution.stdout_lock") as lock_span:
                    lock_span.set_attribute("code_execution.lock_wait_ms", round((lock_acquired_at - wait_started) * 1000.0, 3))
                    lock_span.set_attribute("code_execution.code_chars", len(code or ""))
                    with io.StringIO() as stdout_capture:
                        with redirect_stdout(stdout_capture):
                            # Best-effort, ON-by-default memory cap (see helper
                            # docstring for the per-PROCESS, not per-thread,
                            # limitation). Disable via SANDBOX_MEM_LIMIT_MB=0.
                            # `enforce_limits` is retained for backward-compat but
                            # no longer gates the cap.
                            _maybe_apply_memory_cap(self.logger)
                            exec(code, local_namespace)
                            generate_df = local_namespace.get('generate_df')
                            if not generate_df:
                                raise Exception("No generate_df function found in code")
                            df = self._invoke_generate_df(
                                generate_df, wrapped_clients, excel_files, http_client,
                                load_step=load_step, load_entity=load_entity,
                                federate=federate, input_df=input_df,
                            )
                            # ── df-binding defensive guard (P0 multi-source fix) ──
                            # The multi-source / cross-source UNION path sometimes
                            # builds the combined frame under a different name
                            # (e.g. `combined`, `result`, `frames`) and `return df`
                            # then raises a bare `NameError: name 'df' is not
                            # defined` — which previously surfaced as an opaque
                            # "Execution error" and burned both retries. If
                            # generate_df returned nothing usable, recover by
                            # picking up a DataFrame the model left in the function
                            # namespace: if exactly one non-empty DataFrame variable
                            # exists, bind it; if none, raise a CLEAR, actionable
                            # error so the retry is cheap and correctly aimed.
                            if df is None or not isinstance(df, pd.DataFrame):
                                df = self._recover_df_from_namespace(local_namespace)
                        output_log = stdout_capture.getvalue()
                    lock_span.set_attribute("code_execution.lock_held_ms", round((_time.monotonic() - lock_acquired_at) * 1000.0, 3))
            finally:
                _STDOUT_REDIRECT_LOCK.release()
            span.set_attribute("code_execution.query_count", len(executed_queries))
            span.set_attribute("code_execution.stdout_chars", len(output_log or ""))
            return df, output_log, executed_queries

    def _build_http_client(self) -> Optional[SafeHttpClient]:
        """Return a SafeHttpClient when `enable_web_fetch` is on, else None."""
        settings = self.organization_settings
        if settings is None:
            return None
        try:
            cfg = settings.get_config("enable_web_fetch")
        except Exception:
            return None
        if cfg is None or not getattr(cfg, "value", False):
            return None
        return SafeHttpClient()

    @staticmethod
    def _count_federation_sources(ds_clients: Dict, excel_files: List) -> int:
        """Count distinct queryable sources available to a federated run.

        Each usable DB client counts as one source; the presence of any
        excel/loadable DataFrame counts as one additional source. Federation
        is only worthwhile when this is >= 2.
        """
        n = 0
        for client in (ds_clients or {}).values():
            if client is not None and hasattr(client, "execute_query"):
                n += 1
        if excel_files:
            n += 1
        return n

    def _build_federate_closure(self, ds_clients: Dict, excel_files: List):
        """Return a `federate(sql, *, attachments, dataframes, parquet)` callable
        for the sandbox, or None.

        Returns None (so the sandbox namespace is byte-identical to the legacy
        path) when:
          * the FEDERATION flag is OFF, or
          * the run does not genuinely span more than one source.

        The closure delegates to the bounded DuckDB engine
        (`run_federated_sql`), which sets memory_limit + spill dir and always
        closes its connection. Any operational error degrades to None inside
        the engine rather than raising into user code. `duckdb` is imported
        lazily INSIDE the engine, so when this returns None nothing about DuckDB
        is loaded.
        """
        # Flag gate first — OFF => no import, no closure, identical namespace.
        if not flags.FEDERATION:
            return None
        # Conservative: only engage when the run spans >1 source.
        if self._count_federation_sources(ds_clients, excel_files) < 2:
            return None

        from app.ai.code_execution import duckdb_engine

        def federate(sql, *, attachments=None, dataframes=None, parquet=None):
            """Run ONE federated SQL across attached Postgres / parquet / DataFrames.

            Returns a pandas DataFrame, or None if the federated query could not
            be run (degraded). SELECT-only is enforced before dispatch.
            """
            validate_sql_query(sql)
            return duckdb_engine.run_federated_sql(
                sql,
                attachments=attachments,
                dataframes=dataframes,
                parquet=parquet,
            )

        return federate

    @staticmethod
    def _build_loadable_closures(loadables: Optional[Dict]):
        """Build pure-lookup `load_step` / `load_entity` over a resolved registry.

        The registry maps the exact literal ref used in the code to a
        DataFrame. A miss raises a clear error naming what's available — it
        only fires for dynamic (non-literal) refs that bypassed pre-resolution.
        """
        reg = loadables or {}
        steps = reg.get("steps") or {}
        entities = reg.get("entities") or {}

        def load_step(id_or_name):
            key = str(id_or_name)
            if key in steps:
                return steps[key].copy()
            raise KeyError(
                f"load_step({key!r}) is not available. "
                f"Loadable steps: {list(steps.keys())}. "
                f"Use a string-literal id or name so it can be pre-loaded."
            )

        def load_entity(id_or_name):
            key = str(id_or_name)
            if key in entities:
                return entities[key].copy()
            raise KeyError(
                f"load_entity({key!r}) is not available. "
                f"Loadable entities: {list(entities.keys())}. "
                f"Use a string-literal id or name so it can be pre-loaded."
            )

        return load_step, load_entity

    @staticmethod
    def _invoke_generate_df(
        fn: Callable, wrapped_clients: Dict, excel_files: List,
        http_client: Optional[SafeHttpClient],
        load_step: Optional[Callable] = None, load_entity: Optional[Callable] = None,
        federate: Optional[Callable] = None,
        input_df: Optional[Any] = None,
    ):
        """Call generate_df, binding injectables by parameter name.

        `ds_clients` and `excel_files` are always passed positionally. Any of
        `http`, `load_step`, `load_entity`, `federate` are passed by keyword
        only when the function declares a parameter of that name — so legacy
        two-arg `(ds_clients, excel_files)` and three-arg `(…, http)`
        signatures keep working unchanged. `federate` is only ever non-None
        when the FEDERATION flag is on AND the run spans >1 source.
        """
        injectables = {
            "http": http_client,
            "load_step": load_step,
            "load_entity": load_entity,
            "federate": federate,
            "input_df": input_df,
        }
        try:
            params = inspect.signature(fn).parameters
            names = set(params.keys())
            has_var_kw = any(
                p.kind == inspect.Parameter.VAR_KEYWORD for p in params.values()
            )
        except (TypeError, ValueError):
            names = set()
            has_var_kw = False
        kwargs = {k: v for k, v in injectables.items() if k in names}
        # Skills read `input_df` via **kwargs (not a named param). When the
        # function accepts **kwargs and a frame was supplied (sql= passthrough),
        # deliver it explicitly so it actually reaches the script.
        if has_var_kw and input_df is not None and "input_df" not in kwargs:
            kwargs["input_df"] = input_df
        try:
            return fn(wrapped_clients, excel_files, **kwargs)
        except NameError as e:
            # P0 multi-source fix: a bare `NameError: name 'df' is not defined`
            # almost always means the (often UNION/cross-source) function builds
            # its result under a different variable name and then `return df`s a
            # name that was never assigned on the taken branch. Turn the opaque
            # NameError into a CLEAR, actionable instruction so the retry is
            # aimed correctly instead of guessing. Any other NameError re-raises
            # unchanged. Returns None so the caller's namespace-recovery guard
            # gets a chance before the loop treats it as a real failure.
            msg = str(e)
            if "'df'" in msg or "name 'df'" in msg:
                raise NameError(
                    "name 'df' is not defined: the generate_df function must "
                    "assign its FINAL combined DataFrame to a variable named "
                    "exactly `df` before `return df`. In the multi-source / "
                    "cross-source UNION path, after querying each connection "
                    "separately, concatenate the per-source frames into `df` "
                    "(e.g. `df = pd.concat([df1, df2, ...], ignore_index=True)`) "
                    "and `return df`. Do not return a frame under any other name."
                ) from e
            raise

    @staticmethod
    def _recover_df_from_namespace(namespace: Dict) -> pd.DataFrame:
        """Last-resort df binder for the multi-source codegen contract.

        Called when generate_df returned None / non-DataFrame. Scans the
        post-exec function/module namespace for DataFrame variables:
          * exactly one non-empty DataFrame  -> bind it (the model almost
            certainly built the answer there and forgot to return it);
          * otherwise -> raise a CLEAR, actionable error (not a bare NameError)
            so the retry is cheap and correctly targeted.
        The keys 'pd'/'np'/'df'/dunder are skipped — we only consider genuine
        user-built frames. Empty frames are ignored as candidates so a stray
        `pd.DataFrame()` stub never wins over the real result.
        """
        candidates = {
            k: v for k, v in (namespace or {}).items()
            if isinstance(v, pd.DataFrame) and not k.startswith("__")
            and k not in ("pd", "np")
        }
        non_empty = {k: v for k, v in candidates.items() if len(v.columns) > 0}
        if len(non_empty) == 1:
            return next(iter(non_empty.values()))
        if non_empty:
            names = ", ".join(sorted(non_empty.keys()))
            raise ValueError(
                "generate_df did not return a DataFrame and several DataFrame "
                f"variables exist ({names}); assign the FINAL combined result to "
                "a variable named exactly `df` and `return df`."
            )
        raise ValueError(
            "generate_df returned no DataFrame. Assign the result of your "
            "ds_clients[...].execute_query(...) call(s) to a variable named "
            "exactly `df` and `return df`. For multi-source/UNION questions, "
            "concatenate the per-source frames with pd.concat([...]) into `df`."
        )

    async def execute_code_async(self, *, code: str, ds_clients: Dict, excel_files: List,
                                 captured_timings: Optional[List[dict]] = None,
                                 captured_queries: Optional[List[str]] = None,
                                 loadables: Optional[Dict] = None,
                                 enforce_limits: bool = False,
                                 input_df: Optional[Any] = None) -> Tuple[pd.DataFrame, str, List[str]]:
        """Run execute_code in a thread so it doesn't block the event loop."""
        loop = asyncio.get_running_loop()
        if self.usage_context is not None:
            self.usage_context.loop = loop
        with _tracer.start_as_current_span("code_execution.execute_code_async") as span:
            span.set_attribute("code_execution.pool_max_workers", _CODE_EXEC_POOL._max_workers)
            span.set_attribute("code_execution.code_chars", len(code or ""))
            started = _time.monotonic()
            worker_context = contextvars.copy_context()

            def _run_execute_code():
                return worker_context.run(
                    self.execute_code,
                    code=code,
                    ds_clients=ds_clients,
                    excel_files=excel_files,
                    captured_timings=captured_timings,
                    captured_queries=captured_queries,
                    loadables=loadables,
                    enforce_limits=enforce_limits,
                    input_df=input_df,
                )

            result = await loop.run_in_executor(
                _CODE_EXEC_POOL,
                _run_execute_code,
            )
            span.set_attribute("code_execution.total_ms", round((_time.monotonic() - started) * 1000.0, 3))
            return result

    def get_df_info(self, df: pd.DataFrame) -> Dict:
        """Extract comprehensive information from a DataFrame."""
        def convert_to_native(obj):
            if isinstance(obj, (np.int64, np.int32, np.int16, np.int8)):
                return int(obj)
            if isinstance(obj, (np.float64, np.float32, np.float16)):
                return float(obj)
            if isinstance(obj, np.bool_):
                return bool(obj)
            if isinstance(obj, (np.datetime64, datetime.datetime, datetime.date)):
                return pd.Timestamp(obj).isoformat()
            if isinstance(obj, pd.Timestamp):
                return obj.isoformat()
            if isinstance(obj, datetime.time):
                return obj.isoformat()
            if isinstance(obj, (datetime.timedelta, pd.Timedelta)):
                return str(obj)
            if isinstance(obj, np.ndarray):
                return obj.tolist()
            if isinstance(obj, uuid.UUID):
                return str(obj)
            # Fallback for any other non-JSON-serializable types
            try:
                json.dumps(obj)
                return obj
            except (TypeError, ValueError):
                return str(obj)
        def make_hashable(value: Any) -> Any:
            """
            Convert potentially unhashable values (dict, list, set, ndarray, Timestamp)
            into a hashable representation so nunique/value_counts won't crash.
            """
            try:
                # Fast path: already hashable
                hash(value)
                return value
            except Exception:
                pass
            # Normalize common container types
            if isinstance(value, (pd.Timestamp, datetime.date)):
                return pd.Timestamp(value).isoformat()
            if isinstance(value, np.ndarray):
                return tuple(value.tolist())
            if isinstance(value, (list, tuple)):
                try:
                    return tuple(make_hashable(v) for v in value)
                except Exception:
                    return tuple(str(v) for v in value)
            if isinstance(value, set):
                try:
                    return tuple(sorted(make_hashable(v) for v in value))
                except Exception:
                    return tuple(sorted(str(v) for v in value))
            if isinstance(value, dict):
                try:
                    # Stable, readable representation
                    return json.dumps(value, sort_keys=True, ensure_ascii=False, default=str)
                except Exception:
                    # Fallback to tuple of items
                    try:
                        return tuple(sorted((str(k), str(v)) for k, v in value.items()))
                    except Exception:
                        return str(value)
            # Final fallback
            try:
                return str(value)
            except Exception:
                return None

        info_dict = {
            "total_rows": int(len(df)),
            "total_columns": int(len(df.columns)),
            "column_info": {},
            "memory_usage": int(df.memory_usage(deep=True).sum()),
            "dtypes_count": {str(k): int(v) for k, v in df.dtypes.value_counts().items()},
        }
        # describe(include='all') may fail on unhashable objects (e.g., dict cells). Guard it.
        try:
            desc_dict = df.describe(include='all').to_dict()
        except Exception:
            desc_dict = {}
        for column in df.columns:
            column_info = {
                "dtype": str(df[column].dtype),
                "non_null_count": int(df[column].count()),
                "memory_usage": int(df[column].memory_usage(deep=True)),
                "null_count": int(df[column].isna().sum()),
                # nunique may fail for unhashable objects; fall back to a hashable projection
                "unique_count": 0,
            }
            try:
                column_info["unique_count"] = int(df[column].nunique(dropna=True))
            except Exception:
                try:
                    projected = df[column].map(make_hashable)
                    column_info["unique_count"] = int(projected.nunique(dropna=True))
                except Exception:
                    column_info["unique_count"] = 0
            if column in desc_dict:
                try:
                    stats = {stat: convert_to_native(value) for stat, value in desc_dict[column].items() if pd.notna(value)}
                    column_info.update(stats)
                except Exception:
                    # Best-effort; skip stats if conversion fails
                    pass
            info_dict["column_info"][column] = column_info
        return info_dict

    def format_df_for_widget(self, df: pd.DataFrame, max_rows: Optional[int] = None) -> Dict:
        """Format a DataFrame into a widget-compatible structure.

        Uses pandas' native JSON serialization which handles datetime, time,
        timedelta, numpy types, NaN/NaT, and other edge cases robustly.

        Args:
            df: The DataFrame to format
            max_rows: Maximum rows to include. If None, uses organization setting
                      'limit_row_count' or defaults to 1000.
        """
        # Determine row limit: None means no limit (disabled)
        row_limit_disabled = False
        if max_rows is None:
            if self.organization_settings is not None:
                try:
                    limit_config = self.organization_settings.get_config("limit_row_count")
                    if limit_config.state == FeatureState.DISABLED:
                        row_limit_disabled = True
                    else:
                        max_rows = int(limit_config.value)
                except (AttributeError, TypeError, ValueError):
                    max_rows = 1000
            else:
                max_rows = 1000
        columns = [{"headerName": str(col), "field": str(col)} for col in df.columns]
        if df.empty:
            rows = []
            df_info = {
                "total_rows": 0,
                "total_columns": int(len(df.columns)),
                "column_info": {str(col): {
                    "dtype": str(df[col].dtype),
                    "non_null_count": 0,
                    "memory_usage": 0,
                    "null_count": 0,
                    "unique_count": 0,
                } for col in df.columns},
                "memory_usage": int(df.memory_usage(deep=True).sum()),
                "dtypes_count": {str(k): int(v) for k, v in df.dtypes.value_counts().items()},
            }
        else:
            # Use pandas' native JSON serialization for robust type handling:
            # - date_format='iso' handles datetime, date, time, Timestamp
            # - default_handler=str catches anything else (UUID, Decimal, etc.)
            df_to_serialize = df if row_limit_disabled else df.head(max_rows)
            rows = json.loads(
                df_to_serialize.to_json(orient='records', date_format='iso', default_handler=str)
            )
            df_info = self.get_df_info(df)
        return {
            "rows": rows,
            "columns": columns,
            "loadingColumn": False,
            "info": df_info,
        }

    async def generate_and_execute_stream(
        self,
        *,
        data_model: Dict,
        prompt: str,
        schemas: str,
        ds_clients: Dict,
        excel_files: List,
        code_context_builder: 'CodeContextBuilder',
        code_generator_fn: Callable,
        max_retries: int = 2,
        sigkill_event=None,
    ):
        """
        Async generator that yields dict events:
          { "type": "progress"|"stdout", "payload": {...} }
        At the end, returns (df, code, code_and_error_messages, execution_log)
        """
        retries = 0
        code_and_error_messages: List[Tuple[str, str]] = []
        final_code = ""
        exec_df = pd.DataFrame()
        execution_log = ""
        executed_successfully = False
        while retries < max_retries:
            # Cooperative cancellation check at loop start
            if sigkill_event and hasattr(sigkill_event, 'is_set') and sigkill_event.is_set():
                break

            yield {"type": "progress", "payload": {"stage": "code_generation", "attempt": retries}}
            try:
                # Cancellation before expensive LLM call
                if sigkill_event and hasattr(sigkill_event, 'is_set') and sigkill_event.is_set():
                    break
                _t_codegen = _time.monotonic()
                final_code = await code_generator_fn(
                    data_model=data_model,
                    prompt=prompt,
                    schemas=schemas,
                    ds_clients=ds_clients,
                    excel_files=excel_files,
                    code_and_error_messages=code_and_error_messages,
                    memories="",
                    previous_messages="",
                    retries=retries,
                    prev_data_model_code_pair=None,
                    sigkill_event=sigkill_event,
                    code_context_builder=code_context_builder,
                )
                codegen_ms = round((_time.monotonic() - _t_codegen) * 1000.0, 1)
                yield {"type": "progress", "payload": {"stage": "code_generated", "attempt": retries, "code": final_code, "timing": False}}
            except Exception as e:
                msg = f"Code generation error: {str(e)}"
                code_and_error_messages.append((final_code, msg))
                yield {"type": "stdout", "payload": msg}
                retries += 1
                if retries < max_retries:
                    yield {"type": "progress", "payload": {"stage": "retry", "attempt": retries, "timing": False}}
                continue

            # Executing code
            yield {"type": "progress", "payload": {"stage": "data_query_execution", "attempt": retries}}
            try:
                # Cancellation before executing user code
                if sigkill_event and hasattr(sigkill_event, 'is_set') and sigkill_event.is_set():
                    break
                _t_exec = _time.monotonic()
                query_timings: List[dict] = []
                exec_df, execution_log, executed_queries = await self.execute_code_async(
                    code=final_code, ds_clients=ds_clients, excel_files=excel_files, captured_timings=query_timings
                )
                execution_ms = round((_time.monotonic() - _t_exec) * 1000.0, 1)
                yield {
                    "type": "progress",
                    "payload": {
                        "stage": "post_execution",
                        "attempt": retries,
                        "execution_ms": execution_ms,
                    },
                }
                executed_successfully = True
                break
            except Exception as e:
                msg = f"Execution error: {str(e)}"
                code_and_error_messages.append((final_code, msg))
                yield {"type": "stdout", "payload": msg}
                retries += 1
                if retries < max_retries:
                    yield {"type": "progress", "payload": {"stage": "retry", "attempt": retries, "timing": False}}
                continue

        # If cancelled, emit a final done with empty results to let caller stop cleanly
        if sigkill_event and hasattr(sigkill_event, 'is_set') and sigkill_event.is_set():
            yield {
                "type": "done",
                "payload": {
                    "df": pd.DataFrame(),
                    "code": final_code,
                    "errors": code_and_error_messages,
                    "execution_log": execution_log,
                    "executed_queries": [],
                    "query_timings": [],
                    "codegen_ms": None,
                    "execution_ms": None,
                },
            }
            return
        else:
            # If we never executed successfully (e.g., validation failed up to max retries),
            # signal failure by returning df=None so callers can treat as error.
            if not executed_successfully and code_and_error_messages:
                yield {
                    "type": "done",
                    "payload": {
                        "df": None,
                        "code": final_code,
                        "errors": code_and_error_messages,
                        "execution_log": execution_log,
                        "executed_queries": [],
                        "query_timings": [],
                        "codegen_ms": None,
                        "execution_ms": None,
                    },
                }
            else:
                # Emit a final done event carrying the results instead of returning values
                yield {
                    "type": "done",
                    "payload": {
                        "df": exec_df,
                        "code": final_code,
                        "errors": code_and_error_messages,
                        "execution_log": execution_log,
                        "executed_queries": executed_queries,
                        "query_timings": query_timings,
                        "codegen_ms": codegen_ms,
                        "execution_ms": execution_ms,
                    },
                }

    async def generate_and_execute_stream_v2(
        self,
        *,
        request: CodeGenRequest,
        ds_clients: Dict,
        excel_files: List,
        code_context_builder: Optional['CodeContextBuilder'] = None,
        code_generator_fn: Callable = None,
        sigkill_event=None,
        loadable_resolver_fn: Optional[Callable] = None,
    ):
        """
        V2: Typed context-based generator. Yields the same event shapes as v1.
        """
        retries = 0
        # Respect explicit values (including 0→1). `or 2` was swallowing
        # retries=0 and silently running two attempts.
        _req_retries = getattr(request, "retries", None)
        max_retries = max(1, int(_req_retries)) if _req_retries is not None else 2
        # Dedicated one-shot budget for security violations: on the FIRST block
        # we feed the coder corrective feedback and let it regenerate ONCE,
        # instead of dead-ending. A persistently-unsafe model can't loop forever.
        security_retry_budget = 1
        code_and_error_messages: List[Tuple[str, str]] = []
        final_code = ""
        exec_df = pd.DataFrame()
        execution_log = ""
        executed_successfully = False
        ctx: CodeGenContext = request.context
        # Derive prompt/schemas for legacy generator signature
        derived_prompt = ctx.user_prompt
        derived_interpreted_prompt = ctx.interpreted_prompt
        derived_schemas = ctx.schemas_excerpt

        # Hoisted so the wrapper's capture survives an exception inside
        # execute_code_async — the failure branch can surface the failing SQL.
        query_timings: List[dict] = []
        executed_queries: List[str] = []

        while retries < max_retries:
            if sigkill_event and hasattr(sigkill_event, 'is_set') and sigkill_event.is_set():
                break
            yield {"type": "progress", "payload": {"stage": "code_generation", "attempt": retries}}
            try:
                if sigkill_event and hasattr(sigkill_event, 'is_set') and sigkill_event.is_set():
                    break
                # Call code generator with typed context and legacy params populated from context
                _t_codegen = _time.monotonic()
                final_code = await code_generator_fn(
                    data_model={},
                    prompt=derived_prompt,
                    interpreted_prompt=derived_interpreted_prompt,
                    schemas=derived_schemas,
                    ds_clients=ds_clients,
                    excel_files=excel_files,
                    code_and_error_messages=code_and_error_messages,
                    memories="",
                    previous_messages="",
                    retries=retries,
                    prev_data_model_code_pair=None,
                    sigkill_event=sigkill_event,
                    code_context_builder=None,
                    context=ctx,
                )
                codegen_ms = round((_time.monotonic() - _t_codegen) * 1000.0, 1)
                yield {"type": "progress", "payload": {"stage": "code_generated", "attempt": retries, "code": final_code, "timing": False}}
            except Exception as e:
                msg = f"Code generation error: {str(e)}"
                code_and_error_messages.append((final_code, msg))
                yield {"type": "stdout", "payload": msg}
                retries += 1
                if retries < max_retries:
                    yield {"type": "progress", "payload": {"stage": "retry", "attempt": retries, "timing": False}}
                continue

            # Pre-resolve load_step()/load_entity() references before exec. A
            # resolution miss is folded into the error feedback so the coder
            # regenerates (same path as a bad column), rather than failing the
            # sandbox call.
            loadables = None
            if loadable_resolver_fn is not None and final_code:
                try:
                    step_refs, entity_refs = extract_loadable_refs(final_code)
                    if step_refs or entity_refs:
                        resolved = await loadable_resolver_fn(step_refs, entity_refs)
                        loadables = {
                            "steps": resolved.get("steps", {}),
                            "entities": resolved.get("entities", {}),
                        }
                        resolve_errors = resolved.get("errors") or []
                        if resolve_errors:
                            msg = "Loadable resolution failed: " + " | ".join(resolve_errors)
                            code_and_error_messages.append((final_code, msg))
                            yield {"type": "stdout", "payload": msg}
                            retries += 1
                            if retries < max_retries:
                                yield {"type": "progress", "payload": {"stage": "retry", "attempt": retries, "timing": False}}
                            continue
                except Exception as e:
                    yield {"type": "stdout", "payload": f"Loadable resolution error: {str(e)}"}

            yield {"type": "progress", "payload": {"stage": "data_query_execution", "attempt": retries}}
            try:
                if sigkill_event and hasattr(sigkill_event, 'is_set') and sigkill_event.is_set():
                    break
                _t_exec = _time.monotonic()
                # Fresh per-attempt capture — on success we keep these; on
                # exception the wrapper's partial writes still reach the outer
                # scope so the failure branch can surface the failing SQL / DB error.
                query_timings.clear()
                executed_queries.clear()
                exec_df, execution_log, _ = await self.execute_code_async(
                    code=final_code, ds_clients=ds_clients, excel_files=excel_files,
                    captured_timings=query_timings, captured_queries=executed_queries,
                    loadables=loadables,
                )
                execution_ms = round((_time.monotonic() - _t_exec) * 1000.0, 1)
                yield {
                    "type": "progress",
                    "payload": {
                        "stage": "post_execution",
                        "attempt": retries,
                        "execution_ms": execution_ms,
                    },
                }
                # Treat None/empty-columns DataFrame as a soft failure so the
                # LLM gets a chance to fix defensive stub code that never
                # actually calls execute_query — but only when there's an SQL
                # client or file to query against. URL-fetch-only runs (no
                # ds_clients, no excel_files) legitimately may have nothing
                # to return; the printed output is the deliverable.
                _has_queryable_source = bool(ds_clients) or bool(excel_files)
                if _has_queryable_source and (exec_df is None or not hasattr(exec_df, 'columns') or len(exec_df.columns) == 0):
                    msg = (
                        "Code executed but returned None or an empty DataFrame (0 columns). "
                        "You MUST call ds_clients[\"<client_key>\"].execute_query(...) using the "
                        "EXACT client_key from <connection_clients> and return the resulting DataFrame. "
                        "Do NOT return an empty pd.DataFrame() as a defensive fallback and do NOT "
                        "wrap the query in 'if client is None' branches — the client_key is guaranteed to exist."
                    )
                    code_and_error_messages.append((final_code, msg))
                    yield {"type": "stdout", "payload": msg}
                    retries += 1
                    if retries < max_retries:
                        yield {"type": "progress", "payload": {"stage": "retry", "attempt": retries, "timing": False}}
                    continue
                if exec_df is None:
                    exec_df = pd.DataFrame()
                executed_successfully = True
                break
            except CodeSecurityError as e:
                # Tag security violations distinctly so callers can audit them
                violation_type = "unsafe_python" if isinstance(e, UnsafePythonError) else "unsafe_sql"
                # Always emit the structured event (FE/audit consume this) on
                # EVERY block, including the corrective retry.
                yield {"type": "security_violation", "payload": {"violation_type": violation_type, "message": str(e), "code_snippet": final_code[:500]}}
                # SELF-HEAL ONCE: on the first violation, feed the coder a
                # corrective message and regenerate — most slips are a single
                # stray locals()/getattr the model will drop when told. If the
                # budget is spent (it violated again), dead-end as before so a
                # persistently-unsafe model can't loop forever.
                if security_retry_budget > 0:
                    security_retry_budget -= 1
                    heal_msg = (
                        f"Your code was blocked by the sandbox security check: {str(e)}. "
                        "Regenerate the function WITHOUT the forbidden construct(s). "
                        "Do NOT call locals(), globals(), vars(), getattr/setattr/delattr/hasattr, "
                        "eval, exec, compile, open, input, or __import__, and do NOT import os/sys/"
                        "subprocess or any network/process module. To check if a variable exists use "
                        "try/except NameError or a sentinel default, and access object fields with "
                        "plain dot notation."
                    )
                    code_and_error_messages.append((final_code, heal_msg))
                    yield {"type": "stdout", "payload": f"Security violation ({violation_type}) — regenerating once without the forbidden construct."}
                    retries += 1
                    if retries < max_retries:
                        yield {"type": "progress", "payload": {"stage": "retry", "attempt": retries, "timing": False}}
                    # If max_retries leaves no room to regenerate, fall through to
                    # end the loop (the while condition will stop us).
                    continue
                msg = f"Security violation ({violation_type}): {str(e)}"
                code_and_error_messages.append((final_code, msg))
                yield {"type": "stdout", "payload": msg}
                # Budget spent — not retryable any further.
                break
            except Exception as e:
                msg = f"Execution error: {str(e)}"
                code_and_error_messages.append((final_code, msg))
                yield {"type": "stdout", "payload": msg}
                retries += 1
                if retries < max_retries:
                    yield {"type": "progress", "payload": {"stage": "retry", "attempt": retries, "timing": False}}
                continue

        if sigkill_event and hasattr(sigkill_event, 'is_set') and sigkill_event.is_set():
            yield {
                "type": "done",
                "payload": {
                    "df": pd.DataFrame(),
                    "code": final_code,
                    "errors": code_and_error_messages,
                    "execution_log": execution_log,
                    "executed_queries": [],
                    "query_timings": [],
                    "codegen_ms": None,
                    "execution_ms": None,
                },
            }
            return
        else:
            if not executed_successfully and code_and_error_messages:
                yield {
                    "type": "done",
                    "payload": {
                        "df": None,
                        "code": final_code,
                        "errors": code_and_error_messages,
                        "execution_log": execution_log,
                        "executed_queries": executed_queries,
                        "query_timings": query_timings,
                        "codegen_ms": None,
                        "execution_ms": None,
                    },
                }
            else:
                yield {
                    "type": "done",
                    "payload": {
                        "df": exec_df,
                        "code": final_code,
                        "errors": code_and_error_messages,
                        "execution_log": execution_log,
                        "executed_queries": executed_queries,
                        "query_timings": query_timings,
                        "codegen_ms": codegen_ms,
                        "execution_ms": execution_ms,
                    },
                }

    async def execute_and_update_step(self,
                              data_model: Dict,
                              code_generator_fn: Callable,
                              db_clients: Dict = None,
                              excel_files: List = None,
                              step=None,  # Optional override for current step
                              **generator_kwargs) -> bool:
        """
        Execute code generation/execution process and update the step with results

        Args:
            data_model: The data model to generate code for
            code_generator_fn: Function that generates code
            db_clients: Database clients
            excel_files: Excel files
            step: Override for the step object (uses self.step if None)
            **generator_kwargs: Additional arguments to pass to code_generator_fn

        Returns:
            Boolean indicating if execution was successful
        """
        # Use provided step or fall back to instance step
        current_step = step or self.step
        if not current_step:
            if self.logger:
                self.logger.error("No step provided for execute_and_update_step")
            return False

        df, final_code, code_and_error_messages = await self.generate_and_execute_with_retries(
            data_model=data_model,
            code_generator_fn=code_generator_fn,
            db_clients=db_clients,
            excel_files=excel_files,
            step=current_step,
            max_retries=self.organization_settings.get_config("limit_code_retries").value,
            **generator_kwargs
        )
        
        # Check if the DataFrame has columns, which indicates success even if empty
        if len(df.columns) > 0:
            # Format the data for widget display
            widget_data = self.format_df_for_widget(df)
            
            # Update step with data
            try:
                await self.project_manager.update_step_with_data(self.db, current_step, widget_data)
            except Exception as e:
                if self.logger:
                    self.logger.error(f"Error updating step with data: {str(e)}")
                return False
            return True
        else:
            # Handle error case if all retries failed and we have no columns
            try:
                if self.report and self.head_completion and self.widget:
                    await self.project_manager.create_message(
                        report=self.report,
                        db=self.db,
                        message="I faced some issues while generating data. The result had no columns. Can you try explaining again?",
                        status="success",
                        completion=self.head_completion,
                        widget=self.widget,
                        role="ai_agent"
                    )
            except Exception as e:
                if self.logger:
                    self.logger.error(f"Error creating error message: {str(e)}")
            return False
