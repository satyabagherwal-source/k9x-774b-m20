> **Canonical Learning Artifact**: `07_PROJECT_LEARNING/nasiko-labs-nasiko-learnings.md`  
> **Source**: github ([https://github.com/Nasiko-Labs/nasiko](https://github.com/Nasiko-Labs/nasiko))  
> **Source Version**: `9f84200c`  
> **License**: NOASSERTION  
> **Synthesized By**: zero-clone-structural-synthesizer  
> **Timestamp**: 2026-11-12T02:33:18.504Z  
> **Learning ID**: `learn-github-nasiko-labs-nasiko`  
> **Pipeline Version**: `2.0.0`  
> **Status**: VERIFIED_EMPIRICAL_INTELLIGENCE  
> **Data Governance**: CLASSIFICATION: PUBLIC. Sanitized against PII/secrets.  
> **Policy Invariant**: Strictly for engineering retrieval and architecture documentation. Distillation prohibited.  

---

# Forensic Learning Record (Deep Inspection): Nasiko-Labs/nasiko

> **Canonical Artifact**: `07_PROJECT_LEARNING/nasiko-labs-nasiko-learnings.md`  
> **Source Platform**: GitHub ([https://github.com/Nasiko-Labs/nasiko](https://github.com/Nasiko-Labs/nasiko))  
> **Harvest Method**: Full-Spectrum Deep Extraction (Patches, Diffs, Source Code, Post-Mortems)  
> **Harvest Timestamp**: 2026-11-12T02:33:18.260Z  
> **Compliance State**: Free Tier Guaranteed | Strict Rate-Limit Backoff Honored  

---

## 1. Context & Architectural Overview
- **Repository / Resource**: `Nasiko-Labs/nasiko`
- **Description**: The Open Runtime for AI Agents
- **Primary Language / Ecosystem**: Rust
- **Discovered Manifests / Configurations**: Cargo.toml, README.md
- **Stars / Engagement**: 11961 stars

---

## 2. Multi-Dimensional 8-Axis Investigation & Real Code Patches

### D1: Architecture & Structural Boundaries
- Entry configurations inspected via direct stream: Cargo.toml, README.md.
- Evaluated system abstractions and modular contracts.

### Core Architecture Module: `agents/assistant-agent/nasiko_state.py`
```
"""Durable agent state over the platform's state API.

An A2A agent normally keeps its tasks in process memory, so a restart loses paused work
and the agent cannot run as more than one replica. This module is a drop-in replacement
that keeps that state in the platform instead.

    from nasiko_state import make_task_store

    handler = DefaultRequestHandler(
        agent_executor=MyExecutor(),
        task_store=make_task_store(),   # was: InMemoryTaskStore()
        agent_card=card,
    )
    app = Starlette(routes=...)
    install_shutdown_hooks(app)         # flush pending writes when the server stops

Configuration comes from the environment the platform injects into the container:

    NASIKO_STATE_URL     base URL of the state API (ends in /api/agent-state). Unset means the
                         platform provides no store, and every factory here returns the
                         in-memory implementation the SDK ships, so the same code runs locally.
    NASIKO_AGENT_TOKEN   this agent's state credential. It is the only one accepted: the MCP
                         gateway token is a different credential and is never used here.

Write guarantee (see NasikoTaskStore): a save that changes ``task.status.state`` is on the
server before ``save()`` returns. Other saves are coalesced to at most one write per
COALESCE_WINDOW_SECONDS per task and written on the next state change, by a background timer,
and by ``aclose()``. Nothing calls ``aclose()`` on its own: ``install_shutdown_hooks(app)`` runs
it when the server shuts down (uvicorn does that on SIGTERM and Ctrl-C), and an atexit hook
covers a normal interpreter exit. A hard crash (SIGKILL, power loss), or a SIGTERM in a process
without those hooks, can lose that window of non-status updates; so can an update the platform
could not take for PENDING_MAX_AGE_SECONDS, which is discarded rather than written late.

Both a2a-sdk majors are supported (0.3.x pydantic tasks and 1.x protobuf tasks). The langgraph
checkpointer needs the optional langgraph-checkpoint package; nothing else does.

This file is vendored: agent images are built from the agent's own directory only, so each
agent keeps a committed copy next to its main module. oss/agents/common is canonical and
oss/agents/common/check_vendored.py fails when a copy drifts.
"""

from __future__ import annotations

import asyncio
import atexit
import base64
import contextlib
import functools
import json
import logging
import os
import random
import signal
import threading
import time
from collections import OrderedDict
from collections.abc import AsyncIterator, Callable, Iterator, Mapping, Sequence
from dataclasses import dataclass, fields
from typing import Any, Generic, TypeVar
from urllib.parse import quote, urlsplit

import httpx
from a2a.server.tasks import InMemoryTaskStore, TaskStore
from a2a.types import Task

try:
    from a2a.types import a2a_pb2 as _a2a_pb2  # a2a-sdk 1.x: tasks are protobuf messages
except ImportError:
    _a2a_pb2 = None  # a2a-sdk 0.3.x: tasks are pydantic models

try:
    from langgraph.checkpoint.base import (
        WRITES_IDX_MAP,
        BaseCheckpointSaver,
        CheckpointTuple,
        get_checkpoint_metadata,
    )

    _LANGGRAPH_AVAILABLE = True
except ImportError:
    # langgraph is optional: only agents that checkpoint with it need the package.
    BaseCheckpointSaver = object  # type: ignore[assignment,misc]
    _LANGGRAPH_AVAILABLE = False

logger = logging.getLogger("nasiko_state")

STATE_URL_ENV = "NASIKO_STATE_URL"
AGENT_TOKEN_ENV = "NASIKO_AGENT_TOKEN"

CLIENT_NAME = "nasiko_state.py/1"

CONNECT_TIMEOUT_SECONDS = 2.0
READ_TIMEOUT_SECONDS = 10.0
RETRY_ATTEMPTS = 3
RETRY_BACKOFF_SECONDS = 0.2
# A rate-limited (429) request is retried after the Retry-After the server names, waiting at most
# MAX_RETRY_AFTER_SECONDS per attempt and RATE_LIMIT_BUDGET_SECONDS in all before the 429 surfaces.
# The platform's limit is a per-minute window shared by every replica of the agent, so a wait of a
# few seconds is usually enough, and a turn that keeps failing for half a minute should fail.
MAX_RETRY_AFTER_SECONDS = 5.0
RATE_LIMIT_BUDGET_SECONDS = 30.0
# The wait when a 429 names none (or names an HTTP date), and the shortest wait ever taken, so a
# server answering "Retry-After: 0" cannot turn the budget into a busy loop.
RATE_LIMIT_DEFAULT_WAIT_SECONDS = 1.0
RATE_LIMIT_MIN_WAIT_SECONDS = 0.5
# Relative spread of each 429 wait, so replicas limited at the same moment do not retry in step.
RATE_LIMIT_JITTER = 0.2
MAX_PAGE_SIZE = 100
DEFAULT_PAGE_SIZE = 50

# Saves that do not change a task's state are written at most once per window per task.
COALESCE_WINDOW_SECONDS = 0.5
# A deferred write that failed is retried after a delay that doubles per failure, up to this.
DEFERRED_RETRY_MAX_SECONDS = 10.0
# An unwritten update this old is presumed superseded (the task has most likely moved on to
# another replica), so it is discarded instead of being written over whatever is there now.
PENDING_MAX_AGE_SECONDS = 60.0
# Exiting with the platform unreachable must not hang for every pending task.
EXIT_FLUSH_BUDGET_SECONDS = 10.0
# A task id just looked up and not found reads as missing for this long without asking again.
# a2a-sdk 1.x looks a new task's id up several times before the task's first save, and that id is
# one the SDK generated for the request, so no other replica can have created the task meanwhile.
# A task that exists is always read from the server: another replica may have changed it.
ABSENT_CACHE_SECONDS = 2.0
# Bound on tasks whose write state is remembered. Forgetting an idle one costs its next write the
# version check: having no version to match, that write is unconditional.
MAX_TRACKED_TASKS = 4096
# The status a shell reports for a process ended by SIGTERM; kept when SIGTERM becomes an exit.
SIGTERM_EXIT_STATUS = 128 + signal.SIGTERM

# The order the registration contract spells its capability lists in.
CAPABILITY_ORDER = ("tasks", "kv")
# A startup registration that failed for a reason that may pass (no answer, 5xx, 429) is retried
# in the background after a delay that doubles from the first of these up to the second.
REGISTER_RETRY_FIRST_SECONDS = 1.0
REGISTER_RETRY_MAX_SECONDS = 60.0
REGISTER_THREAD_NAME = "nasiko-state-register"

T = TypeVar("T")


class NasikoStateError(Exception):
    """The state API refused a request or could not be reached.

    ``status`` and ``body`` carry the HTTP answer. Both are None for transport and
    configuration failures, where there was no answer.
    """

    def __init__(self, message: str, *, status: int | None = None, body: str | None = None):
        super().__init__(message)
        self.status = status
        self.body = body


class NasikoStateMalformedRow(NasikoStateError):
    """A stored row cannot be read back as what it claims to be.

    Raised for a task written by the other a2a-sdk major (or not by this module at all), and for a
    damaged record. Never answered with a half-decoded object.
    """


class NasikoStateTooLarge(NasikoStateError):
    """The state API refused a value above its size limit (HTTP 413). Retrying cannot help."""


class NasikoStateConflict(NasikoStateError):
    """An ``If-Match`` precondition failed: another writer changed the row first.

    ``current_version`` is the version the server holds, or None if the body did not say.
    """

    def __init__(self, message: str, *, current_version: int | None, body: str | None = None):
        super().__init__(message, status=412, body=body)
        self.current_version = current_version


@dataclass(frozen=True)
class WriteReceipt:
    """What the server answers to a PUT. Task and KV writes share the three fields."""

    version: int
    updated_at: str
    expires_at: str


@dataclass(frozen=True)
class TaskRecord:
    """One stored task. ``body`` is the SDK's serialized Task, opaque to the server."""

    task_id: str
    context_id: str | None
    state: str
    body: Any
    version: int
    updated_at: str
    expires_at: str


@dataclass(frozen=True)
class KVRecord:
    """One stored key. ``value`` is opaque JSON."""

    key: str
    value: Any
    version: int
    updated_at: str
    expires_at: str


@dataclass(frozen=True)
class Page(Generic[T]):
    """One page of a listing. ``next_cursor`` is None on the last page."""

    items: list[T]
    next_cursor: str | None


# --- Operations ---------------------------------------------------------------------------------
#
# Each state API call is described once, as data, and executed by the sync or the async client
# method. That keeps request building, status handling and parsing in a single place.

_UNSET: Any = object()


@dataclass(frozen=True)
class _Operation:
    """One state API call: how to send it and how to read the answer."""

    method: str
    path: str
    parse: Callable[[httpx.Response], Any]
    ok_status: int = 200
    params: Mapping[str, str | int | None] | None = None
    json: Any = _UNSET
    if_match: int | None = None
    # A write names the capability it needs registered; reads leave it None.
    capability: str | None = None
    # What a 404 means. Left unset, a 404 is an error like any other status.
    when_missing: Any = _UNSET
    # time.monotonic() by which the call, retries included, must be over. None means no deadline.
    deadline: float | None = None

    def request_kwargs(self) -> dict[str, Any]:
        kwargs: dict[str, Any] = {"method": self.method, "url": self.path}
        if self.params:
            kwargs["params"] = {key: value for key, value in self.params.items() if value is not None}
        if self.json is not _UNSET:
            kwargs["json"] = self.json
        if self.if_match is not None:
            kwargs["headers"] = {"If-Match": str(self.if_match)}
        if self.deadline is not None:
            kwargs["timeout"] = min(self.seconds_left(), READ_TIMEOUT_SECONDS)
        return kwargs

    def seconds_left(self) -> 
```

### Core Architecture Module: `agents/claude-sdk/src/nasiko_state.py`
```
"""Durable agent state over the platform's state API.

An A2A agent normally keeps its tasks in process memory, so a restart loses paused work
and the agent cannot run as more than one replica. This module is a drop-in replacement
that keeps that state in the platform instead.

    from nasiko_state import make_task_store

    handler = DefaultRequestHandler(
        agent_executor=MyExecutor(),
        task_store=make_task_store(),   # was: InMemoryTaskStore()
        agent_card=card,
    )
    app = Starlette(routes=...)
    install_shutdown_hooks(app)         # flush pending writes when the server stops

Configuration comes from the environment the platform injects into the container:

    NASIKO_STATE_URL     base URL of the state API (ends in /api/agent-state). Unset means the
                         platform provides no store, and every factory here returns the
                         in-memory implementation the SDK ships, so the same code runs locally.
    NASIKO_AGENT_TOKEN   this agent's state credential. It is the only one accepted: the MCP
                         gateway token is a different credential and is never used here.

Write guarantee (see NasikoTaskStore): a save that changes ``task.status.state`` is on the
server before ``save()`` returns. Other saves are coalesced to at most one write per
COALESCE_WINDOW_SECONDS per task and written on the next state change, by a background timer,
and by ``aclose()``. Nothing calls ``aclose()`` on its own: ``install_shutdown_hooks(app)`` runs
it when the server shuts down (uvicorn does that on SIGTERM and Ctrl-C), and an atexit hook
covers a normal interpreter exit. A hard crash (SIGKILL, power loss), or a SIGTERM in a process
without those hooks, can lose that window of non-status updates; so can an update the platform
could not take for PENDING_MAX_AGE_SECONDS, which is discarded rather than written late.

Both a2a-sdk majors are supported (0.3.x pydantic tasks and 1.x protobuf tasks). The langgraph
checkpointer needs the optional langgraph-checkpoint package; nothing else does.

This file is vendored: agent images are built from the agent's own directory only, so each
agent keeps a committed copy next to its main module. oss/agents/common is canonical and
oss/agents/common/check_vendored.py fails when a copy drifts.
"""

from __future__ import annotations

import asyncio
import atexit
import base64
import contextlib
import functools
import json
import logging
import os
import random
import signal
import threading
import time
from collections import OrderedDict
from collections.abc import AsyncIterator, Callable, Iterator, Mapping, Sequence
from dataclasses import dataclass, fields
from typing import Any, Generic, TypeVar
from urllib.parse import quote, urlsplit

import httpx
from a2a.server.tasks import InMemoryTaskStore, TaskStore
from a2a.types import Task

try:
    from a2a.types import a2a_pb2 as _a2a_pb2  # a2a-sdk 1.x: tasks are protobuf messages
except ImportError:
    _a2a_pb2 = None  # a2a-sdk 0.3.x: tasks are pydantic models

try:
    from langgraph.checkpoint.base import (
        WRITES_IDX_MAP,
        BaseCheckpointSaver,
        CheckpointTuple,
        get_checkpoint_metadata,
    )

    _LANGGRAPH_AVAILABLE = True
except ImportError:
    # langgraph is optional: only agents that checkpoint with it need the package.
    BaseCheckpointSaver = object  # type: ignore[assignment,misc]
    _LANGGRAPH_AVAILABLE = False

logger = logging.getLogger("nasiko_state")

STATE_URL_ENV = "NASIKO_STATE_URL"
AGENT_TOKEN_ENV = "NASIKO_AGENT_TOKEN"

CLIENT_NAME = "nasiko_state.py/1"

CONNECT_TIMEOUT_SECONDS = 2.0
READ_TIMEOUT_SECONDS = 10.0
RETRY_ATTEMPTS = 3
RETRY_BACKOFF_SECONDS = 0.2
# A rate-limited (429) request is retried after the Retry-After the server names, waiting at most
# MAX_RETRY_AFTER_SECONDS per attempt and RATE_LIMIT_BUDGET_SECONDS in all before the 429 surfaces.
# The platform's limit is a per-minute window shared by every replica of the agent, so a wait of a
# few seconds is usually enough, and a turn that keeps failing for half a minute should fail.
MAX_RETRY_AFTER_SECONDS = 5.0
RATE_LIMIT_BUDGET_SECONDS = 30.0
# The wait when a 429 names none (or names an HTTP date), and the shortest wait ever taken, so a
# server answering "Retry-After: 0" cannot turn the budget into a busy loop.
RATE_LIMIT_DEFAULT_WAIT_SECONDS = 1.0
RATE_LIMIT_MIN_WAIT_SECONDS = 0.5
# Relative spread of each 429 wait, so replicas limited at the same moment do not retry in step.
RATE_LIMIT_JITTER = 0.2
MAX_PAGE_SIZE = 100
DEFAULT_PAGE_SIZE = 50

# Saves that do not change a task's state are written at most once per window per task.
COALESCE_WINDOW_SECONDS = 0.5
# A deferred write that failed is retried after a delay that doubles per failure, up to this.
DEFERRED_RETRY_MAX_SECONDS = 10.0
# An unwritten update this old is presumed superseded (the task has most likely moved on to
# another replica), so it is discarded instead of being written over whatever is there now.
PENDING_MAX_AGE_SECONDS = 60.0
# Exiting with the platform unreachable must not hang for every pending task.
EXIT_FLUSH_BUDGET_SECONDS = 10.0
# A task id just looked up and not found reads as missing for this long without asking again.
# a2a-sdk 1.x looks a new task's id up several times before the task's first save, and that id is
# one the SDK generated for the request, so no other replica can have created the task meanwhile.
# A task that exists is always read from the server: another replica may have changed it.
ABSENT_CACHE_SECONDS = 2.0
# Bound on tasks whose write state is remembered. Forgetting an idle one costs its next write the
# version check: having no version to match, that write is unconditional.
MAX_TRACKED_TASKS = 4096
# The status a shell reports for a process ended by SIGTERM; kept when SIGTERM becomes an exit.
SIGTERM_EXIT_STATUS = 128 + signal.SIGTERM

# The order the registration contract spells its capability lists in.
CAPABILITY_ORDER = ("tasks", "kv")
# A startup registration that failed for a reason that may pass (no answer, 5xx, 429) is retried
# in the background after a delay that doubles from the first of these up to the second.
REGISTER_RETRY_FIRST_SECONDS = 1.0
REGISTER_RETRY_MAX_SECONDS = 60.0
REGISTER_THREAD_NAME = "nasiko-state-register"

T = TypeVar("T")


class NasikoStateError(Exception):
    """The state API refused a request or could not be reached.

    ``status`` and ``body`` carry the HTTP answer. Both are None for transport and
    configuration failures, where there was no answer.
    """

    def __init__(self, message: str, *, status: int | None = None, body: str | None = None):
        super().__init__(message)
        self.status = status
        self.body = body


class NasikoStateMalformedRow(NasikoStateError):
    """A stored row cannot be read back as what it claims to be.

    Raised for a task written by the other a2a-sdk major (or not by this module at all), and for a
    damaged record. Never answered with a half-decoded object.
    """


class NasikoStateTooLarge(NasikoStateError):
    """The state API refused a value above its size limit (HTTP 413). Retrying cannot help."""


class NasikoStateConflict(NasikoStateError):
    """An ``If-Match`` precondition failed: another writer changed the row first.

    ``current_version`` is the version the server holds, or None if the body did not say.
    """

    def __init__(self, message: str, *, current_version: int | None, body: str | None = None):
        super().__init__(message, status=412, body=body)
        self.current_version = current_version


@dataclass(frozen=True)
class WriteReceipt:
    """What the server answers to a PUT. Task and KV writes share the three fields."""

    version: int
    updated_at: str
    expires_at: str


@dataclass(frozen=True)
class TaskRecord:
    """One stored task. ``body`` is the SDK's serialized Task, opaque to the server."""

    task_id: str
    context_id: str | None
    state: str
    body: Any
    version: int
    updated_at: str
    expires_at: str


@dataclass(frozen=True)
class KVRecord:
    """One stored key. ``value`` is opaque JSON."""

    key: str
    value: Any
    version: int
    updated_at: str
    expires_at: str


@dataclass(frozen=True)
class Page(Generic[T]):
    """One page of a listing. ``next_cursor`` is None on the last page."""

    items: list[T]
    next_cursor: str | None


# --- Operations ---------------------------------------------------------------------------------
#
# Each state API call is described once, as data, and executed by the sync or the async client
# method. That keeps request building, status handling and parsing in a single place.

_UNSET: Any = object()


@dataclass(frozen=True)
class _Operation:
    """One state API call: how to send it and how to read the answer."""

    method: str
    path: str
    parse: Callable[[httpx.Response], Any]
    ok_status: int = 200
    params: Mapping[str, str | int | None] | None = None
    json: Any = _UNSET
    if_match: int | None = None
    # A write names the capability it needs registered; reads leave it None.
    capability: str | None = None
    # What a 404 means. Left unset, a 404 is an error like any other status.
    when_missing: Any = _UNSET
    # time.monotonic() by which the call, retries included, must be over. None means no deadline.
    deadline: float | None = None

    def request_kwargs(self) -> dict[str, Any]:
        kwargs: dict[str, Any] = {"method": self.method, "url": self.path}
        if self.params:
            kwargs["params"] = {key: value for key, value in self.params.items() if value is not None}
        if self.json is not _UNSET:
            kwargs["json"] = self.json
        if self.if_match is not None:
            kwargs["headers"] = {"If-Match": str(self.if_match)}
        if self.deadline is not None:
            kwargs["timeout"] = min(self.seconds_left(), READ_TIMEOUT_SECONDS)
        return kwargs

    def seconds_left(self) -> 
```

### Core Architecture Module: `agents/common/js/nasiko-state/src/client.js`
```
/**
 * Typed client for the platform's state API (see oss/agents/common/nasiko_state.py for the
 * Python twin). One method per endpoint; failures raise the typed errors from errors.js.
 *
 * Connection errors and 5xx answers are retried (RETRY_ATTEMPTS attempts in total, exponential
 * backoff) because every call is idempotent; so is a 429, after the Retry-After it names when
 * that is at most MAX_RETRY_AFTER_SECONDS. Other 4xx answers never are. A conditional write whose
 * outcome is unknown (the request went out and no answer came back) is not repeated: it would
 * conflict with its own first attempt.
 *
 * The first write of each kind (tasks, kv) registers the agent with the platform, once.
 */

import {
  NasikoStateConflict,
  NasikoStateError,
  NasikoStateNotFound,
  NasikoStateRateLimited,
  NasikoStateTooLarge,
  NasikoStateUnauthorized,
} from "./errors.js";

export const STATE_URL_ENV = "NASIKO_STATE_URL";
export const AGENT_TOKEN_ENV = "NASIKO_AGENT_TOKEN";
export const CLIENT_NAME = "nasiko-state.js/1";

export const RETRY_ATTEMPTS = 3;
export const RETRY_BACKOFF_MS = 200;
export const REQUEST_TIMEOUT_MS = 10_000;
// The longest Retry-After a rate-limited request waits out; a longer one surfaces the 429.
export const MAX_RETRY_AFTER_SECONDS = 5;
export const MAX_PAGE_SIZE = 100;

// The order the registration contract spells its capability lists in.
const CAPABILITY_ORDER = ["tasks", "kv"];

// Failures that happen before the request is sent, so repeating a conditional write is safe.
const BEFORE_SEND_CODES = new Set(["ECONNREFUSED", "ENOTFOUND", "EAI_AGAIN", "UND_ERR_CONNECT_TIMEOUT"]);

/**
 * Escape everything but unreserved characters, so '/', ':' and '%' in an id stay inert. Matches
 * the Python store's encoding, which both use for URL segments and composite keys.
 * @param {string} value
 */
export function percentEncode(value) {
  return encodeURIComponent(value).replace(/[!'()*]/g, (c) => "%" + c.charCodeAt(0).toString(16).toUpperCase());
}

/**
 * @typedef {{version: number, updatedAt: string, expiresAt: string}} WriteReceipt
 * @typedef {{taskId: string, contextId: string | null, state: string, body: any, version: number,
 *   updatedAt: string, expiresAt: string}} TaskRecord
 * @typedef {{key: string, value: any, version: number, updatedAt: string, expiresAt: string}} KVRecord
 * @template T
 * @typedef {{items: T[], nextCursor: string | null}} Page
 */

export class NasikoStateClient {
  #baseUrl;
  #headers;
  #clientName;
  #fetch;
  #retryBackoffMs;
  #requestTimeoutMs;
  #registered = new Set();
  #registering = Promise.resolve();

  /**
   * @param {string} baseUrl base URL of the state API (ends in /api/agent-state)
   * @param {string} token this agent's state credential
   * @param {{clientName?: string, fetch?: typeof fetch, retryBackoffMs?: number,
   *   requestTimeoutMs?: number}} [options]
   */
  constructor(baseUrl, token, options = {}) {
    if (!/^https?:\/\/[^/]/.test(baseUrl)) {
      throw new NasikoStateError(`${STATE_URL_ENV} must be an http(s) URL, got ${JSON.stringify(baseUrl)}`);
    }
    if (!token) throw new NasikoStateError("the state API needs an agent token and none was given");
    this.#baseUrl = baseUrl.replace(/\/+$/, "");
    this.#clientName = options.clientName ?? CLIENT_NAME;
    this.#headers = { Authorization: `Bearer ${token}`, "User-Agent": this.#clientName };
    this.#fetch = options.fetch ?? globalThis.fetch;
    this.#retryBackoffMs = options.retryBackoffMs ?? RETRY_BACKOFF_MS;
    this.#requestTimeoutMs = options.requestTimeoutMs ?? REQUEST_TIMEOUT_MS;
  }

  /**
   * Build a client from the platform's environment, or null when it provides no state API.
   * @param {Record<string, string | undefined>} [env]
   * @returns {NasikoStateClient | null}
   */
  static fromEnv(env = process.env) {
    const url = (env[STATE_URL_ENV] ?? "").trim();
    if (!url) return null;
    const token = (env[AGENT_TOKEN_ENV] ?? "").trim();
    if (!token) {
      throw new NasikoStateError(
        `${STATE_URL_ENV} is set but ${AGENT_TOKEN_ENV} is empty or missing: the state API needs ` +
          `this agent's state credential, which the platform injects as ${AGENT_TOKEN_ENV}`,
      );
    }
    return new NasikoStateClient(url, token);
  }

  toString() {
    return `NasikoStateClient(${this.#baseUrl})`;
  }

  // --- registration -------------------------------------------------------------------------

  /**
   * Tell the platform which kinds of state this agent keeps. Writes do this on their own.
   * @param {string[]} capabilities
   * @param {string} [clientName]
   */
  async register(capabilities, clientName) {
    await this.#request("POST", "/register", {
      json: { capabilities: [...capabilities], client: clientName ?? this.#clientName },
      okStatus: 204,
    });
    for (const capability of capabilities) this.#registered.add(capability);
  }

  // --- tasks --------------------------------------------------------------------------------

  /**
   * Create or replace a task.
   * @param {string} taskId
   * @param {{contextId: string | null, state: string, body: any, ifMatch?: number | null}} fields
   * @returns {Promise<WriteReceipt>}
   */
  async putTask(taskId, { contextId, state, body, ifMatch = null }) {
    await this.#ensureRegistered("tasks");
    const data = await this.#request("PUT", `/tasks/${percentEncode(taskId)}`, {
      json: { context_id: contextId, state, body },
      ifMatch,
    });
    return receiptFrom(data);
  }

  /** @returns {Promise<TaskRecord | null>} */
  async getTask(taskId) {
    const data = await this.#request("GET", `/tasks/${percentEncode(taskId)}`, { whenMissing: null });
    return data === null ? null : taskRecordFrom(data);
  }

  /** Delete a task. False means there was no such task. */
  async deleteTask(taskId, { ifMatch = null } = {}) {
    await this.#ensureRegistered("tasks");
    return this.#delete(`/tasks/${percentEncode(taskId)}`, ifMatch);
  }

  /**
   * @param {{contextId?: string | null, state?: string | null, limit?: number, cursor?: string | null}} [filters]
   * @returns {Promise<Page<TaskRecord>>}
   */
  async listTasks({ contextId, state, limit, cursor } = {}) {
    const data = await this.#request("GET", "/tasks", {
      query: { context_id: contextId, state, limit, cursor },
    });
    return pageFrom(data, taskRecordFrom);
  }

  // --- key-value ----------------------------------------------------------------------------

  /**
   * @param {string} key
   * @param {any} value opaque JSON
   * @param {{ifMatch?: number | null}} [options]
   * @returns {Promise<WriteReceipt>}
   */
  async putKv(key, value, { ifMatch = null } = {}) {
    await this.#ensureRegistered("kv");
    const data = await this.#request("PUT", `/kv/${percentEncode(key)}`, { json: { value }, ifMatch });
    return receiptFrom(data);
  }

  /** @returns {Promise<KVRecord | null>} */
  async getKv(key) {
    const data = await this.#request("GET", `/kv/${percentEncode(key)}`, { whenMissing: null });
    return data === null ? null : kvRecordFrom(data);
  }

  /** Delete a key. False means there was no such key. */
  async deleteKv(key, { ifMatch = null } = {}) {
    await this.#ensureRegistered("kv");
    return this.#delete(`/kv/${percentEncode(key)}`, ifMatch);
  }

  /**
   * @param {{prefix?: string | null, limit?: number, cursor?: string | null}} [filters]
   * @returns {Promise<Page<KVRecord>>}
   */
  async listKv({ prefix, limit, cursor } = {}) {
    const data = await this.#request("GET", "/kv", { query: { prefix, limit, cursor } });
    return pageFrom(data, kvRecordFrom);
  }

  // --- execution ----------------------------------------------------------------------------

  async #delete(path, ifMatch) {
    const answer = await this.#request("DELETE", path, { ifMatch, okStatus: 204, whenMissing: false });
    return answer !== false;
  }

  /** Registers on the first write of a kind; concurrent first writes share one registration. */
  async #ensureRegistered(capability) {
    if (this.#registered.has(capability)) return;
    const registration = this.#registering.then(async () => {
      if (this.#registered.has(capability)) return;
      await this.register(this.#capabilitiesWith(capability));
    });
    // The chain must survive a failed registration, or every later write would reject with it.
    this.#registering = registration.catch(() => {});
    await registration;
  }

  #capabilitiesWith(capability) {
    const wanted = new Set([...this.#registered, capability]);
    const known = CAPABILITY_ORDER.filter((name) => wanted.has(name));
    return [...known, ...[...wanted].filter((name) => !CAPABILITY_ORDER.includes(name)).sort()];
  }

  /**
   * Send one request with retries and interpret the answer.
   * @returns {Promise<any>} the parsed JSON body, null for a 204, or `whenMissing` on a 404
   */
  async #request(method, path, { json, query, ifMatch = null, okStatus = 200, whenMissing } = {}) {
    const url = this.#baseUrl + path + queryString(query);
    const init = { method, headers: this.#requestHeaders(json !== undefined, ifMatch) };
    if (json !== undefined) init.body = JSON.stringify(json);
    const description = `state API ${method} ${path}`;

    for (let attempt = 1; ; attempt++) {
      const outcome = await this.#attempt(url, init);
      const delayMs = this.#retryDelayMs(attempt, outcome, ifMatch !== null);
      if (delayMs !== null) {
        if (delayMs > 0) await sleep(delayMs);
        continue;
      }
      if (outcome.error) {
        throw new NasikoStateError(`${description} request failed: ${outcome.error.message}`, {
          cause: outcome.error,
        });
      }
      return await interpret(outcome.response, description, okStatus, whenMissing);
    }
  }

  #requestHeaders(hasBody, ifMatch) {
    const headers = { ...this.#headers };
    if (hasBody) headers["Content-Type"] = "application/json";
    if (ifMatch !== null) headers["If-Mat
```

### Core Architecture Module: `agents/common/js/nasiko-state/src/errors.js`
```
/**
 * Errors raised by the state client and stores. Every failure is a NasikoStateError; the
 * subclasses name the answers a caller can act on. Nothing falls back silently.
 */

export class NasikoStateError extends Error {
  /**
   * @param {string} message
   * @param {{status?: number | null, body?: string | null, cause?: unknown}} [details]
   *   `status` and `body` carry the HTTP answer; both are null for transport and configuration
   *   failures, where there was no answer.
   */
  constructor(message, { status = null, body = null, cause } = {}) {
    super(message, cause === undefined ? undefined : { cause });
    this.name = new.target.name;
    this.status = status;
    this.body = body;
  }
}

/** 401: the agent token is missing, unknown, or not a state-scoped credential. */
export class NasikoStateUnauthorized extends NasikoStateError {}

/** 404 on an operation that has no "missing" result (reads and deletes return null / false). */
export class NasikoStateNotFound extends NasikoStateError {}

/** 412: an If-Match precondition failed because another writer changed the row first. */
export class NasikoStateConflict extends NasikoStateError {
  /**
   * @param {string} message
   * @param {{currentVersion: number | null, body?: string | null}} details
   */
  constructor(message, { currentVersion, body = null }) {
    super(message, { status: 412, body });
    /** The version the server holds, or null if its answer did not say. */
    this.currentVersion = currentVersion;
  }
}

/** 413: a value above the platform's size limit. Retrying cannot help. */
export class NasikoStateTooLarge extends NasikoStateError {}

/** 429: over the per-agent request rate and not worth waiting out. */
export class NasikoStateRateLimited extends NasikoStateError {
  /**
   * @param {string} message
   * @param {{retryAfterSeconds: number | null, body?: string | null}} details
   */
  constructor(message, { retryAfterSeconds, body = null }) {
    super(message, { status: 429, body });
    this.retryAfterSeconds = retryAfterSeconds;
  }
}

/**
 * A stored row cannot be read back as what it claims to be: written by the other a2a SDK major,
 * not by a Nasiko store at all, or damaged. Never answered with a half-decoded object.
 */
export class NasikoStateMalformedRow extends NasikoStateError {}

/** Whether the same request could succeed later: no answer at all, or a server-side failure. */
export function isTransient(error) {
  return error instanceof NasikoStateError && (error.status === null || error.status >= 500);
}

```

### Core Architecture Module: `agents/common/js/nasiko-state/src/index.js`
```
/**
 * Durable agent state over the Nasiko platform's state API.
 *
 *   import { taskStoreFromEnv, installShutdownHooks } from "nasiko-state";
 *
 *   const handler = new DefaultRequestHandler(card, taskStoreFromEnv(), executor);
 *   installShutdownHooks(); // flush pending writes on SIGTERM / SIGINT
 *
 * Configuration comes from the environment the platform injects: NASIKO_STATE_URL (base URL of
 * the state API) and NASIKO_AGENT_TOKEN (this agent's state credential, the only one accepted).
 * With NASIKO_STATE_URL unset every factory returns the SDK's in-memory implementation.
 */

export * from "./errors.js";
export {
  AGENT_TOKEN_ENV,
  CLIENT_NAME,
  MAX_PAGE_SIZE,
  NasikoStateClient,
  STATE_URL_ENV,
  percentEncode,
} from "./client.js";
export {
  COALESCE_WINDOW_MS,
  PENDING_MAX_AGE_MS,
  NasikoTaskStore,
  TASK_FORMAT,
  closeOpenTaskStores,
  decodeStoredTask,
  encodeStoredTask,
  installShutdownHooks,
  stateName,
  taskStoreFromEnv,
} from "./task-store.js";

```

### Core Architecture Module: `agents/common/js/nasiko-state/src/task-store.js`
```
/**
 * An a2a-js TaskStore that keeps tasks in the platform's state API. Port of NasikoTaskStore in
 * oss/agents/common/nasiko_state.py; the two read each other's rows.
 *
 * Written against @a2a-js/sdk 1.3.0, whose TaskStore is `save(task, context)`,
 * `load(taskId, context)` and `list(params, context)`. Tasks are protobuf-shaped there, and are
 * stored as their proto3 JSON, tagged with the format that wrote them:
 * `{"format": "a2a-1", "task": ...}`. The 0.3.x SDK is not supported: a row of another format is
 * refused with NasikoStateMalformedRow rather than half-decoded.
 *
 * Write guarantee: a save that changes `task.status.state` is on the server before `save()`
 * resolves. Other saves are coalesced to at most one write per COALESCE_WINDOW_MS per task and
 * written on the next state change, by a timer, and by `close()`. A hard crash can lose that
 * window of non-status updates; an update the platform could not take for PENDING_MAX_AGE_MS is
 * discarded rather than written late. Errors reject; nothing is swallowed.
 *
 * Replicas: every write is conditional on the version this process last saw of the task
 * (If-Match). A state change that loses raises NasikoStateConflict; a coalesced update that loses
 * is dropped (logged). Either way the store re-reads, and `load()` returns the other writer's row.
 *
 * Tasks are scoped to the agent, not to an end user: the SDK's per-user owner resolution (the
 * `context` argument) does not apply.
 */

import { Task, TaskState, taskStateToJSON } from "@a2a-js/sdk";
import { InMemoryTaskStore } from "@a2a-js/sdk/server";

import { NasikoStateClient } from "./client.js";
import {
  NasikoStateConflict,
  NasikoStateError,
  NasikoStateMalformedRow,
  isTransient,
} from "./errors.js";

export const TASK_FORMAT = "a2a-1";
export const COALESCE_WINDOW_MS = 500;
// A deferred write that failed is retried after a delay that doubles per failure, up to this.
export const DEFERRED_RETRY_MAX_MS = 10_000;
// An unwritten update this old is presumed superseded (the task has most likely moved to another
// replica), so it is discarded instead of being written over whatever is there now.
export const PENDING_MAX_AGE_MS = 60_000;
// Bound on tasks whose write state is remembered. Forgetting an idle one costs its next write the
// version check: having no version to match, that write is unconditional.
export const MAX_TRACKED_TASKS = 4096;
export const DEFAULT_PAGE_SIZE = 50;

/** Durable stores this process opened and has not closed: what closeOpenTaskStores closes. */
const openStores = new Set();

// --- format ---------------------------------------------------------------------------------------

/** 'TASK_STATE_INPUT_REQUIRED' -> 'input-required', the vocabulary the state column uses. */
export function stateName(state) {
  const name = taskStateToJSON(state).replace(/^TASK_STATE_/, "").toLowerCase().replaceAll("_", "-");
  return name === "unspecified" || name === "unrecognized" ? "unknown" : name;
}

/** The body written to the state API: the task as proto3 JSON, tagged with its format. */
export function encodeStoredTask(task) {
  // Through JSON, so the snapshot is plain data that shares nothing with the SDK's live object.
  return JSON.parse(JSON.stringify({ format: TASK_FORMAT, task: Task.toJSON(task) }));
}

export function decodeStoredTask(body, taskId) {
  const storedFormat = body !== null && typeof body === "object" ? body.format : undefined;
  if (storedFormat !== TASK_FORMAT || !("task" in body)) {
    throw new NasikoStateMalformedRow(
      `stored task ${JSON.stringify(taskId)} is in format ${JSON.stringify(storedFormat)}, and this ` +
        `store reads ${JSON.stringify(TASK_FORMAT)} only`,
    );
  }
  let task;
  try {
    task = Task.fromJSON(body.task);
  } catch (cause) {
    throw new NasikoStateMalformedRow(`stored task ${JSON.stringify(taskId)} cannot be decoded: ${cause.message}`, {
      cause,
    });
  }
  // fromJSON turns {} into an empty task rather than failing, so check the identity too.
  if (task.id !== taskId) {
    throw new NasikoStateMalformedRow(
      `stored task ${JSON.stringify(taskId)} holds a body for task ${JSON.stringify(task.id)}`,
    );
  }
  return task;
}

function snapshotOf(task) {
  return {
    taskId: task.id,
    contextId: task.contextId || null,
    state: task.status ? stateName(task.status.state) : "unknown",
    body: encodeStoredTask(task),
    savedAt: Date.now(),
  };
}

const isStale = (snapshot) => Date.now() - snapshot.savedAt > PENDING_MAX_AGE_MS;

// --- per-task bookkeeping -------------------------------------------------------------------------

/** Runs one async function at a time, in call order. */
class Mutex {
  #tail = Promise.resolve();

  isLocked = false;

  runExclusive(fn) {
    const result = this.#tail.then(async () => {
      this.isLocked = true;
      try {
        return await fn();
      } finally {
        this.isLocked = false;
      }
    });
    this.#tail = result.catch(() => {});
    return result;
  }
}

/** Write-coalescing and concurrency bookkeeping for one task. */
class TaskSlot {
  constructor(taskId) {
    this.taskId = taskId;
    /** The newest snapshot the server has not confirmed yet. */
    this.pending = null;
    /** The row's version as this process last saw it. Every write is conditional on it. */
    this.version = null;
    /** State of the newest snapshot sent or read; a save in any other state is written through. */
    this.state = null;
    this.lastWriteStarted = Number.NEGATIVE_INFINITY;
    /** Consecutive failed writes; spaces out the background retries. */
    this.failedWrites = 0;
    this.timer = null;
    /** One write per task at a time, so an older snapshot cannot land after a newer one. */
    this.lock = new Mutex();
  }

  isIdle() {
    return this.pending === null && this.timer === null && !this.lock.isLocked;
  }
}

// --- the store ------------------------------------------------------------------------------------

export class NasikoTaskStore {
  #client;
  #windowMs;
  #logger;
  /** @type {Map<string, TaskSlot>} insertion order is recency order */
  #slots = new Map();

  /**
   * @param {NasikoStateClient} client
   * @param {{coalesceWindowMs?: number, logger?: Pick<Console, "warn" | "error">}} [options]
   */
  constructor(client, { coalesceWindowMs = COALESCE_WINDOW_MS, logger = console } = {}) {
    this.#client = client;
    this.#windowMs = coalesceWindowMs;
    this.#logger = logger;
    openStores.add(this);
  }

  /** @param {import("@a2a-js/sdk").Task} task */
  async save(task, _context) {
    const snapshot = snapshotOf(task);
    const slot = this.#slot(snapshot.taskId);
    slot.pending = snapshot;
    if (snapshot.state === slot.state) {
      this.#scheduleFlush(slot);
      return;
    }
    slot.state = snapshot.state;
    try {
      await this.#writePending(slot);
    } catch (error) {
      // The state change is still owed; retry it rather than wait for a save that may never come.
      if (isTransient(error)) this.#scheduleFlush(slot);
      throw error;
    }
  }

  async load(taskId, _context) {
    const slot = this.#slot(taskId);
    // Under the slot's lock, so a write in flight cannot be mistaken for another writer's.
    return slot.lock.runExclusive(async () => {
      const record = await this.#client.getTask(taskId);
      return this.#newestOf(slot, record);
    });
  }

  async delete(taskId, _context) {
    const slot = this.#slot(taskId);
    await slot.lock.runExclusive(async () => {
      slot.pending = null; // an unwritten snapshot must not bring the task back
      await this.#client.deleteTask(taskId);
    });
    if (this.#slots.get(taskId) === slot) this.#slots.delete(taskId);
  }

  /**
   * tasks/list, served by the server; it can lag by one coalescing window. totalSize is unknown
   * and reported as 0 (the state API gives no totals). statusTimestampAfter is inclusive (>=),
   * like the Python store and unlike the SDK's in-memory store.
   */
  async list(params, _context) {
    const limit = params.pageSize || DEFAULT_PAGE_SIZE;
    const page = await this.#client.listTasks({
      contextId: params.contextId || null,
      state: params.status ? stateName(params.status) : null,
      limit,
      cursor: params.pageToken || null,
    });
    const tasks = page.items
      .map((record) => decodeStoredTask(record.body, record.taskId))
      .filter((task) => statusChangedSince(task, params.statusTimestampAfter))
      .map((task) => shaped(task, params));
    // totalSize stays 0: the state API reports no totals, and this page's size would be a wrong one.
    return { tasks, nextPageToken: page.nextCursor ?? "", pageSize: tasks.length, totalSize: 0 };
  }

  /** Write everything pending, stop the timers. Rejects with the first failure, after trying all. */
  async close() {
    openStores.delete(this);
    for (const slot of this.#slots.values()) this.#clearTimer(slot);
    const owed = [...this.#slots.values()].filter((slot) => this.#owesAWrite(slot));
    const outcomes = await Promise.allSettled(owed.map((slot) => this.#writePending(slot)));
    const failures = [];
    outcomes.forEach((outcome, i) => {
      if (outcome.status === "fulfilled") return;
      if (outcome.reason instanceof NasikoStateConflict) this.#logSuperseded(owed[i], outcome.reason);
      else failures.push(outcome.reason);
    });
    for (const failure of failures.slice(1)) {
      this.#logger.error(`a pending task write could not be flushed on close: ${failure.message}`);
    }
    if (failures.length > 0) throw failures[0];
  }

  // --- writing ----------------------------------------------------------------------------------

  #writePending(slot) {
    return slot.lock.runExclusive(async () => {
      const snapshot = slot.pending;
      if (snapshot === null) return; // a newer write already carried it
      slot.lastWriteStarted = Date.now();
      let receipt;
      try {
        receipt 
```

### Core Architecture Module: `agents/common/nasiko_state.py`
```
"""Durable agent state over the platform's state API.

An A2A agent normally keeps its tasks in process memory, so a restart loses paused work
and the agent cannot run as more than one replica. This module is a drop-in replacement
that keeps that state in the platform instead.

    from nasiko_state import make_task_store

    handler = DefaultRequestHandler(
        agent_executor=MyExecutor(),
        task_store=make_task_store(),   # was: InMemoryTaskStore()
        agent_card=card,
    )
    app = Starlette(routes=...)
    install_shutdown_hooks(app)         # flush pending writes when the server stops

Configuration comes from the environment the platform injects into the container:

    NASIKO_STATE_URL     base URL of the state API (ends in /api/agent-state). Unset means the
                         platform provides no store, and every factory here returns the
                         in-memory implementation the SDK ships, so the same code runs locally.
    NASIKO_AGENT_TOKEN   this agent's state credential. It is the only one accepted: the MCP
                         gateway token is a different credential and is never used here.

Write guarantee (see NasikoTaskStore): a save that changes ``task.status.state`` is on the
server before ``save()`` returns. Other saves are coalesced to at most one write per
COALESCE_WINDOW_SECONDS per task and written on the next state change, by a background timer,
and by ``aclose()``. Nothing calls ``aclose()`` on its own: ``install_shutdown_hooks(app)`` runs
it when the server shuts down (uvicorn does that on SIGTERM and Ctrl-C), and an atexit hook
covers a normal interpreter exit. A hard crash (SIGKILL, power loss), or a SIGTERM in a process
without those hooks, can lose that window of non-status updates; so can an update the platform
could not take for PENDING_MAX_AGE_SECONDS, which is discarded rather than written late.

Both a2a-sdk majors are supported (0.3.x pydantic tasks and 1.x protobuf tasks). The langgraph
checkpointer needs the optional langgraph-checkpoint package; nothing else does.

This file is vendored: agent images are built from the agent's own directory only, so each
agent keeps a committed copy next to its main module. oss/agents/common is canonical and
oss/agents/common/check_vendored.py fails when a copy drifts.
"""

from __future__ import annotations

import asyncio
import atexit
import base64
import contextlib
import functools
import json
import logging
import os
import random
import signal
import threading
import time
from collections import OrderedDict
from collections.abc import AsyncIterator, Callable, Iterator, Mapping, Sequence
from dataclasses import dataclass, fields
from typing import Any, Generic, TypeVar
from urllib.parse import quote, urlsplit

import httpx
from a2a.server.tasks import InMemoryTaskStore, TaskStore
from a2a.types import Task

try:
    from a2a.types import a2a_pb2 as _a2a_pb2  # a2a-sdk 1.x: tasks are protobuf messages
except ImportError:
    _a2a_pb2 = None  # a2a-sdk 0.3.x: tasks are pydantic models

try:
    from langgraph.checkpoint.base import (
        WRITES_IDX_MAP,
        BaseCheckpointSaver,
        CheckpointTuple,
        get_checkpoint_metadata,
    )

    _LANGGRAPH_AVAILABLE = True
except ImportError:
    # langgraph is optional: only agents that checkpoint with it need the package.
    BaseCheckpointSaver = object  # type: ignore[assignment,misc]
    _LANGGRAPH_AVAILABLE = False

logger = logging.getLogger("nasiko_state")

STATE_URL_ENV = "NASIKO_STATE_URL"
AGENT_TOKEN_ENV = "NASIKO_AGENT_TOKEN"

CLIENT_NAME = "nasiko_state.py/1"

CONNECT_TIMEOUT_SECONDS = 2.0
READ_TIMEOUT_SECONDS = 10.0
RETRY_ATTEMPTS = 3
RETRY_BACKOFF_SECONDS = 0.2
# A rate-limited (429) request is retried after the Retry-After the server names, waiting at most
# MAX_RETRY_AFTER_SECONDS per attempt and RATE_LIMIT_BUDGET_SECONDS in all before the 429 surfaces.
# The platform's limit is a per-minute window shared by every replica of the agent, so a wait of a
# few seconds is usually enough, and a turn that keeps failing for half a minute should fail.
MAX_RETRY_AFTER_SECONDS = 5.0
RATE_LIMIT_BUDGET_SECONDS = 30.0
# The wait when a 429 names none (or names an HTTP date), and the shortest wait ever taken, so a
# server answering "Retry-After: 0" cannot turn the budget into a busy loop.
RATE_LIMIT_DEFAULT_WAIT_SECONDS = 1.0
RATE_LIMIT_MIN_WAIT_SECONDS = 0.5
# Relative spread of each 429 wait, so replicas limited at the same moment do not retry in step.
RATE_LIMIT_JITTER = 0.2
MAX_PAGE_SIZE = 100
DEFAULT_PAGE_SIZE = 50

# Saves that do not change a task's state are written at most once per window per task.
COALESCE_WINDOW_SECONDS = 0.5
# A deferred write that failed is retried after a delay that doubles per failure, up to this.
DEFERRED_RETRY_MAX_SECONDS = 10.0
# An unwritten update this old is presumed superseded (the task has most likely moved on to
# another replica), so it is discarded instead of being written over whatever is there now.
PENDING_MAX_AGE_SECONDS = 60.0
# Exiting with the platform unreachable must not hang for every pending task.
EXIT_FLUSH_BUDGET_SECONDS = 10.0
# A task id just looked up and not found reads as missing for this long without asking again.
# a2a-sdk 1.x looks a new task's id up several times before the task's first save, and that id is
# one the SDK generated for the request, so no other replica can have created the task meanwhile.
# A task that exists is always read from the server: another replica may have changed it.
ABSENT_CACHE_SECONDS = 2.0
# Bound on tasks whose write state is remembered. Forgetting an idle one costs its next write the
# version check: having no version to match, that write is unconditional.
MAX_TRACKED_TASKS = 4096
# The status a shell reports for a process ended by SIGTERM; kept when SIGTERM becomes an exit.
SIGTERM_EXIT_STATUS = 128 + signal.SIGTERM

# The order the registration contract spells its capability lists in.
CAPABILITY_ORDER = ("tasks", "kv")
# A startup registration that failed for a reason that may pass (no answer, 5xx, 429) is retried
# in the background after a delay that doubles from the first of these up to the second.
REGISTER_RETRY_FIRST_SECONDS = 1.0
REGISTER_RETRY_MAX_SECONDS = 60.0
REGISTER_THREAD_NAME = "nasiko-state-register"

T = TypeVar("T")


class NasikoStateError(Exception):
    """The state API refused a request or could not be reached.

    ``status`` and ``body`` carry the HTTP answer. Both are None for transport and
    configuration failures, where there was no answer.
    """

    def __init__(self, message: str, *, status: int | None = None, body: str | None = None):
        super().__init__(message)
        self.status = status
        self.body = body


class NasikoStateMalformedRow(NasikoStateError):
    """A stored row cannot be read back as what it claims to be.

    Raised for a task written by the other a2a-sdk major (or not by this module at all), and for a
    damaged record. Never answered with a half-decoded object.
    """


class NasikoStateTooLarge(NasikoStateError):
    """The state API refused a value above its size limit (HTTP 413). Retrying cannot help."""


class NasikoStateConflict(NasikoStateError):
    """An ``If-Match`` precondition failed: another writer changed the row first.

    ``current_version`` is the version the server holds, or None if the body did not say.
    """

    def __init__(self, message: str, *, current_version: int | None, body: str | None = None):
        super().__init__(message, status=412, body=body)
        self.current_version = current_version


@dataclass(frozen=True)
class WriteReceipt:
    """What the server answers to a PUT. Task and KV writes share the three fields."""

    version: int
    updated_at: str
    expires_at: str


@dataclass(frozen=True)
class TaskRecord:
    """One stored task. ``body`` is the SDK's serialized Task, opaque to the server."""

    task_id: str
    context_id: str | None
    state: str
    body: Any
    version: int
    updated_at: str
    expires_at: str


@dataclass(frozen=True)
class KVRecord:
    """One stored key. ``value`` is opaque JSON."""

    key: str
    value: Any
    version: int
    updated_at: str
    expires_at: str


@dataclass(frozen=True)
class Page(Generic[T]):
    """One page of a listing. ``next_cursor`` is None on the last page."""

    items: list[T]
    next_cursor: str | None


# --- Operations ---------------------------------------------------------------------------------
#
# Each state API call is described once, as data, and executed by the sync or the async client
# method. That keeps request building, status handling and parsing in a single place.

_UNSET: Any = object()


@dataclass(frozen=True)
class _Operation:
    """One state API call: how to send it and how to read the answer."""

    method: str
    path: str
    parse: Callable[[httpx.Response], Any]
    ok_status: int = 200
    params: Mapping[str, str | int | None] | None = None
    json: Any = _UNSET
    if_match: int | None = None
    # A write names the capability it needs registered; reads leave it None.
    capability: str | None = None
    # What a 404 means. Left unset, a 404 is an error like any other status.
    when_missing: Any = _UNSET
    # time.monotonic() by which the call, retries included, must be over. None means no deadline.
    deadline: float | None = None

    def request_kwargs(self) -> dict[str, Any]:
        kwargs: dict[str, Any] = {"method": self.method, "url": self.path}
        if self.params:
            kwargs["params"] = {key: value for key, value in self.params.items() if value is not None}
        if self.json is not _UNSET:
            kwargs["json"] = self.json
        if self.if_match is not None:
            kwargs["headers"] = {"If-Match": str(self.if_match)}
        if self.deadline is not None:
            kwargs["timeout"] = min(self.seconds_left(), READ_TIMEOUT_SECONDS)
        return kwargs

    def seconds_left(self) -> 
```

### Core Architecture Module: `agents/crewai/src/nasiko_state.py`
```
"""Durable agent state over the platform's state API.

An A2A agent normally keeps its tasks in process memory, so a restart loses paused work
and the agent cannot run as more than one replica. This module is a drop-in replacement
that keeps that state in the platform instead.

    from nasiko_state import make_task_store

    handler = DefaultRequestHandler(
        agent_executor=MyExecutor(),
        task_store=make_task_store(),   # was: InMemoryTaskStore()
        agent_card=card,
    )
    app = Starlette(routes=...)
    install_shutdown_hooks(app)         # flush pending writes when the server stops

Configuration comes from the environment the platform injects into the container:

    NASIKO_STATE_URL     base URL of the state API (ends in /api/agent-state). Unset means the
                         platform provides no store, and every factory here returns the
                         in-memory implementation the SDK ships, so the same code runs locally.
    NASIKO_AGENT_TOKEN   this agent's state credential. It is the only one accepted: the MCP
                         gateway token is a different credential and is never used here.

Write guarantee (see NasikoTaskStore): a save that changes ``task.status.state`` is on the
server before ``save()`` returns. Other saves are coalesced to at most one write per
COALESCE_WINDOW_SECONDS per task and written on the next state change, by a background timer,
and by ``aclose()``. Nothing calls ``aclose()`` on its own: ``install_shutdown_hooks(app)`` runs
it when the server shuts down (uvicorn does that on SIGTERM and Ctrl-C), and an atexit hook
covers a normal interpreter exit. A hard crash (SIGKILL, power loss), or a SIGTERM in a process
without those hooks, can lose that window of non-status updates; so can an update the platform
could not take for PENDING_MAX_AGE_SECONDS, which is discarded rather than written late.

Both a2a-sdk majors are supported (0.3.x pydantic tasks and 1.x protobuf tasks). The langgraph
checkpointer needs the optional langgraph-checkpoint package; nothing else does.

This file is vendored: agent images are built from the agent's own directory only, so each
agent keeps a committed copy next to its main module. oss/agents/common is canonical and
oss/agents/common/check_vendored.py fails when a copy drifts.
"""

from __future__ import annotations

import asyncio
import atexit
import base64
import contextlib
import functools
import json
import logging
import os
import random
import signal
import threading
import time
from collections import OrderedDict
from collections.abc import AsyncIterator, Callable, Iterator, Mapping, Sequence
from dataclasses import dataclass, fields
from typing import Any, Generic, TypeVar
from urllib.parse import quote, urlsplit

import httpx
from a2a.server.tasks import InMemoryTaskStore, TaskStore
from a2a.types import Task

try:
    from a2a.types import a2a_pb2 as _a2a_pb2  # a2a-sdk 1.x: tasks are protobuf messages
except ImportError:
    _a2a_pb2 = None  # a2a-sdk 0.3.x: tasks are pydantic models

try:
    from langgraph.checkpoint.base import (
        WRITES_IDX_MAP,
        BaseCheckpointSaver,
        CheckpointTuple,
        get_checkpoint_metadata,
    )

    _LANGGRAPH_AVAILABLE = True
except ImportError:
    # langgraph is optional: only agents that checkpoint with it need the package.
    BaseCheckpointSaver = object  # type: ignore[assignment,misc]
    _LANGGRAPH_AVAILABLE = False

logger = logging.getLogger("nasiko_state")

STATE_URL_ENV = "NASIKO_STATE_URL"
AGENT_TOKEN_ENV = "NASIKO_AGENT_TOKEN"

CLIENT_NAME = "nasiko_state.py/1"

CONNECT_TIMEOUT_SECONDS = 2.0
READ_TIMEOUT_SECONDS = 10.0
RETRY_ATTEMPTS = 3
RETRY_BACKOFF_SECONDS = 0.2
# A rate-limited (429) request is retried after the Retry-After the server names, waiting at most
# MAX_RETRY_AFTER_SECONDS per attempt and RATE_LIMIT_BUDGET_SECONDS in all before the 429 surfaces.
# The platform's limit is a per-minute window shared by every replica of the agent, so a wait of a
# few seconds is usually enough, and a turn that keeps failing for half a minute should fail.
MAX_RETRY_AFTER_SECONDS = 5.0
RATE_LIMIT_BUDGET_SECONDS = 30.0
# The wait when a 429 names none (or names an HTTP date), and the shortest wait ever taken, so a
# server answering "Retry-After: 0" cannot turn the budget into a busy loop.
RATE_LIMIT_DEFAULT_WAIT_SECONDS = 1.0
RATE_LIMIT_MIN_WAIT_SECONDS = 0.5
# Relative spread of each 429 wait, so replicas limited at the same moment do not retry in step.
RATE_LIMIT_JITTER = 0.2
MAX_PAGE_SIZE = 100
DEFAULT_PAGE_SIZE = 50

# Saves that do not change a task's state are written at most once per window per task.
COALESCE_WINDOW_SECONDS = 0.5
# A deferred write that failed is retried after a delay that doubles per failure, up to this.
DEFERRED_RETRY_MAX_SECONDS = 10.0
# An unwritten update this old is presumed superseded (the task has most likely moved on to
# another replica), so it is discarded instead of being written over whatever is there now.
PENDING_MAX_AGE_SECONDS = 60.0
# Exiting with the platform unreachable must not hang for every pending task.
EXIT_FLUSH_BUDGET_SECONDS = 10.0
# A task id just looked up and not found reads as missing for this long without asking again.
# a2a-sdk 1.x looks a new task's id up several times before the task's first save, and that id is
# one the SDK generated for the request, so no other replica can have created the task meanwhile.
# A task that exists is always read from the server: another replica may have changed it.
ABSENT_CACHE_SECONDS = 2.0
# Bound on tasks whose write state is remembered. Forgetting an idle one costs its next write the
# version check: having no version to match, that write is unconditional.
MAX_TRACKED_TASKS = 4096
# The status a shell reports for a process ended by SIGTERM; kept when SIGTERM becomes an exit.
SIGTERM_EXIT_STATUS = 128 + signal.SIGTERM

# The order the registration contract spells its capability lists in.
CAPABILITY_ORDER = ("tasks", "kv")
# A startup registration that failed for a reason that may pass (no answer, 5xx, 429) is retried
# in the background after a delay that doubles from the first of these up to the second.
REGISTER_RETRY_FIRST_SECONDS = 1.0
REGISTER_RETRY_MAX_SECONDS = 60.0
REGISTER_THREAD_NAME = "nasiko-state-register"

T = TypeVar("T")


class NasikoStateError(Exception):
    """The state API refused a request or could not be reached.

    ``status`` and ``body`` carry the HTTP answer. Both are None for transport and
    configuration failures, where there was no answer.
    """

    def __init__(self, message: str, *, status: int | None = None, body: str | None = None):
        super().__init__(message)
        self.status = status
        self.body = body


class NasikoStateMalformedRow(NasikoStateError):
    """A stored row cannot be read back as what it claims to be.

    Raised for a task written by the other a2a-sdk major (or not by this module at all), and for a
    damaged record. Never answered with a half-decoded object.
    """


class NasikoStateTooLarge(NasikoStateError):
    """The state API refused a value above its size limit (HTTP 413). Retrying cannot help."""


class NasikoStateConflict(NasikoStateError):
    """An ``If-Match`` precondition failed: another writer changed the row first.

    ``current_version`` is the version the server holds, or None if the body did not say.
    """

    def __init__(self, message: str, *, current_version: int | None, body: str | None = None):
        super().__init__(message, status=412, body=body)
        self.current_version = current_version


@dataclass(frozen=True)
class WriteReceipt:
    """What the server answers to a PUT. Task and KV writes share the three fields."""

    version: int
    updated_at: str
    expires_at: str


@dataclass(frozen=True)
class TaskRecord:
    """One stored task. ``body`` is the SDK's serialized Task, opaque to the server."""

    task_id: str
    context_id: str | None
    state: str
    body: Any
    version: int
    updated_at: str
    expires_at: str


@dataclass(frozen=True)
class KVRecord:
    """One stored key. ``value`` is opaque JSON."""

    key: str
    value: Any
    version: int
    updated_at: str
    expires_at: str


@dataclass(frozen=True)
class Page(Generic[T]):
    """One page of a listing. ``next_cursor`` is None on the last page."""

    items: list[T]
    next_cursor: str | None


# --- Operations ---------------------------------------------------------------------------------
#
# Each state API call is described once, as data, and executed by the sync or the async client
# method. That keeps request building, status handling and parsing in a single place.

_UNSET: Any = object()


@dataclass(frozen=True)
class _Operation:
    """One state API call: how to send it and how to read the answer."""

    method: str
    path: str
    parse: Callable[[httpx.Response], Any]
    ok_status: int = 200
    params: Mapping[str, str | int | None] | None = None
    json: Any = _UNSET
    if_match: int | None = None
    # A write names the capability it needs registered; reads leave it None.
    capability: str | None = None
    # What a 404 means. Left unset, a 404 is an error like any other status.
    when_missing: Any = _UNSET
    # time.monotonic() by which the call, retries included, must be over. None means no deadline.
    deadline: float | None = None

    def request_kwargs(self) -> dict[str, Any]:
        kwargs: dict[str, Any] = {"method": self.method, "url": self.path}
        if self.params:
            kwargs["params"] = {key: value for key, value in self.params.items() if value is not None}
        if self.json is not _UNSET:
            kwargs["json"] = self.json
        if self.if_match is not None:
            kwargs["headers"] = {"If-Match": str(self.if_match)}
        if self.deadline is not None:
            kwargs["timeout"] = min(self.seconds_left(), READ_TIMEOUT_SECONDS)
        return kwargs

    def seconds_left(self) -> 
```

### Core Architecture Module: `agents/currency-agent/nasiko_state.py`
```
"""Durable agent state over the platform's state API.

An A2A agent normally keeps its tasks in process memory, so a restart loses paused work
and the agent cannot run as more than one replica. This module is a drop-in replacement
that keeps that state in the platform instead.

    from nasiko_state import make_task_store

    handler = DefaultRequestHandler(
        agent_executor=MyExecutor(),
        task_store=make_task_store(),   # was: InMemoryTaskStore()
        agent_card=card,
    )
    app = Starlette(routes=...)
    install_shutdown_hooks(app)         # flush pending writes when the server stops

Configuration comes from the environment the platform injects into the container:

    NASIKO_STATE_URL     base URL of the state API (ends in /api/agent-state). Unset means the
                         platform provides no store, and every factory here returns the
                         in-memory implementation the SDK ships, so the same code runs locally.
    NASIKO_AGENT_TOKEN   this agent's state credential. It is the only one accepted: the MCP
                         gateway token is a different credential and is never used here.

Write guarantee (see NasikoTaskStore): a save that changes ``task.status.state`` is on the
server before ``save()`` returns. Other saves are coalesced to at most one write per
COALESCE_WINDOW_SECONDS per task and written on the next state change, by a background timer,
and by ``aclose()``. Nothing calls ``aclose()`` on its own: ``install_shutdown_hooks(app)`` runs
it when the server shuts down (uvicorn does that on SIGTERM and Ctrl-C), and an atexit hook
covers a normal interpreter exit. A hard crash (SIGKILL, power loss), or a SIGTERM in a process
without those hooks, can lose that window of non-status updates; so can an update the platform
could not take for PENDING_MAX_AGE_SECONDS, which is discarded rather than written late.

Both a2a-sdk majors are supported (0.3.x pydantic tasks and 1.x protobuf tasks). The langgraph
checkpointer needs the optional langgraph-checkpoint package; nothing else does.

This file is vendored: agent images are built from the agent's own directory only, so each
agent keeps a committed copy next to its main module. oss/agents/common is canonical and
oss/agents/common/check_vendored.py fails when a copy drifts.
"""

from __future__ import annotations

import asyncio
import atexit
import base64
import contextlib
import functools
import json
import logging
import os
import random
import signal
import threading
import time
from collections import OrderedDict
from collections.abc import AsyncIterator, Callable, Iterator, Mapping, Sequence
from dataclasses import dataclass, fields
from typing import Any, Generic, TypeVar
from urllib.parse import quote, urlsplit

import httpx
from a2a.server.tasks import InMemoryTaskStore, TaskStore
from a2a.types import Task

try:
    from a2a.types import a2a_pb2 as _a2a_pb2  # a2a-sdk 1.x: tasks are protobuf messages
except ImportError:
    _a2a_pb2 = None  # a2a-sdk 0.3.x: tasks are pydantic models

try:
    from langgraph.checkpoint.base import (
        WRITES_IDX_MAP,
        BaseCheckpointSaver,
        CheckpointTuple,
        get_checkpoint_metadata,
    )

    _LANGGRAPH_AVAILABLE = True
except ImportError:
    # langgraph is optional: only agents that checkpoint with it need the package.
    BaseCheckpointSaver = object  # type: ignore[assignment,misc]
    _LANGGRAPH_AVAILABLE = False

logger = logging.getLogger("nasiko_state")

STATE_URL_ENV = "NASIKO_STATE_URL"
AGENT_TOKEN_ENV = "NASIKO_AGENT_TOKEN"

CLIENT_NAME = "nasiko_state.py/1"

CONNECT_TIMEOUT_SECONDS = 2.0
READ_TIMEOUT_SECONDS = 10.0
RETRY_ATTEMPTS = 3
RETRY_BACKOFF_SECONDS = 0.2
# A rate-limited (429) request is retried after the Retry-After the server names, waiting at most
# MAX_RETRY_AFTER_SECONDS per attempt and RATE_LIMIT_BUDGET_SECONDS in all before the 429 surfaces.
# The platform's limit is a per-minute window shared by every replica of the agent, so a wait of a
# few seconds is usually enough, and a turn that keeps failing for half a minute should fail.
MAX_RETRY_AFTER_SECONDS = 5.0
RATE_LIMIT_BUDGET_SECONDS = 30.0
# The wait when a 429 names none (or names an HTTP date), and the shortest wait ever taken, so a
# server answering "Retry-After: 0" cannot turn the budget into a busy loop.
RATE_LIMIT_DEFAULT_WAIT_SECONDS = 1.0
RATE_LIMIT_MIN_WAIT_SECONDS = 0.5
# Relative spread of each 429 wait, so replicas limited at the same moment do not retry in step.
RATE_LIMIT_JITTER = 0.2
MAX_PAGE_SIZE = 100
DEFAULT_PAGE_SIZE = 50

# Saves that do not change a task's state are written at most once per window per task.
COALESCE_WINDOW_SECONDS = 0.5
# A deferred write that failed is retried after a delay that doubles per failure, up to this.
DEFERRED_RETRY_MAX_SECONDS = 10.0
# An unwritten update this old is presumed superseded (the task has most likely moved on to
# another replica), so it is discarded instead of being written over whatever is there now.
PENDING_MAX_AGE_SECONDS = 60.0
# Exiting with the platform unreachable must not hang for every pending task.
EXIT_FLUSH_BUDGET_SECONDS = 10.0
# A task id just looked up and not found reads as missing for this long without asking again.
# a2a-sdk 1.x looks a new task's id up several times before the task's first save, and that id is
# one the SDK generated for the request, so no other replica can have created the task meanwhile.
# A task that exists is always read from the server: another replica may have changed it.
ABSENT_CACHE_SECONDS = 2.0
# Bound on tasks whose write state is remembered. Forgetting an idle one costs its next write the
# version check: having no version to match, that write is unconditional.
MAX_TRACKED_TASKS = 4096
# The status a shell reports for a process ended by SIGTERM; kept when SIGTERM becomes an exit.
SIGTERM_EXIT_STATUS = 128 + signal.SIGTERM

# The order the registration contract spells its capability lists in.
CAPABILITY_ORDER = ("tasks", "kv")
# A startup registration that failed for a reason that may pass (no answer, 5xx, 429) is retried
# in the background after a delay that doubles from the first of these up to the second.
REGISTER_RETRY_FIRST_SECONDS = 1.0
REGISTER_RETRY_MAX_SECONDS = 60.0
REGISTER_THREAD_NAME = "nasiko-state-register"

T = TypeVar("T")


class NasikoStateError(Exception):
    """The state API refused a request or could not be reached.

    ``status`` and ``body`` carry the HTTP answer. Both are None for transport and
    configuration failures, where there was no answer.
    """

    def __init__(self, message: str, *, status: int | None = None, body: str | None = None):
        super().__init__(message)
        self.status = status
        self.body = body


class NasikoStateMalformedRow(NasikoStateError):
    """A stored row cannot be read back as what it claims to be.

    Raised for a task written by the other a2a-sdk major (or not by this module at all), and for a
    damaged record. Never answered with a half-decoded object.
    """


class NasikoStateTooLarge(NasikoStateError):
    """The state API refused a value above its size limit (HTTP 413). Retrying cannot help."""


class NasikoStateConflict(NasikoStateError):
    """An ``If-Match`` precondition failed: another writer changed the row first.

    ``current_version`` is the version the server holds, or None if the body did not say.
    """

    def __init__(self, message: str, *, current_version: int | None, body: str | None = None):
        super().__init__(message, status=412, body=body)
        self.current_version = current_version


@dataclass(frozen=True)
class WriteReceipt:
    """What the server answers to a PUT. Task and KV writes share the three fields."""

    version: int
    updated_at: str
    expires_at: str


@dataclass(frozen=True)
class TaskRecord:
    """One stored task. ``body`` is the SDK's serialized Task, opaque to the server."""

    task_id: str
    context_id: str | None
    state: str
    body: Any
    version: int
    updated_at: str
    expires_at: str


@dataclass(frozen=True)
class KVRecord:
    """One stored key. ``value`` is opaque JSON."""

    key: str
    value: Any
    version: int
    updated_at: str
    expires_at: str


@dataclass(frozen=True)
class Page(Generic[T]):
    """One page of a listing. ``next_cursor`` is None on the last page."""

    items: list[T]
    next_cursor: str | None


# --- Operations ---------------------------------------------------------------------------------
#
# Each state API call is described once, as data, and executed by the sync or the async client
# method. That keeps request building, status handling and parsing in a single place.

_UNSET: Any = object()


@dataclass(frozen=True)
class _Operation:
    """One state API call: how to send it and how to read the answer."""

    method: str
    path: str
    parse: Callable[[httpx.Response], Any]
    ok_status: int = 200
    params: Mapping[str, str | int | None] | None = None
    json: Any = _UNSET
    if_match: int | None = None
    # A write names the capability it needs registered; reads leave it None.
    capability: str | None = None
    # What a 404 means. Left unset, a 404 is an error like any other status.
    when_missing: Any = _UNSET
    # time.monotonic() by which the call, retries included, must be over. None means no deadline.
    deadline: float | None = None

    def request_kwargs(self) -> dict[str, Any]:
        kwargs: dict[str, Any] = {"method": self.method, "url": self.path}
        if self.params:
            kwargs["params"] = {key: value for key, value in self.params.items() if value is not None}
        if self.json is not _UNSET:
            kwargs["json"] = self.json
        if self.if_match is not None:
            kwargs["headers"] = {"If-Match": str(self.if_match)}
        if self.deadline is not None:
            kwargs["timeout"] = min(self.seconds_left(), READ_TIMEOUT_SECONDS)
        return kwargs

    def seconds_left(self) -> 
```

### Core Architecture Module: `agents/google-adk/src/nasiko_state.py`
```
"""Durable agent state over the platform's state API.

An A2A agent normally keeps its tasks in process memory, so a restart loses paused work
and the agent cannot run as more than one replica. This module is a drop-in replacement
that keeps that state in the platform instead.

    from nasiko_state import make_task_store

    handler = DefaultRequestHandler(
        agent_executor=MyExecutor(),
        task_store=make_task_store(),   # was: InMemoryTaskStore()
        agent_card=card,
    )
    app = Starlette(routes=...)
    install_shutdown_hooks(app)         # flush pending writes when the server stops

Configuration comes from the environment the platform injects into the container:

    NASIKO_STATE_URL     base URL of the state API (ends in /api/agent-state). Unset means the
                         platform provides no store, and every factory here returns the
                         in-memory implementation the SDK ships, so the same code runs locally.
    NASIKO_AGENT_TOKEN   this agent's state credential. It is the only one accepted: the MCP
                         gateway token is a different credential and is never used here.

Write guarantee (see NasikoTaskStore): a save that changes ``task.status.state`` is on the
server before ``save()`` returns. Other saves are coalesced to at most one write per
COALESCE_WINDOW_SECONDS per task and written on the next state change, by a background timer,
and by ``aclose()``. Nothing calls ``aclose()`` on its own: ``install_shutdown_hooks(app)`` runs
it when the server shuts down (uvicorn does that on SIGTERM and Ctrl-C), and an atexit hook
covers a normal interpreter exit. A hard crash (SIGKILL, power loss), or a SIGTERM in a process
without those hooks, can lose that window of non-status updates; so can an update the platform
could not take for PENDING_MAX_AGE_SECONDS, which is discarded rather than written late.

Both a2a-sdk majors are supported (0.3.x pydantic tasks and 1.x protobuf tasks). The langgraph
checkpointer needs the optional langgraph-checkpoint package; nothing else does.

This file is vendored: agent images are built from the agent's own directory only, so each
agent keeps a committed copy next to its main module. oss/agents/common is canonical and
oss/agents/common/check_vendored.py fails when a copy drifts.
"""

from __future__ import annotations

import asyncio
import atexit
import base64
import contextlib
import functools
import json
import logging
import os
import random
import signal
import threading
import time
from collections import OrderedDict
from collections.abc import AsyncIterator, Callable, Iterator, Mapping, Sequence
from dataclasses import dataclass, fields
from typing import Any, Generic, TypeVar
from urllib.parse import quote, urlsplit

import httpx
from a2a.server.tasks import InMemoryTaskStore, TaskStore
from a2a.types import Task

try:
    from a2a.types import a2a_pb2 as _a2a_pb2  # a2a-sdk 1.x: tasks are protobuf messages
except ImportError:
    _a2a_pb2 = None  # a2a-sdk 0.3.x: tasks are pydantic models

try:
    from langgraph.checkpoint.base import (
        WRITES_IDX_MAP,
        BaseCheckpointSaver,
        CheckpointTuple,
        get_checkpoint_metadata,
    )

    _LANGGRAPH_AVAILABLE = True
except ImportError:
    # langgraph is optional: only agents that checkpoint with it need the package.
    BaseCheckpointSaver = object  # type: ignore[assignment,misc]
    _LANGGRAPH_AVAILABLE = False

logger = logging.getLogger("nasiko_state")

STATE_URL_ENV = "NASIKO_STATE_URL"
AGENT_TOKEN_ENV = "NASIKO_AGENT_TOKEN"

CLIENT_NAME = "nasiko_state.py/1"

CONNECT_TIMEOUT_SECONDS = 2.0
READ_TIMEOUT_SECONDS = 10.0
RETRY_ATTEMPTS = 3
RETRY_BACKOFF_SECONDS = 0.2
# A rate-limited (429) request is retried after the Retry-After the server names, waiting at most
# MAX_RETRY_AFTER_SECONDS per attempt and RATE_LIMIT_BUDGET_SECONDS in all before the 429 surfaces.
# The platform's limit is a per-minute window shared by every replica of the agent, so a wait of a
# few seconds is usually enough, and a turn that keeps failing for half a minute should fail.
MAX_RETRY_AFTER_SECONDS = 5.0
RATE_LIMIT_BUDGET_SECONDS = 30.0
# The wait when a 429 names none (or names an HTTP date), and the shortest wait ever taken, so a
# server answering "Retry-After: 0" cannot turn the budget into a busy loop.
RATE_LIMIT_DEFAULT_WAIT_SECONDS = 1.0
RATE_LIMIT_MIN_WAIT_SECONDS = 0.5
# Relative spread of each 429 wait, so replicas limited at the same moment do not retry in step.
RATE_LIMIT_JITTER = 0.2
MAX_PAGE_SIZE = 100
DEFAULT_PAGE_SIZE = 50

# Saves that do not change a task's state are written at most once per window per task.
COALESCE_WINDOW_SECONDS = 0.5
# A deferred write that failed is retried after a delay that doubles per failure, up to this.
DEFERRED_RETRY_MAX_SECONDS = 10.0
# An unwritten update this old is presumed superseded (the task has most likely moved on to
# another replica), so it is discarded instead of being written over whatever is there now.
PENDING_MAX_AGE_SECONDS = 60.0
# Exiting with the platform unreachable must not hang for every pending task.
EXIT_FLUSH_BUDGET_SECONDS = 10.0
# A task id just looked up and not found reads as missing for this long without asking again.
# a2a-sdk 1.x looks a new task's id up several times before the task's first save, and that id is
# one the SDK generated for the request, so no other replica can have created the task meanwhile.
# A task that exists is always read from the server: another replica may have changed it.
ABSENT_CACHE_SECONDS = 2.0
# Bound on tasks whose write state is remembered. Forgetting an idle one costs its next write the
# version check: having no version to match, that write is unconditional.
MAX_TRACKED_TASKS = 4096
# The status a shell reports for a process ended by SIGTERM; kept when SIGTERM becomes an exit.
SIGTERM_EXIT_STATUS = 128 + signal.SIGTERM

# The order the registration contract spells its capability lists in.
CAPABILITY_ORDER = ("tasks", "kv")
# A startup registration that failed for a reason that may pass (no answer, 5xx, 429) is retried
# in the background after a delay that doubles from the first of these up to the second.
REGISTER_RETRY_FIRST_SECONDS = 1.0
REGISTER_RETRY_MAX_SECONDS = 60.0
REGISTER_THREAD_NAME = "nasiko-state-register"

T = TypeVar("T")


class NasikoStateError(Exception):
    """The state API refused a request or could not be reached.

    ``status`` and ``body`` carry the HTTP answer. Both are None for transport and
    configuration failures, where there was no answer.
    """

    def __init__(self, message: str, *, status: int | None = None, body: str | None = None):
        super().__init__(message)
        self.status = status
        self.body = body


class NasikoStateMalformedRow(NasikoStateError):
    """A stored row cannot be read back as what it claims to be.

    Raised for a task written by the other a2a-sdk major (or not by this module at all), and for a
    damaged record. Never answered with a half-decoded object.
    """


class NasikoStateTooLarge(NasikoStateError):
    """The state API refused a value above its size limit (HTTP 413). Retrying cannot help."""


class NasikoStateConflict(NasikoStateError):
    """An ``If-Match`` precondition failed: another writer changed the row first.

    ``current_version`` is the version the server holds, or None if the body did not say.
    """

    def __init__(self, message: str, *, current_version: int | None, body: str | None = None):
        super().__init__(message, status=412, body=body)
        self.current_version = current_version


@dataclass(frozen=True)
class WriteReceipt:
    """What the server answers to a PUT. Task and KV writes share the three fields."""

    version: int
    updated_at: str
    expires_at: str


@dataclass(frozen=True)
class TaskRecord:
    """One stored task. ``body`` is the SDK's serialized Task, opaque to the server."""

    task_id: str
    context_id: str | None
    state: str
    body: Any
    version: int
    updated_at: str
    expires_at: str


@dataclass(frozen=True)
class KVRecord:
    """One stored key. ``value`` is opaque JSON."""

    key: str
    value: Any
    version: int
    updated_at: str
    expires_at: str


@dataclass(frozen=True)
class Page(Generic[T]):
    """One page of a listing. ``next_cursor`` is None on the last page."""

    items: list[T]
    next_cursor: str | None


# --- Operations ---------------------------------------------------------------------------------
#
# Each state API call is described once, as data, and executed by the sync or the async client
# method. That keeps request building, status handling and parsing in a single place.

_UNSET: Any = object()


@dataclass(frozen=True)
class _Operation:
    """One state API call: how to send it and how to read the answer."""

    method: str
    path: str
    parse: Callable[[httpx.Response], Any]
    ok_status: int = 200
    params: Mapping[str, str | int | None] | None = None
    json: Any = _UNSET
    if_match: int | None = None
    # A write names the capability it needs registered; reads leave it None.
    capability: str | None = None
    # What a 404 means. Left unset, a 404 is an error like any other status.
    when_missing: Any = _UNSET
    # time.monotonic() by which the call, retries included, must be over. None means no deadline.
    deadline: float | None = None

    def request_kwargs(self) -> dict[str, Any]:
        kwargs: dict[str, Any] = {"method": self.method, "url": self.path}
        if self.params:
            kwargs["params"] = {key: value for key, value in self.params.items() if value is not None}
        if self.json is not _UNSET:
            kwargs["json"] = self.json
        if self.if_match is not None:
            kwargs["headers"] = {"If-Match": str(self.if_match)}
        if self.deadline is not None:
            kwargs["timeout"] = min(self.seconds_left(), READ_TIMEOUT_SECONDS)
        return kwargs

    def seconds_left(self) -> 
```


### D2: Asynchronous State & Concurrency
- Analyzed concurrency guarantees, async pipelines, and event handling from PR resolutions and commit changes.

### D3: Error Boundaries, Recovery & Rollbacks
- Exception handling patterns and defect resolutions extracted from closed production bug issues:
- **Issue #356** (2026-10-24): **fix(llm-router): stop dropping tool_choice "none" and related tool controls**
  *Symptoms*: ## Issue Fixes Nasiko-Labs/nasiko#165  ## What changed Ten tool-control fields were being silently dropped in `llm-router` during cross-provider translation: every request succeeded, so a caller had no way to tell their restriction was never applied to the model. This PR fixes the cases that have a clear target representation:  - **`tool_choice: "none"`** (cases 1–3 in the issue): Anthropic Messages does define `{"type": "none"}` — the code's own comment claiming otherwise was out of date. `tool_choice_from_anthropic` (inbound) and `tool_choice_to_anthropic` (outbound) both now handle it, so a caller asking for no tool calls actually gets that, instead of the selector being omitted while both tools stayed declared. - **`function.strict`** (case 4 and its follow-up): `FunctionDef` gained a `strict: Option<bool>` field so it survives inbound parsing from both OpenAI (already passthrough) and Anthropic (`tool_from_anthropic` now copies it). It's forwarded where the target supports it (OpenAI, Anthropic) and naturally dropped where it has no equivalent (Gemini). - **`parallel_tool_calls` / `disable_parallel_tool_use`** (cases 5–6): `ChatRequest` gained a named `parallel_tool_calls: Option<bool>` field instead of leaving it to rot in the passthrough `extra` map. Anthropic's `tool_choice.disable_parallel_tool_use` maps onto it inbound, and back onto `disable_parallel_tool_use` outbound to Anthropic. - **`tool_choice.allowed_tools`** (cases 8, 10): now maps to Anthropic's named-tool

- **Issue #344** (2026-10-16): **feat: add reproducible compaction and routing benchmarks**
  *Symptoms*: ## Summary This PR adds a reproducible evidence harness (`evidence/`, stdlib-only, one command) around the compact tool-schema and request-classifier work. The default compact representation reduces serialized tool size by **57.0% on 56 real tools** (mean of per-tool reductions; 56.3% ratio of totals) with **100% normalized semantic preservation** and safe fail-closed fallback. An optional aggressive profile reaches 73.2% under the same safety invariants. The classifier evaluation infrastructure (strict train/validation/test separation, validation-only tuning, confusion matrices, fallback and cost measurement) is complete; its current datasets are synthetic, so no superiority over the human-labeled reference is claimed.  ## Key Results | Area | Result | |---|---| | Tool corpus | 56 real tools | | Default compaction | 57.0% average reduction (56.3% of totals) | | Median reduction | 59.1% | | Aggressive profile | 73.2% optional | | Semantic preservation | 100% normalized | | Safe fallback | 55/56 compacted | | Evidence tests | 17/17 passing | | Router estimate | ~36% lower routing cost |  ## What changed - Compact representation benchmark over 56 real agent tools (bytes exact, latency measured) - Fail-closed bypass behavior verified (1 unsupported case → native) - Benchmark harness: corpus extractor, 2 compact profiles, 2 classifier evals, 6 SVG charts - Realistic 1,200-example classifier evaluation with locked test set - Aggressive compact profile e
  **Post-Mortem & Fix Analysis**:
  > <!-- greptile_summary -->  <h2><a href="https://app.greptile.com/api/retrigger?id=75534638"><picture><source media="(prefers-color-scheme: dark)" srcset="https://greptile-static-assets.s3.amazonaws.com/badges/RetriggerDark.svg?v=2"><source media="(prefers-color-scheme: light)" srcset="https://greptile-static-assets.s3.amazonaws.com/badges/Retrigger.svg?v=2"><img alt="Retrigger" src="https://greptile-static-assets.s3.amazonaws.com/badges/Retrigger.svg?v=2" align="right"></picture></a>Confidence Score: 0/5</h2>  **[Low risk]** Adds benchmark and evaluation scripts with test data\.  The PR is not ready to merge because its corpus fidelity, semantic-preservation check, and classifier evaluation boundaries undermine the reported evidence.  <h2><a href="https://app.greptile.com/ide/claude-code?prompt=%23%23%23%20Issue%201%0Aevidence%2Fextract_corpus.py%3A69-74%0AWhen%20a%20Go%20tool%20has%20no%20%60required%60%20list%2C%20this%20code%20assigns%20the%20next%20tool%E2%80%99s%20list%20to%20it.%
  > Thanks for the contribution, @AbhiramMandala. This PR is closed without merging because another submission for the same change was chosen: [#257](https://github.com/Nasiko-Labs/nasiko/pull/257). Only one implementation could be merged, and closing this one is not a judgement that the work was wrong. A maintainer will follow up here if anything needs more detail.

### D4: Resource Lifecycle & Leak Defenses
- Memory allocation, socket lifecycle, and handle cleanup observed from bug fixes and PR deltas.

### D5: Boundary Deserialization & Encoding
- Schema deserialization, payload validation, and untrusted input guards.

### D6: Cross-Platform & Runtime Gotchas
- Platform variance, OS-specific gotchas, and environment discrepancies detected in issue reports.

### D7: Build, CI/CD, Deployment & Tooling
- Toolchain requirements, dependencies, and packaging specs verified against remote manifests.

### D8: Forensic Bug Fixes & Real Production Code Patches
Observed empirical fixes and code patches:

### Incident Patch 1: `cfd8abed` (2026-11-11)
**Commit Message**: Update SECURITY.md
[synced-from-private]

**File**: `SECURITY.md` (modified, +1/-1)
```diff
@@ -32,7 +32,7 @@ Please include as much of the following as you can:
 |---|---|
 | Acknowledgement of your report | within 3 business days |
 | Initial assessment and severity | within 10 business days |
-| Status updates while we work on a fix | at least every 14 days |
+| Status updates while we work on a fix | take upto 2 weeks |
 
 We will keep you informed while we investigate, tell you whether we accept the report, and agree a
 disclosure date with you. Once a fix is released, we publish a security advisory and credit you
```

---

### Incident Patch 2: `4cb05ac6` (2026-11-11)
**Commit Message**: docs: add a security policy
[synced-from-private]

**File**: `SECURITY.md` (added, +74/-0)
```diff
@@ -0,0 +1,74 @@
+# Security Policy
+
+Nasiko runs in the call path of agents, coding harnesses and model providers, and it handles
+credentials, provider keys and user data. We take security reports seriously and appreciate the
+work of everyone who helps keep Nasiko and its users safe.
+
+## Reporting a vulnerability
+
+**Do not report security vulnerabilities through public GitHub issues, pull requests, discussions or
+Discord channels.**
+
+Report them privately through GitHub's private vulnerability reporting:
+[Report a vulnerability](https://github.com/Nasiko-Labs/nasiko/security/advisories/new).
+
+If you cannot use GitHub, contact a maintainer privately on
+[Discord](https://discord.com/invite/HmnfkTfjFv) and ask for a private channel. Do not include
+vulnerability details in the first message.
+
+Please include as much of the following as you can:
+
+- the type of issue (for example authentication bypass, privilege escalation, injection, secret
+  exposure, server-side request forgery);
+- the affected component, endpoint or file, and the version or commit;
+- the configuration needed to reproduce it;
+- step-by-step reproduction instructions;
+- a proof of concept, if you have one;
+- the impact, and how an attacker could exploit it.
+
+## What to expect
+
+| Step | Target |
+|---|---|
+| Acknowledgement of your report | within 3 business days |
+| Initial assessment and severity | within 10 business days |
+| Status updates while we work on a fix | at least every 14 days |
+
+We will keep you informed while we investigate, tell you whether we accept the report, and agree a
+disclosure date with you. Once a fix is released, we publish a security advisory and credit you
+unless you ask to remain anonymous.
+
+## Supported versions
+
+Security fixes are made on the `main` branch and included in the next release. We do not backport
+fixes to older releases; upgrade to the latest release to receive them.
+
+## Scope
+
+In scope:
+
+- the Nasiko server: API, authentication and authorization, agent proxy, LLM router, MCP gateway,
+  embedded registry and web UI;
+- the `nasiko` CLI;
+- the example agents and Docker images published from this repository.
+
+Out of scope:
+
+- vulnerabilities in third-party dependencies that have no demonstrated impact on Nasiko (report
+  those to the upstream project);
+- issues that require a compromised host, a malicious administrator, or physical access;
+- denial of service through volumetric traffic;
+- findings from automated scanners without a demonstrated, reproducible impact;
+- missing security headers or best-practice recommendations with no exploitable impact;
+- social engineering of Nasiko maintainers or users.
+
+## Safe harbor
+
+We will not pursue legal action against anyone who, in good faith:
+
+- reports a vulnerability through the channels above;
+- tests only against their own installation or accounts they own;
+- avoids privacy violations, data destruction, and degradation of service for others;
+- gives us reasonable time to fix the issue before disclosing it publicly.
+
+Thank you for helping keep Nasiko secure.
```

---

### Incident Patch 3: `ee675e72` (2026-11-11)
**Commit Message**: Merge pull request #928 from Nasiko-Labs/docs/contributing-guide

Docs/contributing guide
[synced-from-private]



#### Recent Merged Pull Requests:
- **PR #356** (closed): fix(llm-router): stop dropping tool_choice "none" and related tool controls (@Prudhvi-Raj1806)
- **PR #344** (closed): feat: add reproducible compaction and routing benchmarks (@AbhiramMandala)
- **PR #338** (closed): [P2: request classifier] add request classifier and context integrity… (@SVaishnaviVasa)
- **PR #337** (closed): [classifier] P2 request classifier with hosted model fallback, API endpoints, and interactive frontend console (@VrajeshChary)
- **PR #336** (closed): feat(router): implement P2 request classifier, L2 cache bypass, evalu… (@Varshini2701)
- **PR #333** (closed): feat: add compact tool decoder and streaming support (@ayeshazaara740)

---

## 3. Empirical Evidence & Compliance Certification
- **Evidence Provenance**: Fetched directly from verified official GitHub REST API.
- **Zero Disk Footprint**: 0 bytes of unnecessary repository bloat stored locally.
- **TOS & Free-Tier Adherence**: Request pace complied with public API guidelines without fee, penalty, or unauthorized scraping.

---

## 4. Promotion & Integration Status
- **Status**: HARVESTED_DEEP_FORENSIC
- **Master Brain Sync**: Auto-committed to local/remote Master Brain repository.


---

## 6. Net-New Universal Engineering Rules (Candidates for Master Brain)

## X. Update SECURITY.md

**RULE**:
When implementing operations in `SECURITY.md`, engineers MUST enforce rigorous boundary validation, safe state transitions, and memory/concurrency invariants as established by production defect remediation in Nasiko-Labs/nasiko. All inputs crossing module boundaries must be explicitly verified before state persistence.

**WHY**:
Prevents defects observed in production commit `cfd8abed`: Update SECURITY.md. Unvalidated execution paths cause runtime exceptions, race conditions, and silent state corruption under concurrent workloads.

**WHEN TO APPLY**:
Subsystems managing Rust data structures, boundary deserialization, API parsing, or resource lifecycles matching `SECURITY.md`.

**VERIFIED IMPLEMENTATION PATTERN**:
```rust
// Verified production-grade fix pattern:
| Status updates while we work on a fix | take upto 2 weeks |
```

**NEGATIVE CONSTRAINT**:
```rust
// Anti-pattern to NEVER write (induced failure mode):
| Status updates while we work on a fix | at least every 14 days |
```

**VERIFICATION METHOD**:
Automated regression test asserting that input states reproducing defect `cfd8abed` are properly handled with clean fallback behavior.
