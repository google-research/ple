# Copyright 2026 Google LLC
#
# Licensed under the Apache License, Version 2.0 (the "License");
# you may not use this file except in compliance with the License.
# You may obtain a copy of the License at
#
#     http://www.apache.org/licenses/LICENSE-2.0
#
# Unless required by applicable law or agreed to in writing, software
# distributed under the License is distributed on an "AS IS" BASIS,
# WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
# See the License for the specific language governing permissions and
# limitations under the License.

"""Tool-calling harness for any OpenAI-compatible model endpoint.

Connects to `MODEL_BASE_URL` using `MODEL_API_KEY` and `MODEL_NAME`. The model
works in the task container through four built-in tools (`bash`, `read_file`,
`write_file`, `edit_file`) plus the task's own MCP tools, and finishes when it
provides a complete answer without calling a tool. That answer becomes the final
message.

Optional environment variables: `MAX_OUTPUT_TOKENS` (default `32000`),
`COMPACT_AT_TOKENS` (default `150000`), and `REASONING_EFFORT` (default `max`
for Claude, `high` for other models).
"""

from __future__ import annotations

import asyncio
import json
import os
import posixpath
import re
import sys
from typing import Any

import openai
import taskbridge

MODEL = os.environ.get("MODEL_NAME", "")
# The model's highest reasoning level: max for Claude, high for the others
# (Gemini refuses max). REASONING_EFFORT overrides it.
EFFORT = os.environ.get("REASONING_EFFORT") or (
    "max" if "claude" in MODEL.lower() else "high"
)
COMPACT_AT_TOKENS = int(os.environ.get("COMPACT_AT_TOKENS", "150000"))
TOOL_RESULT_CHARS = 30_000
# MCP tools are offered as functions up to this many characters of JSON in all
DIRECT_MCP_CHARS = 40_000
# functions one request may offer (OpenAI's limit), the built-in four included
MAX_TOOLS = 128
KEEP_RECENT_RESULTS = 12
FINISH_MARGIN_SEC = 180
RETRY_WAITS = (5, 15, 30, 60, 120)
# How endpoints word an error saying the conversation no longer fits. OpenAI's
# error for too many tools ("'tools':
# array too long") does not match.
CONTEXT_FULL = re.compile(
    r"context.?(length|window|size|limit)|maximum context|too many"
    r" tokens|prompt is too long"
    r"|(input|prompt|request|messages?)\b[^.]{0,40}(too long|exceed)"
    r"|exceed[^.]{0,40}(token|context)",
    re.I,
)
# The context window and the prompt's share of it, as vLLM, OpenAI and Anthropic
# word them in such an error.
WINDOW_RE = re.compile(
    r"maximum context length (?:is |of )?(\d+)"
    r"|context (?:window|length|size)(?: limit)?(?: is| of)? (\d+)"
    r"|tokens? > (\d+) maximum|maximum number of tokens allowed \((\d+)\)",
    re.I,
)
PROMPT_RE = re.compile(
    r"(\d+) input tokens|(\d+) in the messages|prompt is too long: (\d+)"
    r"|input token count \((\d+)\)",
    re.I,
)
MIN_OUTPUT = 1024  # the fewest output tokens to ask for
# characters an unread tool result keeps, however full the context
UNREAD_KEEP = 600
# tokens left free in the window, since tokenizers count a little differently
CONTEXT_MARGIN = 1024
# How endpoints word an error refusing a parameter or value outright, unlike one
# that names a smaller maximum.
UNSUPPORTED = re.compile(
    r"unsupported|unrecogni[sz]ed|unknown|not supported|does not support|not"
    r" (allowed|permitted)"
    r"|extra (inputs|fields)|unexpected",
    re.I,
)
# The standard fields of a streamed tool call, of its function, and of a reply's
# delta. Any other field an endpoint sends goes back with the message: Gemini
# refuses a tool call without its thought signature, which comes in the call's
# extra_content.
CALL_FIELDS = {"index", "id", "type", "function"}
FUNCTION_FIELDS = {"name", "arguments"}
DELTA_FIELDS = {
    "role",
    "content",
    "tool_calls",
    "function_call",
    "refusal",
    "audio",
    "annotations",
    "reasoning_content",
    "reasoning",
}

client = openai.AsyncOpenAI(
    base_url=os.environ.get("MODEL_BASE_URL"),
    api_key=os.environ.get("MODEL_API_KEY") or "none",
    max_retries=0,
    timeout=900,
)

SYSTEM = """You are an expert engineer working on a task in a Linux container. Your tools act inside it: bash (it \
starts in {workdir}), read_file, write_file and edit_file. The container has no internet access.{mcp}

How to work:
- Read the whole task, then look at the files you were given before choosing an approach.
- Work in small, verified steps. Compute numbers with code rather than by hand, and check units.
- When the task says how the result is checked (a time limit, a format, a test), check it that way yourself.
- Write each deliverable exactly where, under the name and in the format the task asks for. Write it early, then \
improve it.
- Produce office and binary formats (docx, xlsx, pdf, ...) with code, such as python3 and the libraries in the \
container, so they are real files of that format.
- Before you finish, open every deliverable again and check that it is complete and readable.
- You have about {minutes} minutes in total; the time left is shown after the results of your tools.

When the work is done, answer without calling a tool: a short summary of what you delivered (the path of each file) \
and the key results. That answer is graded together with your files."""

MCP_DIRECT = """

The task also offers its own tools (the functions named <server>__<tool>)."""

MCP_CATALOG = """

The task also offers its own tools, listed below by server. Call mcp_find to see a tool's parameters, then mcp_call \
to run it.
{catalog}"""

SUMMARY_PROMPT = """The conversation is getting long, so the earlier turns will be removed. Write notes that let you \
continue without them: what the task requires, what you found in the files, every file you created or changed (with \
its path and state), the numbers and decisions so far, and what remains to do. Be specific."""


def tool(
    name: str, description: str, required: list[str], **properties: Any
) -> dict[str, Any]:
  """Builds an OpenAI function-tool definition dictionary.

  Args:
    name: Tool function name.
    description: Human-readable tool description.
    required: List of required parameter names.
    **properties: Parameter JSON Schema definitions keyed by parameter name.

  Returns:
    An OpenAI function-tool specification dictionary.
  """
  return {
      "type": "function",
      "function": {
          "name": name,
          "description": description,
          "parameters": {
              "type": "object",
              "properties": properties,
              "required": required,
          },
      },
  }


TOOLS = [
    tool(
        "bash",
        "Run a bash command in the task container and return its exit code and"
        " output. Each call starts a new shell in the working directory: only"
        " files persist between calls.",
        ["command"],
        command={"type": "string"},
        timeout_sec={
            "type": "integer",
            "description": (
                "Stop the command after this many seconds (default 120)."
            ),
        },
    ),
    tool(
        "read_file",
        "Read a text file from the task container.",
        ["path"],
        path={"type": "string"},
    ),
    tool(
        "write_file",
        "Create or overwrite a file in the task container; parent directories"
        " are created.",
        ["path", "content"],
        path={"type": "string"},
        content={"type": "string"},
        append={
            "type": "boolean",
            "description": (
                "Add to the end of the file instead (write a large file in"
                " parts)."
            ),
        },
    ),
    tool(
        "edit_file",
        "Replace exact text in a file. old_text must occur exactly once unless"
        " replace_all is true.",
        ["path", "old_text", "new_text"],
        path={"type": "string"},
        old_text={"type": "string"},
        new_text={"type": "string"},
        replace_all={"type": "boolean"},
    ),
]
MCP_TOOLS = [
    tool(
        "mcp_find",
        "Show the description and parameters of the task's own tools that match"
        " a query.",
        ["query"],
        query={
            "type": "string",
            "description": "A tool name, or words describing what you need.",
        },
    ),
    tool(
        "mcp_call",
        "Run one of the task's own tools.",
        ["tool", "arguments"],
        tool={"type": "string", "description": "The tool's name as listed."},
        arguments={"type": "object"},
    ),
]


def clip(text: str, limit: int = TOOL_RESULT_CHARS) -> str:
  """Truncates `text` in the middle if it exceeds `limit` characters.

  Args:
    text: String to clip.
    limit: Maximum character length before truncation.

  Returns:
    The original string if within `limit`, or a middle-truncated string.
  """
  if len(text) <= limit:
    return text
  head = limit * 2 // 3
  return (
      f"{text[:head]}\n[... {len(text) - limit} characters cut"
      f" ...]\n{text[-(limit - head):]}"
  )


def parse_arguments(call: dict[str, Any]) -> dict[str, Any] | str:
  """Parses a tool call's arguments into a dict or returns an error string.

  Rewrites `call["arguments"]` as canonical JSON (`"{}"` when invalid) because
  endpoints reject conversations containing malformed tool-call arguments.

  Args:
    call: Tool-call dictionary with an `arguments` JSON string field.

  Returns:
    The parsed arguments dictionary, or an error string for the model.
  """

  def reject(constant):
    raise ValueError(f"{constant} is not valid JSON")

  try:
    args = json.loads(call["arguments"] or "{}", parse_constant=reject)
    if not isinstance(args, dict):
      raise ValueError("the arguments must be a JSON object")
    call["arguments"] = (
        json.dumps(args, ensure_ascii=False)
        .encode("utf-8", "replace")
        .decode("utf-8")
    )
    return args
  except ValueError as exc:
    call["arguments"] = "{}"
    return (
        f"error: the arguments are not a valid JSON object ({exc}); send the"
        " call again"
    )


def unique_name(name: str, taken: Any) -> str:
  """Truncates `name` to 64 chars and appends `_2`, `_3`, ... if in `taken`.

  Args:
    name: Desired function name.
    taken: Collection or mapping of already-used function names.

  Returns:
    A unique function name of at most 64 characters.
  """
  candidate, n = name[:64], 1
  while candidate in taken:
    n += 1
    candidate = f"{name[:63 - len(str(n))]}_{n}"
  return candidate


def visible(text: str) -> str:
  """Strips `<think>...</think>` reasoning blocks from `text`.

  Args:
    text: Assistant response content string.

  Returns:
    The trimmed response text with inline `<think>` blocks removed.
  """
  return re.sub(r"<think>.*?(</think>|$)", "", text or "", flags=re.S).strip()


def extra_fields(part: Any, known: set[str]) -> dict[str, Any]:
  """Extracts non-null extra fields from a streamed SDK object `part`.

  The OpenAI SDK stores undeclared provider fields in `part.model_extra`.

  Args:
    part: Streamed Pydantic model object (delta, tool call, or function).
    known: Set of standard field names to exclude.

  Returns:
    Dictionary of extra fields not in `known` whose values are not `None`.
  """
  fields = getattr(part, "model_extra", None) or {}
  return {k: v for k, v in fields.items() if k not in known and v is not None}


def merged(old: Any, new: Any, key: str = "") -> Any:
  """Merges a single delta's extra field value `new` into `old`.

  Merges dictionaries key-by-key, concatenates lists, and replaces scalars.
  Delegates `thinking_blocks` lists to `thinking_blocks()`.

  Args:
    old: Accumulated field value so far.
    new: Incoming delta field value.
    key: Field name being merged.

  Returns:
    The merged field value.
  """
  if key == "thinking_blocks" and isinstance(new, list):
    return thinking_blocks(old if isinstance(old, list) else [], new)
  if isinstance(old, dict) and isinstance(new, dict):
    return {**old, **{k: merged(old.get(k), v, k) for k, v in new.items()}}
  if isinstance(old, list) and isinstance(new, list):
    return old + new
  return new


def thinking_blocks(
    blocks: list[dict[str, Any]], new: list[Any]
) -> list[dict[str, Any]]:
  """Accumulates streamed Claude `thinking_blocks` deltas.

  Joins consecutive deltas into the current block until a `signature` closes it;
  redacted blocks (containing `data`) arrive whole and are kept separate.

  Args:
    blocks: Existing list of accumulated thinking blocks.
    new: New list of thinking block deltas from the stream chunk.

  Returns:
    Updated list of thinking block dictionaries.
  """
  out = [dict(b) for b in blocks]
  for b in new:
    if not isinstance(b, dict):
      continue
    last = out[-1] if out else None
    if (
        last is None
        or last.get("signature")
        or last.get("data")
        or b.get("data")
        or last.get("type") != b.get("type")
    ):
      out.append(dict(b))
      continue
    last["thinking"] = (last.get("thinking") or "") + (b.get("thinking") or "")
    if b.get("signature"):
      last["signature"] = b["signature"]
  return out


def signed(block: Any) -> bool:
  """Returns whether `block` has a `signature` or redacted `data` field.

  Args:
    block: Candidate thinking block dictionary.

  Returns:
    `True` if Claude will accept `block` in a subsequent turn, else `False`.
  """
  return isinstance(block, dict) and bool(
      block.get("signature") or block.get("data")
  )


def drop_thinking(
    message: dict[str, Any], unless: Any = lambda block: False
) -> dict[str, Any]:
  """Filters `thinking_blocks` in `message`, keeping blocks matching `unless`.

  Args:
    message: Assistant message dictionary to modify in place.
    unless: Predicate `unless(block)` returning `True` for blocks to keep.

  Returns:
    The modified `message` dictionary.
  """
  if isinstance(message.get("thinking_blocks"), list):
    message["thinking_blocks"] = [
        b for b in message["thinking_blocks"] if unless(b)
    ]
  fields = message.get("provider_specific_fields")
  if isinstance(fields, dict) and isinstance(
      fields.get("thinking_blocks"), list
  ):
    message["provider_specific_fields"] = {
        **fields,
        "thinking_blocks": [b for b in fields["thinking_blocks"] if unless(b)],
    }
  return message


class MCPServer(taskbridge.MCPClient):
  """Client wrapper for a single task MCP server and its discovered tools."""

  def __init__(self, session: taskbridge.Session, spec: dict[str, Any]):
    super().__init__(session, spec["url"], client="custom-harness")
    self.name = spec["name"]
    self.tools: list[dict[str, Any]] = []

  async def start(self) -> None:
    """Initializes the MCP session and fetches the server's tool list."""
    await self.initialize()
    self.tools = await self.list_tools()

  async def call(self, name: str, arguments: dict[str, Any]) -> str:
    """Calls tool `name` on the MCP server and formats the result as text.

    Args:
      name: Unprefixed MCP tool name on this server.
      arguments: Tool input arguments dictionary.

    Returns:
      Formatted text output (prefixed with `error: ` if `isError` is set).
    """
    result = await self.call_tool(name, arguments)
    parts = []
    content = (
        result.get("content") if isinstance(result.get("content"), list) else []
    )
    for item in content:
      kind = item.get("type") if isinstance(item, dict) else None
      if kind == "text":
        parts.append(str(item.get("text", "")))
      elif kind == "resource":
        parts.append(json.dumps(item.get("resource"))[:TOOL_RESULT_CHARS])
      elif kind == "resource_link":  # its uri, name and mimeType
        parts.append(json.dumps(item)[:TOOL_RESULT_CHARS])
      else:
        parts.append(f"[{kind or 'unknown'} content not shown]")
    if not parts and result.get("structuredContent") is not None:
      parts.append(json.dumps(result["structuredContent"]))
    text = "\n".join(parts) or "(no content)"
    return f"error: {text}" if result.get("isError") else text


class Reply:
  """Accumulates a streamed chat-completion response and its tool calls."""

  def __init__(self):
    self.text, self.reasoning, self.calls, self.usage, self.finish = (
        "",
        "",
        {},
        None,
        None,
    )
    self.extra = {}  # fields beyond DELTA_FIELDS, sent back with the message
    self._by_index, self._by_id, self._last = {}, {}, None

  def add_call(self, part: Any) -> None:
    """Adds one streamed tool-call delta to the accumulated calls.

    Groups deltas by `index`, or by `id` when an endpoint omits or reuses
    `index`. Deltas with neither continue the most recent call unless
    `_another_call` detects a new call boundary. Preserves provider-specific
    extra fields on both the call and its `function`.

    Args:
      part: Streamed tool-call delta object from a completion chunk.
    """
    index, call_id = (
        getattr(part, "index", None),
        getattr(part, "id", None) or "",
    )
    function = getattr(part, "function", None)
    name = (getattr(function, "name", None) or "") if function else ""
    key = self._by_index.get(index) if index is not None else None
    if (
        key is not None
        and call_id
        and self.calls[key]["id"] not in ("", call_id)
    ):
      key = None
    if (
        key is not None
        and not call_id
        and name
        and self._another_call(self.calls[key], name)
    ):
      key = None
    if key is None and call_id:
      key = self._by_id.get(call_id)
    if (
        key is None
        and index is None
        and not call_id
        and self._last is not None
        and not (name and self._another_call(self.calls[self._last], name))
    ):
      key = self._last
    if key is None:
      key = len(self.calls)
      self.calls[key] = {
          "id": "",
          "name": "",
          "arguments": "",
          "extra": {},
          "function_extra": {},
      }
    if index is not None:
      self._by_index[index] = key
    if call_id:
      self._by_id[call_id] = key
    call = self.calls[key]
    call["id"] = call["id"] or call_id
    call["name"] = call["name"] or name
    call["arguments"] += (
        (getattr(function, "arguments", None) or "") if function else ""
    )
    call["extra"] = merged(call["extra"], extra_fields(part, CALL_FIELDS))
    if function:
      call["function_extra"] = merged(
          call["function_extra"], extra_fields(function, FUNCTION_FIELDS)
      )
    self._last = key

  @staticmethod
  def _another_call(call: dict[str, Any], name: str) -> bool:
    """Checks whether a nameless-ID delta for `name` starts a new tool call.

    Returns `True` when `call` already has a function name and either `name`
    differs or `call["arguments"]` is already a complete JSON object.

    Args:
      call: Currently accumulating tool-call dictionary.
      name: Function name on the incoming delta.

    Returns:
      `True` if the delta begins a separate tool call, else `False`.
    """
    if not call["name"]:
      return False
    if name != call["name"]:
      return True
    try:
      return isinstance(json.loads(call["arguments"]), dict)
    except ValueError:
      return False

  def message(self) -> dict[str, Any]:
    """Builds the assistant message dict for the conversation history.

    Preserves provider-specific fields while stripping unsigned thinking blocks
    that Claude would reject.

    Returns:
      The formatted assistant message dictionary.
    """
    message = {**self.extra, "role": "assistant", "content": self.text or None}
    if self.calls:
      message["tool_calls"] = [
          {
              **c["extra"],
              "id": c["id"],
              "type": "function",
              "function": {
                  **c["function_extra"],
                  "name": c["name"],
                  "arguments": c["arguments"],
              },
          }
          for c in self.calls.values()
      ]
    if self.reasoning:
      message["reasoning_content"] = self.reasoning
    return drop_thinking(message, unless=signed)


class OutOfTime(Exception):  # pylint: disable=g-bad-exception-name
  """Raised when retrying a failed model call would exceed the time budget."""


class CutOff(asyncio.TimeoutError):  # pylint: disable=g-bad-exception-name
  """Raised when a streamed reply is cut off by its per-call deadline."""


class Agent:
  """Manages the conversation, tool execution, and context compaction loop."""

  def __init__(self, session: taskbridge.Session):
    self.session = session
    self.tools = list(TOOLS)
    self.mcp: dict[str, tuple[MCPServer, dict[str, Any]]] = {}
    self.messages: list[dict[str, Any]] = []
    self.prompt_tokens = 0
    # Each call asks for output_limit(): output_ceiling (MAX_OUTPUT_TOKENS,
    # lowered by shrink_output when the endpoint refuses that many), or less
    # when the context window has less room beside the prompt.
    self.output_ceiling = int(os.environ.get("MAX_OUTPUT_TOKENS", "32000"))
    self.context_window: int | None = None  # learned from a context-full error
    self.max_output = self.output_ceiling  # the limit the last call asked for
    # max_tokens once an endpoint refuses this one
    self.token_limit = "max_completion_tokens"
    # empty once an endpoint refuses it
    self.effort = {"reasoning_effort": EFFORT}
    self.finish_margin = FINISH_MARGIN_SEC

  async def run(self) -> str:
    """Runs the agent tool-calling loop until the task is complete.

    Returns:
      The final summary message produced by the agent.
    """
    mcp = await self.connect_mcp()
    left = self.session.time_left()
    # time kept for the final summary: FINISH_MARGIN_SEC, or a quarter of a
    # short task's time
    self.finish_margin = (
        FINISH_MARGIN_SEC
        if left is None
        else min(FINISH_MARGIN_SEC, max(left, 0) / 4)
    )
    self.messages = [
        {
            "role": "system",
            "content": SYSTEM.format(
                workdir=self.session.workdir,
                mcp=mcp,
                minutes=int(left / 60) if left else "unlimited",
            ),
        },
        {"role": "user", "content": self.session.instruction},
    ]
    # head: the text of an answer cut off at the output limit
    nudges, head = 0, ""
    while True:
      left = self.session.time_left()
      if left is not None and left < self.finish_margin:
        return await self.finish("Time is almost up.")
      try:
        reply = await self.complete(head=head)
      except OutOfTime:
        return await self.finish(
            "Time is almost up, and the model is not answering."
        )
      # what it streamed is the answer if the summary call fails too
      except CutOff:
        return await self.finish("Time is almost up.")
      arguments = [parse_arguments(call) for call in reply.calls.values()]
      if reply.text or reply.calls:
        # A turn with neither (its output went to hidden reasoning, or a content
        # filter stopped it) is not sent back: endpoints refuse an assistant
        # message with null content and no tool calls.
        self.messages.append(reply.message())
      text = visible(head + reply.text)
      if text:
        self.session.final_message = text
      if not reply.calls:
        if visible(reply.text) and reply.finish == "length":
          # cut off at the output limit: ask for the rest, and reset the
          # empty-turn count
          nudges, head = 0, head + reply.text
          self.messages.append({
              "role": "user",
              "content": (
                  f"Your reply was cut off at the {self.max_output}-token"
                  " output limit. Continue where it stopped, and put long"
                  " content in files with write_file rather than in a reply."
              ),
          })
          continue
        if visible(reply.text) or nudges >= 2:
          return text or self.session.final_message
        nudges += 1  # only consecutive empty turns end the run
        self.messages.append({
            "role": "user",
            "content": (
                "Continue the task; when it is done, answer with "
                "your summary of the deliverables."
            ),
        })
        continue
      nudges, head = 0, ""
      for call, args in zip(reply.calls.values(), arguments):
        result = (
            await self.run_tool(call["name"], args)
            if isinstance(args, dict)
            else args
        )
        if reply.finish == "length" and isinstance(args, str):
          result += (
              f" Your reply hit the {self.max_output}-token output limit; write"
              " large files in parts."
          )
        self.messages.append(
            {"role": "tool", "tool_call_id": call["id"], "content": result}
        )
      left = self.session.time_left()
      if left is not None:
        self.messages[-1]["content"] += f"\n[{int(left // 60)} minutes left]"
      if self.prompt_tokens > self.compact_at():
        await self.compact()

  async def finish(self, why: str) -> str:
    """Prompts the model for a final summary without tools when time is up.

    Args:
      why: Reason string prepended to the wrap-up prompt.

    Returns:
      The final summary text, falling back to `self.session.final_message`.
    """
    self.messages.append({
        "role": "user",
        "content": (
            f"{why} Stop working now and answer with your final "
            "summary: what you delivered, where, and the key results."
        ),
    })
    left = self.session.time_left()
    # the summary call gets taskbridge.time_share(left, 30) seconds, and at
    # least 5
    reserve = (
        0 if left is None else left - max(5, taskbridge.time_share(left, 30))
    )
    try:
      text = visible(
          (
              await self.complete(tool_choice="none", reserve=reserve, head="")
          ).text
      )
    except (CutOff, openai.OpenAIError, OutOfTime):
      text = ""
    return text or self.session.final_message

  async def connect_mcp(self) -> str:
    """Connects to the task's MCP servers and registers their tools.

    Exposes a small set of MCP tools directly as OpenAI functions; for larger
    tool sets, lists their names in the system prompt and exposes `mcp_find`
    and `mcp_call`.

    Returns:
      The system-prompt section describing the available MCP tools.
    """
    for spec in self.session.mcp_servers:
      server = MCPServer(self.session, spec)
      try:
        await server.start()
      except (taskbridge.TaskError, RuntimeError, ValueError) as exc:
        await self.session.log(f"MCP server {server.name} unavailable: {exc}")
        continue
      for t in server.tools:
        name = re.sub(r"[^A-Za-z0-9_-]", "_", f"{server.name}__{t['name']}")
        self.mcp[unique_name(name, self.mcp)] = (server, t)
      await self.session.log(
          f"MCP server {server.name}: {len(server.tools)} tools"
      )
    if not self.mcp:
      return ""
    functions = [
        {
            "type": "function",
            "function": {
                "name": name,
                "description": (t.get("description") or t["name"])[:1024],
                "parameters": (
                    {
                        k: v
                        for k, v in (t.get("inputSchema") or {}).items()
                        if k != "$schema"
                    }
                    or {"type": "object", "properties": {}}
                ),
            },
        }
        for name, (_, t) in self.mcp.items()
    ]
    if (
        len(json.dumps(functions)) <= DIRECT_MCP_CHARS
        and len(self.tools) + len(functions) <= MAX_TOOLS
    ):
      self.tools += functions
      return MCP_DIRECT
    self.tools += MCP_TOOLS
    servers: dict[str, list[str]] = {}
    for name, (server, _) in self.mcp.items():
      servers.setdefault(server.name, []).append(name)
    return MCP_CATALOG.format(
        catalog="\n".join(
            f"{s}: {', '.join(names)}" for s, names in servers.items()
        )
    )

  def find_mcp(self, query: str) -> str:
    """Finds MCP tools matching `query` and formats their schemas.

    Returns as many matching tool schemas as fit within `TOOL_RESULT_CHARS`
    (always at least one, without truncating any individual schema).

    Args:
      query: Tool name or search keywords.

    Returns:
      Formatted descriptions and JSON parameter schemas of matching tools.
    """
    words = [w for w in re.split(r"[^a-z0-9]+", query.lower()) if w]

    def score(item):
      name, (_, t) = item
      text = f"{name} {t.get('description') or ''}".lower()
      return (
          (query == name) * 100
          + sum(w in name.lower() for w in words) * 3
          + sum(w in text for w in words)
      )

    best = [
        item
        for item in sorted(self.mcp.items(), key=score, reverse=True)[:8]
        if score(item) > 0
    ]
    if not best:
      return (
          f"no tool matches {query!r}; the names are listed in the system"
          " prompt"
      )
    found = [
        f"{name}: {(t.get('description') or '')[:400]}\nparameters:"
        f" {json.dumps(t.get('inputSchema') or {})}"
        for name, (_, t) in best
    ]
    while len(found) > 1 and len("\n\n".join(found)) > TOOL_RESULT_CHARS:
      found.pop()
    return "\n\n".join(found)

  async def complete(
      self,
      tool_choice: str = "auto",
      reserve: float | None = None,
      head: str | None = None,
  ) -> Reply:
    """Streams one model completion with retries and context-limit recovery.

    Stops streaming `reserve` seconds before the task deadline. Automatically
    adapts token limit parameters, shrinks output ceilings, or compacts the
    conversation when the endpoint reports a context-length error.

    Args:
      tool_choice: OpenAI `tool_choice` value (`"auto"` or `"none"`).
      reserve: Seconds before the task deadline at which to cut off the call.
      head: Prefix text from a prior length-truncated reply, if continuing.

    Returns:
      The completed `Reply` object.

    Raises:
      OutOfTime: If a transient error occurs and there is not enough time left
        to wait and retry.
      CutOff: If the response is still streaming when `reserve` is reached.
      openai.APIError: If a non-retryable API error occurs or retries are
        exhausted.
    """
    reserve = self.finish_margin if reserve is None else reserve
    waits = iter(RETRY_WAITS)
    while True:
      try:
        reply = await self.stream(self.messages, tool_choice, reserve, head)
        await self.record(reply)
        return reply
      except openai.APIStatusError as exc:
        error = str(exc)
        if exc.status_code == 400 and CONTEXT_FULL.search(error):
          # The conversation does not fit. Try in this order:
          # 1. fewer output tokens, when the error shows that alone makes room
          #    (restored as the prompt shrinks);
          # 2. compact() what the model has already read;
          # 3. fewer output tokens anyway, when the error did not give the
          #    prompt's size;
          # 4. cut_unread(), the tool results the model has not read yet.
          sent, measured = self.max_output, self.learn_context(error)
          if (
              measured
              and self.room() >= MIN_OUTPUT
              and self.output_limit() < sent
          ):
            continue
          if (
              await self.compact(force=True)
              or (not measured and self.output_limit() < sent)
              or self.cut_unread()
          ):
            continue
          raise
        if exc.status_code == 400 and (
            self.use_max_tokens(error)
            or self.drop_effort(error)
            or self.shrink_output(error)
        ):
          continue
        if not (exc.status_code in (408, 409, 429) or exc.status_code >= 500):
          raise
        failure = exc
      # a connection error, a timeout, an error inside the stream
      except openai.APIError as exc:
        failure = exc
      wait = next(waits, None)
      if wait is None:
        raise failure
      left = self.session.time_left()
      if left is not None and left - wait < reserve:
        await self.session.log(
            f"model call failed ({str(failure)[:300]}); no time left to wait"
            f" {wait}s"
        )
        raise OutOfTime(str(failure)[:300]) from failure
      await self.session.log(
          f"model call failed ({str(failure)[:300]}); again in {wait}s"
      )
      await asyncio.sleep(wait)

  def use_max_tokens(self, error: str) -> bool:
    """Switches to `max_tokens` if `error` rejects `max_completion_tokens`.

    Args:
      error: Error message string from a 400 `APIStatusError`.

    Returns:
      `True` if the token limit parameter was switched to `max_tokens`.
    """
    if (
        self.token_limit != "max_completion_tokens"
        or "max_completion_tokens" not in error
        or not UNSUPPORTED.search(error)
    ):
      return False
    self.token_limit = "max_tokens"
    return True

  def drop_effort(self, error: str) -> bool:
    """Stops sending `reasoning_effort` once an endpoint refuses it.

    A model without reasoning, or a server that does not know the parameter,
    answers `400` naming it.

    Args:
      error: Error message string from a 400 `APIStatusError`.

    Returns:
      `True` if `reasoning_effort` was being sent and is now dropped.
    """
    if not self.effort or "reasoning_effort" not in error:
      return False
    self.effort = {}
    return True

  def shrink_output(self, error: str) -> bool:
    """Lowers `output_ceiling` when `error` indicates a smaller output limit.

    Args:
      error: Error message string from a 400 `APIStatusError`.

    Returns:
      `True` if `output_ceiling` was reduced, else `False`.
    """
    if UNSUPPORTED.search(error):
      return False
    limit = re.search(r"(\d+)\s*\(exclusive\)", error)
    stated = re.search(
        r"at most (\d+)|(\d+), which is the maximum|maximum (?:allowed"
        r" )?(?:number of )?(?:output|"
        r"completion) tokens (?:is |of )?(\d+)",
        error,
        re.I,
    )
    if limit:
      new = int(limit.group(1)) - 1
    elif stated:
      new = int(next(g for g in stated.groups() if g))
    elif re.search(
        r"max_?(completion_)?tokens|maxOutputTokens|output tokens", error, re.I
    ):
      new = self.max_output // 2
    else:
      return False
    if new >= self.max_output or new < MIN_OUTPUT:
      return False
    self.output_ceiling = new
    return True

  def learn_context(self, error: str) -> bool:
    """Extracts context window and prompt token counts from `error`.

    Args:
      error: Error message string from a context-length `APIStatusError`.

    Returns:
      `True` if both `context_window` and `prompt_tokens` are now known.
    """
    window, prompt = WINDOW_RE.search(error), PROMPT_RE.search(error)
    if window:
      self.context_window = int(next(g for g in window.groups() if g))
    if prompt:
      self.prompt_tokens = int(next(g for g in prompt.groups() if g))
    return bool(prompt and self.context_window)

  def room(self) -> int | None:
    """Returns remaining output token capacity in the known context window.

    Returns:
      Available tokens beside the prompt, or `None` if the window size is
      unknown.
    """
    return (
        self.context_window - self.prompt_tokens - CONTEXT_MARGIN
        if self.context_window
        else None
    )

  def output_limit(self) -> int:
    """Computes the max output tokens to request on the next completion call.

    Returns:
      `output_ceiling`, clamped down to `room()` when known (never below
      `MIN_OUTPUT`).
    """
    room = self.room()
    return (
        self.output_ceiling
        if room is None
        else max(MIN_OUTPUT, min(self.output_ceiling, room))
    )

  def compact_at(self) -> int:
    """Returns the prompt token threshold at which to trigger compaction.

    Returns:
      `COMPACT_AT_TOKENS`, or a lower threshold when the known context window
      requires more room for output.
    """
    if not self.context_window:
      return COMPACT_AT_TOKENS
    room = min(self.output_ceiling, self.context_window // 2)
    return max(
        self.context_window // 4,
        min(COMPACT_AT_TOKENS, self.context_window - room - CONTEXT_MARGIN),
    )

  def estimate_prompt_tokens(self) -> int:
    """Estimates prompt token count at four JSON characters per token.

    Returns:
      Estimated number of tokens in `self.messages`.
    """
    return sum(len(json.dumps(m)) for m in self.messages) // 4

  async def stream(
      self,
      messages: list[dict[str, Any]],
      tool_choice: str,
      reserve: float,
      head: str | None = None,
  ) -> Reply:
    """Streams a single chat completion call up to `reserve` seconds before end.

    If `head` is provided and the stream is cut off or cancelled, updates
    `self.session.final_message` with `visible(head + reply.text)`.

    Args:
      messages: Conversation message list to send.
      tool_choice: OpenAI `tool_choice` setting (`"auto"` or `"none"`).
      reserve: Seconds to hold back before the session deadline.
      head: Prefix text from an earlier truncated response, or `None`.

    Returns:
      The accumulated `Reply` instance.

    Raises:
      CutOff: If the stream times out at `left - reserve`.
      asyncio.CancelledError: If the task is cancelled during streaming.
    """
    left = self.session.time_left()
    self.max_output = self.output_limit()
    reply = Reply()

    async def read():
      stream = await client.chat.completions.create(
          model=MODEL,
          messages=messages,
          tools=self.tools,
          tool_choice=tool_choice,
          stream=True,
          stream_options={"include_usage": True},
          **self.effort,
          **{self.token_limit: self.max_output},
      )
      async for chunk in stream:
        reply.usage = chunk.usage or reply.usage
        if not chunk.choices:
          continue
        delta = chunk.choices[0].delta
        reply.finish = chunk.choices[0].finish_reason or reply.finish
        reply.text += delta.content or ""
        reply.reasoning += (
            getattr(delta, "reasoning_content", None)
            or getattr(delta, "reasoning", None)
            or ""
        )
        reply.extra = merged(reply.extra, extra_fields(delta, DELTA_FIELDS))
        for part in delta.tool_calls or []:
          reply.add_call(part)

    try:
      await asyncio.wait_for(read(), None if left is None else left - reserve)
    except (asyncio.TimeoutError, asyncio.CancelledError) as exc:
      if head is not None:
        self.session.final_message = (
            visible(head + reply.text) or self.session.final_message
        )
      if isinstance(exc, asyncio.CancelledError):
        raise
      raise CutOff() from None
    for n, call in reply.calls.items():
      call["id"] = call["id"] or f"call_{n}_{len(self.messages)}"
      # some open models leak chat-template tokens into it
      call["name"] = call["name"].split("<|")[0].strip()
    return reply

  async def record(self, reply: Reply) -> None:
    """Updates `prompt_tokens` from `reply` and reports token usage.

    Args:
      reply: Completed `Reply` from `stream()`.
    """
    if reply.usage is None:
      self.prompt_tokens = self.estimate_prompt_tokens()
      return
    self.prompt_tokens = reply.usage.prompt_tokens or 0
    await self.report(reply)

  async def report(self, reply: Reply) -> None:
    """Reports token usage from `reply` to the evaluator session if present.

    Args:
      reply: Completed `Reply` whose `usage` should be reported.
    """
    usage = reply.usage
    if usage is None:
      return
    cached = (
        getattr(
            getattr(usage, "prompt_tokens_details", None), "cached_tokens", 0
        )
        or 0
    )
    await self.session.usage(
        MODEL, usage.prompt_tokens or 0, usage.completion_tokens or 0, cached
    )

  async def run_tool(self, name: str, args: dict[str, Any]) -> str:
    """Dispatches a tool call by `name` and returns its clipped text output.

    Args:
      name: Tool function name (`bash`, `read_file`, `write_file`, `edit_file`,
        `mcp_find`, `mcp_call`, or a direct MCP tool name).
      args: Parsed tool arguments dictionary.

    Returns:
      The tool output or error string.
    """
    await self.session.log(f"{name} {json.dumps(args)[:400]}")
    try:
      if name == "mcp_call":
        name, args = str(args.get("tool", "")), args.get("arguments") or {}
        args = json.loads(args) if isinstance(args, str) else args
        if name not in self.mcp:
          return f"error: no tool named {name!r}; use mcp_find"
      if name in self.mcp:
        server, t = self.mcp[name]
        return clip(await server.call(t["name"], args))
      if name == "mcp_find":
        return self.find_mcp(str(args.get("query", "")))
      handler = {
          "bash": self.bash,
          "read_file": self.read_file,
          "write_file": self.write_file,
          "edit_file": self.edit_file,
      }.get(name)
      return (
          clip(await handler(**args))
          if handler
          else f"error: there is no tool named {name}"
      )
    except taskbridge.TaskError as exc:
      return f"error: {exc}"
    except (
        AttributeError,
        KeyError,
        TypeError,
        ValueError,
        RuntimeError,
    ) as exc:
      return f"error: {type(exc).__name__}: {exc}"

  def path(self, path: str) -> str:
    """Resolves `path` relative to `self.session.workdir` if not absolute.

    Args:
      path: Absolute or workdir-relative file path.

    Returns:
      The resolved container path string.
    """
    return (
        path
        if path.startswith("/")
        else posixpath.join(self.session.workdir, path)
    )

  async def bash(self, command: str, timeout_sec: int = 120) -> str:
    """Executes `command` with bash in the task container.

    Args:
      command: Shell command string to run.
      timeout_sec: Timeout in seconds.

    Returns:
      Formatted exit code and command output string.
    """
    cap = int(self.session.limits.get("exec_timeout_sec") or 600)
    result = await self.session.exec(
        command, taskbridge.positive_int(timeout_sec, 120, cap)
    )
    note = " (timed out)" if result.get("timed_out") else ""
    return (
        "exit code"
        f" {result['exit_code']}{note}\n{result['output'] or '(no output)'}"
    )

  async def read_file(self, path: str) -> str:
    """Reads a UTF-8 text file from `path` in the task container.

    Args:
      path: File path inside the task container.

    Returns:
      Decoded file contents, or a notice if the file is binary or empty.
    """
    data = await self.session.read_file(self.path(path))
    if b"\0" in data[:8192]:
      return (
          f"{path} is a binary file ({len(data)} bytes); inspect it with bash"
          " (python3, unzip -l, ...)"
      )
    return data.decode("utf-8", "replace") or "(empty file)"

  async def write_file(
      self, path: str, content: str, append: bool = False
  ) -> str:
    """Writes or appends `content` to `path` in the task container.

    Args:
      path: Destination file path inside the task container.
      content: Text content to write.
      append: Whether to append to the file instead of overwriting.

    Returns:
      Confirmation string with the resulting file size in bytes.
    """
    size = await self.session.write_file(
        self.path(path), content, append=bool(append)
    )
    return f"{path} now holds {size} bytes"

  async def edit_file(
      self, path: str, old_text: str, new_text: str, replace_all: bool = False
  ) -> str:
    """Replaces `old_text` with `new_text` in `path` inside the task container.

    Args:
      path: Target file path inside the task container.
      old_text: Substring to search for.
      new_text: Replacement string.
      replace_all: Whether to replace all occurrences instead of requiring one.

    Returns:
      Confirmation string or an error message if `old_text` is missing or
      ambiguous.
    """
    text = (await self.session.read_file(self.path(path))).decode("utf-8")
    count = text.count(old_text) if old_text else 0
    if count == 0:
      return f"error: old_text was not found in {path}"
    if count > 1 and not replace_all:
      return (
          f"error: old_text occurs {count} times in {path}; add context to make"
          " it unique, or set replace_all"
      )
    await self.session.write_file(
        self.path(path),
        text.replace(old_text, new_text, -1 if replace_all else 1),
    )
    return f"replaced {count if replace_all else 1} occurrence(s) in {path}"

  def unread(self) -> list[dict[str, Any]]:
    """Returns tool result messages appended after the last assistant turn.

    Returns:
      List of unread `"tool"` role message dictionaries.
    """
    last = max(
        (n for n, m in enumerate(self.messages) if m["role"] == "assistant"),
        default=0,
    )
    return [m for m in self.messages[last:] if m["role"] == "tool"]

  async def compact(self, force: bool = False) -> bool:
    """Compacts conversation history without modifying unread tool results.

    First truncates older read tool outputs (keeping `KEEP_RECENT_RESULTS`
    unless `force` is `True`). If that is insufficient, summarizes older turns
    via a model call. Drops thinking blocks after any modified message index so
    Claude does not reject subsequent requests.

    Args:
      force: Whether compaction was triggered by a context-full error.

    Returns:
      `True` if any tool results were truncated or turns were summarized.
    """
    unread = {id(m) for m in self.unread()}
    results = [
        (n, m) for n, m in enumerate(self.messages) if m["role"] == "tool"
    ]
    # with `force`, the endpoint's own count of the prompt wins when it is
    # larger: the estimate can run low
    cuts, size = [], max(
        self.estimate_prompt_tokens(), self.prompt_tokens if force else 0
    )
    for n, m in results if force else results[:-KEEP_RECENT_RESULTS]:
      if force and self.context_window and size <= self.compact_at():
        break
      if len(m["content"]) > 600 and id(m) not in unread:
        size -= (len(m["content"]) - 400) // 4
        m["content"] = (
            m["content"][:400]
            + "\n[... removed to save context; run the tool again if needed"
            " ...]"
        )
        cuts.append(n)
    if cuts:
      self.drop_thinking_after(cuts[0])
      await self.session.log(f"context: cut {len(cuts)} old tool results")
      self.prompt_tokens = self.estimate_prompt_tokens()
      if (
          not force
          or not self.context_window
          or self.prompt_tokens <= self.compact_at()
      ):
        return True
    cut = len(self.messages) - 6
    # the kept turns must not start with tool results whose call was replaced by
    # the notes
    while cut > 3 and self.messages[cut]["role"] == "tool":
      cut -= 1
    if cut < 10:  # too few turns to be worth a notes call
      return bool(cuts)
    try:
      notes = await self.stream(
          self.messages[:cut] + [{"role": "user", "content": SUMMARY_PROMPT}],
          "none",
          self.finish_margin,
      )
    except (openai.APIError, asyncio.TimeoutError) as exc:
      await self.session.log(
          f"context: notes failed ({str(exc)[:200] or 'out of time'})"
      )
      return bool(cuts)
    await self.report(notes)
    text = visible(notes.text)
    if not text:
      await self.session.log(
          "context: the notes came back empty, so the turns are kept"
      )
      return bool(cuts)
    if notes.finish == "length":
      text += "\n[the notes were cut off at the output limit]"
    self.messages = (
        self.messages[:2]
        + [{
            "role": "user",
            "content": (
                "Your notes on the work so far (earlier "
                "turns were removed to save context):\n"
                + text
            ),
        }]
        + self.messages[cut:]
    )
    self.drop_thinking_after(2)
    await self.session.log(f"context: replaced {cut - 2} messages with notes")
    self.prompt_tokens = self.estimate_prompt_tokens()
    return True

  def drop_thinking_after(self, changed: int) -> None:
    """Drops thinking blocks from assistant turns after `messages[changed]`.

    Args:
      changed: Message index that was modified by compaction.
    """
    for m in self.messages[changed + 1 :]:
      if m["role"] == "assistant":
        drop_thinking(m)

  def cut_unread(self) -> bool:
    """Truncates unread tool results as a last resort when context is full.

    Clips each unread tool output exceeding `2 * UNREAD_KEEP` to an equal share
    of the remaining context window (or halves it when the window size is
    unknown).

    Returns:
      `True` if at least one unread tool result was shortened, else `False`.
    """
    unread = [m for m in self.unread() if len(m["content"]) > 2 * UNREAD_KEEP]
    if not unread:
      return False
    share = None
    if self.context_window:
      rest = (
          self.estimate_prompt_tokens()
          - sum(len(m["content"]) for m in unread) // 4
      )
      share = (self.compact_at() - rest) * 4 // len(unread)
    for m in unread:
      size = len(m["content"])
      # a share within 100 characters of the size would barely shrink it
      keep = size // 2 if share is None or share >= size - 100 else share
      m["content"] = clip(m["content"], max(UNREAD_KEEP, keep))
    self.prompt_tokens = self.estimate_prompt_tokens()
    return True


async def solve(session: taskbridge.Session) -> str:
  """Runs `Agent` on `session` and returns the final answer.

  Args:
    session: Active task session.

  Returns:
    The final summary string returned by the agent.
  """
  print(
      f"task: workdir {session.workdir}, model {MODEL},"
      f" {len(session.mcp_servers)} MCP server(s)",
      file=sys.stderr,
  )
  return await Agent(session).run()


if __name__ == "__main__":
  taskbridge.run(solve)
