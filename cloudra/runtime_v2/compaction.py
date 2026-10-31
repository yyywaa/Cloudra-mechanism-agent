"""Context compaction for the session-level context projection.

统一覆盖全部轮次：一次 compact 把会话上下文的**全部历史消息**（用户指令、
assistant 回复与工具调用、工具结果）折叠成一条结构化摘要。不设逐字保留区
——用户消息同样进摘要；唯一不压缩的是 harness 前缀本身（静态协议 + 动态
快照，由调用方按当前状态重新装配）。产物布局：

1. harness 前缀（调用方重新装配的静态协议 + 当前动态快照）；
2. 当前 pin 通知的重渲染（调用方提供）；
3. 一条 assistant「[Context compact]」结构化摘要消息（字段经结构化校验，
   带来源消息序号）。

摘要之后到达的输入（本轮 inbox 消息）由调用方在发送前追加，因而当前指令
永远逐字可见。用户意图的无损保证落在两处：摘要契约（objective /
active_requests / constraints / corrections 逐条保留）与本轮输入本身——
不再靠「原文永久驻留」；相应地，摘要器是旧历史的**唯一**载体，丢掉即丢失。

摘要输入按现有模型容量（context_window − 输出预算，留余量）分段：消息逐字
完整，单条超预算消息的文本跨段切块；每个区段成功并通过结构化校验后才汇总
（形状/来源不符时把校验错误回喂重问一次，仍不符即放弃）。多段摘要按容量
分批合并（合并载荷超预算时分多轮进行），无法收敛即放弃。

拒替换条件（空输出/结构错误/区段失败/取消/合并容量不足/摘要未缩短轨迹）
一律保留原上下文并报告原因，禁止静默裁剪。

触发时机:
- 手动 compact（pending_compactions → 轮次边界应用）
- 达到上下文预算（估算留余量）
- 真实 overflow（400/413）——有界重试，同一输入无进展不重复压缩

安装语义：候选上下文由 AgentRunner 经 ContextBroker.install_compacted
一条 context.compacted 事件原子安装；校验/持久化/版本不符时不产生事件，
投影保持原样。

The handoff is an **assistant** summary, never ``role: user``: injecting a
user message made the model treat compact as a new turn and stop working.
"""

from __future__ import annotations

import asyncio
import json
import logging
import time
from typing import Any, Awaitable, Callable, Optional

from pydantic import BaseModel, Field, ValidationError

from cloudra.infra.token_estimator import TokenEstimator
from cloudra.runtime_v2.schemas import AgentSession

logger = logging.getLogger(__name__)

# messages -> summary text
Summarizer = Callable[[list[dict[str, Any]]], Awaitable[str]]

_COMPACT_MARKER = "[Context compact]"

# 摘要契约（计划原文，逐字）；结构化 JSON 形状是对模型的硬要求，
# 校验走 json.loads + pydantic + 显式检查（无正则）。
COMPACT_SUMMARY_CONTRACT = """\
Preserve the original user objective, every still-active request,
constraint, prohibition, authorization boundary, and delivery criterion.
Record user corrections and which earlier requests they explicitly replace.
Do not treat assistant proposals or tool output as user instructions.
Keep completed work separate from pending requests, failed attempts,
unverified claims, evidence paths, computed values, and next actions.
Never drop an unresolved user request merely because it is old."""

_JSON_SHAPE_NOTE = """\
Return ONLY a JSON object (no markdown fence, no prose before or after it) \
with exactly these nine keys in this shape:

{
  "objective": {"text": "<statement>", "sources": [<int>]},
  "active_requests": [{"text": "<statement>", "sources": [<int>]}, ...],
  "corrections": [{"text": "<statement>", "replaces": "<the earlier request \
it supersedes>", "sources": [<int>]}, ...],
  "constraints": [{"text": "<statement>", "sources": [<int>]}, ...],
  "pending": [{"text": "<statement>", "sources": [<int>]}, ...],
  "completed": [{"text": "<statement>", "sources": [<int>]}, ...],
  "failed_attempts": [{"text": "<statement>", "sources": [<int>]}, ...],
  "evidence": [{"text": "<statement>", "sources": [<int>]}, ...],
  "next_actions": [{"text": "<statement>", "sources": [<int>]}, ...]
}

objective is ONE entry object; the other eight fields are JSON arrays of \
entry objects. Never place a single object where an array is required and \
never null: use [] when a field has nothing to report, and never a \
placeholder entry with empty text. "sources" are the 0-based [index] numbers \
of the trajectory lines each statement came from; keep them accurate and \
inside the numbered range.\
"""

# GH #48 建议 4：给形状说明配一个「最小合法示例」（与上面九键同形），把三种
# 实测畸形（objective 裸字符串 / 单元素数组 / 围栏+散文）压到一眼可对照的程度。
# 示例必须**不依赖任何容错路径**就是合法的：它要能直接过 json.loads +
# CompactSummary.model_validate（tests/test_compaction_prompt_example.py 把这条
# 钉死），否则等于把模型引向错误形状。
_MINIMAL_EXAMPLE_JSON = """\
{"objective": {"text": "Explain this result.", "sources": [0]},
 "active_requests": [],
 "corrections": [], "constraints": [], "pending": [], "completed": [],
 "failed_attempts": [], "evidence": [], "next_actions": []}"""

_MINIMAL_EXAMPLE_NOTE = (
    "\n\nMinimal valid example for the hypothetical trajectory line below. "
    "Derive every value and source index from the actual input; do not copy "
    "the example:\n"
    "[0] user: Explain this result.\n\n"
    + _MINIMAL_EXAMPLE_JSON
)

_COMPACT_INSTRUCTION = (
    "You are compacting an agent's execution trajectory at a context "
    "boundary. The user message carries the whole trajectory as numbered "
    "lines ([index] role: text), oldest first — user instructions, assistant "
    "replies and tool calls, and tool results. Your summary REPLACES all of "
    "it: the original messages are deleted afterwards, so anything you drop "
    "is lost. An earlier '[Context compact]' summary inside the trajectory is "
    "itself a condensed record of still older work — merge it into the new "
    "summary instead of treating it as a new event.\n\n"
    + COMPACT_SUMMARY_CONTRACT
    + "\n\n"
    + _JSON_SHAPE_NOTE
    + _MINIMAL_EXAMPLE_NOTE
)

_MERGE_INSTRUCTION = (
    "You are merging partial compaction summaries of consecutive segments of "
    "one agent trajectory into a single final summary. The user message "
    "carries the partial summaries as a JSON array (in trajectory order). "
    "Drop duplication between consecutive segments; keep correction order "
    "visible. The contract:\n\n"
    + COMPACT_SUMMARY_CONTRACT
    + "\n\n"
    + _JSON_SHAPE_NOTE
    + _MINIMAL_EXAMPLE_NOTE
)

# Cap for summary text stored inside compaction.finished event data.
SUMMARY_EVENT_CAP = 8000

# 上下文预算估算余量：估算到 (window − 输出预算) 的 85% 即触发/分段
_BUDGET_MARGIN = 0.85
# settings 未配置 context_window 时的内部兜底（现有 config 缺省值之外的
# 新用户配置键一律不加）
_DEFAULT_CONTEXT_WINDOW = 128_000


# ---------------------------------------------------------------------------
# 渲染与容量估算
# ---------------------------------------------------------------------------


def _content_to_text(content: Any) -> str:
    """Render message content to text for measurement and summarizer input.

    Visual-mode contexts carry parts lists (text + stable image_ref parts;
    legacy in-flight image_url data URLs).  Feeding the raw list into
    ``str()`` would dump the whole base64 payload into the summarization call,
    so image parts degrade to their existing text description here——图像只
    保留可回读引用与既有文本描述，不声称纯文本摘要完整理解了图像。
    """
    if content is None:
        return ""
    if isinstance(content, str):
        return content
    if isinstance(content, list):
        texts = []
        for part in content:
            if not isinstance(part, dict):
                texts.append(str(part))
                continue
            if part.get("type") == "image_url":
                url = str((part.get("image_url") or {}).get("url") or "")
                mime = url[5:].split(";", 1)[0] if url.startswith("data:") else "external"
                texts.append(f"[Image: {mime} attachment omitted during compaction]")
            elif part.get("type") == "image_ref":
                texts.append(
                    str(part.get("fallback") or f"[Image: {part.get('path')}]")
                )
            else:
                texts.append(str(part.get("text") or ""))
        return " ".join(text for text in texts if text)
    return str(content)


def render_message_text(message: dict[str, Any]) -> str:
    """把一条投影消息渲染成摘要输入里的文本（``[i] role: text`` 行的正文）。

    这里是**给摘要模型看的**文本：content（视觉 parts 降级为文本描述）、
    assistant 的 tool_calls（工具名 + 参数）、tool 的 tool_call_id、思考模式的
    reasoning_content。容量计量走 ``estimate_messages_tokens``（TokenEstimator，
    同一批字段），两者刻意分开：渲染要可读，计量要与线缆一致。
    """
    parts: list[str] = []
    content = _content_to_text(message.get("content"))
    if content:
        parts.append(content)
    reasoning = message.get("reasoning_content") or message.get("reasoning")
    if reasoning:
        parts.append(f"(reasoning) {reasoning}")
    calls = message.get("tool_calls")
    if isinstance(calls, list):
        for call in calls:
            if not isinstance(call, dict):
                continue
            arguments = call.get("arguments")
            if not isinstance(arguments, str):
                arguments = json.dumps(
                    arguments if arguments is not None else {}, ensure_ascii=False
                )
            parts.append(f"-> call {call.get('name') or 'unknown'} {arguments}")
    if message.get("role") == "tool" and message.get("tool_call_id"):
        parts.append(f"(tool_call_id={message['tool_call_id']})")
    return "\n".join(parts)


def estimate_tokens(text: str) -> int:
    """一段文本的 token 计数：``TokenEstimator.count_text``（tiktoken）。

    tiktoken 不可用时由 TokenEstimator 内部回退到 CJK 感知启发式。只用于压缩
    触发与分段，不用于计费。旧实现一律按 4 字符/token 折算，中文重负载低估
    约 2.3 倍（GH #40 实测：估 452,780 vs 真实 1,048,407 token），预算闸门形同
    虚设、上下文一路涨到 provider 硬拒。

    ``tiktoken`` 对上千条消息是毫秒到秒级 CPU 工作：协程里请经
    ``asyncio.to_thread`` 调用（同 ``llm_client.count_message_tokens``）。
    """
    if not text:
        return 0
    return int(TokenEstimator.count_text(text))


def estimate_messages_tokens(messages: list[dict[str, Any]]) -> int:
    """投影的 prompt token 计数：``TokenEstimator.count_messages``（tiktoken）。

    content（含视觉 parts）、role/name、tool_call_id、tool_calls（工具名 + 参数）
    与 reasoning_content 全部计入，与线上真正发送的内容一致——旧实现只看
    content，带 tool_calls 的 assistant 消息被估成空。
    """
    if not messages:
        return 0
    return int(TokenEstimator.count_messages(messages))


def usable_prompt_tokens(context_window: int, max_output: int) -> int:
    """可用提示词容量（token）：(context_window − 输出预算) × 余量。"""
    window = context_window or _DEFAULT_CONTEXT_WINDOW
    output = max_output or 0
    return max(int((window - output) * _BUDGET_MARGIN), 512)


def context_over_budget(
    messages: list[dict[str, Any]], *, context_window: int, max_output: int
) -> bool:
    """预算触发判据：投影估算超过可用容量（未配置 context_window 用内部兜底）。"""
    return estimate_messages_tokens(messages) > usable_prompt_tokens(
        context_window, max_output
    )


# ---------------------------------------------------------------------------
# 结构化摘要：字段校验与渲染（无正则）
# ---------------------------------------------------------------------------


class CompactSummaryError(ValueError):
    """摘要输出为空 / 非 JSON / 结构不符（来源下标越界不在此列：钳制并计数）。"""


class SummaryEntry(BaseModel):
    text: str
    sources: list[int] = Field(default_factory=list)


class CorrectionEntry(SummaryEntry):
    replaces: str = ""


class CompactSummary(BaseModel):
    objective: SummaryEntry
    active_requests: list[SummaryEntry] = Field(default_factory=list)
    corrections: list[CorrectionEntry] = Field(default_factory=list)
    constraints: list[SummaryEntry] = Field(default_factory=list)
    pending: list[SummaryEntry] = Field(default_factory=list)
    completed: list[SummaryEntry] = Field(default_factory=list)
    failed_attempts: list[SummaryEntry] = Field(default_factory=list)
    evidence: list[SummaryEntry] = Field(default_factory=list)
    next_actions: list[SummaryEntry] = Field(default_factory=list)
    # 被钳制进轨迹范围的来源下标数量（parse 计入，随 stats 透出）。排除在
    # model_dump 之外：合并载荷回喂摘要模型，不需要这条 harness 记账。
    clamped_sources: int = Field(default=0, exclude=True)


def _all_entries(summary: CompactSummary) -> list[SummaryEntry]:
    return [
        summary.objective,
        *summary.active_requests,
        *summary.corrections,
        *summary.constraints,
        *summary.pending,
        *summary.completed,
        *summary.failed_attempts,
        *summary.evidence,
        *summary.next_actions,
    ]


def _exc_label(exc: BaseException) -> str:
    """拒替换 stats 的错误标签：``str(exc)`` 为空（如裸 ``TimeoutError``）时
    落到类型名——GH #48 实录 segment_failed error='' 把真实拒因完全藏住。"""
    return str(exc) or type(exc).__name__


def _strip_code_fence(text: str) -> str:
    """剥掉模型常见的代码围栏：首行围栏（可带语言标签，如 json）必剥；
    尾部找最后一个独立围栏行并连同其后散文截断（模型爱"围栏后再解释
    两句"）。显式 token 扫描，无正则。"""
    lines = text.splitlines()
    if not lines or not lines[0].startswith("```"):
        return text
    body = lines[1:]
    for idx in range(len(body) - 1, -1, -1):
        if body[idx].strip() == "```":
            body = body[:idx]
            break
    return "\n".join(body).strip()


_ENTRY_LIST_FIELDS = (
    "active_requests",
    "corrections",
    "constraints",
    "pending",
    "completed",
    "failed_attempts",
    "evidence",
    "next_actions",
)


def _promote_summary_shapes(data: Any) -> Any:
    """GH #48 实测（glm-5.3-flash）的三种首答畸形做**无损**形状提升：

    - ``objective`` 写成单元素数组 → 取该元素；
    - ``objective`` 写成裸字符串 → 包成 ``{"text": ...}``；
    - 列表字段的条目写成裸字符串 → 包成 ``{"text": ...}``（sources 走默认）。

    只提升形状、不补造内容——空 objective / 缺 text 仍 fail-loud 拒收；
    "单个对象当列表"不做提升（既有重问一次的既定路径，别处测试钉死）。
    """
    if not isinstance(data, dict):
        return data
    objective = data.get("objective")
    if isinstance(objective, list) and len(objective) == 1:
        data["objective"] = objective[0]
    if isinstance(data.get("objective"), str):
        data["objective"] = {"text": data["objective"]}
    for field in _ENTRY_LIST_FIELDS:
        value = data.get(field)
        if isinstance(value, list):
            data[field] = [
                ({"text": item} if isinstance(item, str) else item) for item in value
            ]
    return data


def parse_compact_summary(raw: str, *, trajectory_len: int) -> CompactSummary:
    """json.loads + pydantic 校验 + 来源下标钳制。

    空输出 / 非 JSON / 结构不符 / 空 objective 一律 fail-loud 拒收（绝不降级
    解析）。来源下标越界则**钳制**进轨迹范围并计数（``clamped_sources``，随
    stats 透出到 compaction.finished）：在上千条消息的轨迹上要求模型精确引用
    位置下标本就不现实——实测（GH #40）一次 1606 条轨迹的摘要因越界 10 被整体
    拒收、压缩再也做不成。钳制 + 计数是可审计的记录，不是静默降级。
    围栏剥离与 GH #48 的三种无损形状提升见 :func:`_strip_code_fence` /
    :func:`_promote_summary_shapes`（thinking 模型重问一次动辄数分钟且可能
    撞 summary_timeout，能无损吃下的形状不该烧掉唯一一次重试）。
    """
    text = (raw or "").strip()
    if not text:
        raise CompactSummaryError("empty summary output")
    if text.startswith("```"):
        text = _strip_code_fence(text)
    try:
        data = json.loads(text)
    except json.JSONDecodeError as exc:
        raise CompactSummaryError(f"summary is not valid JSON: {exc}") from exc
    data = _promote_summary_shapes(data)
    try:
        summary = CompactSummary.model_validate(data)
    except ValidationError as exc:
        raise CompactSummaryError(
            f"summary failed structural validation: {exc}"
        ) from exc
    if not summary.objective.text.strip():
        raise CompactSummaryError("objective is empty")
    clamped = 0
    last = max(trajectory_len - 1, 0)
    for entry in _all_entries(summary):
        for position, index in enumerate(entry.sources):
            if index < 0 or index >= trajectory_len:
                entry.sources[position] = min(max(index, 0), last)
                clamped += 1
    summary.clamped_sources = clamped
    if clamped:
        logger.warning(
            "compaction summary: clamped %d out-of-range source index(es) into 0..%d",
            clamped,
            last,
        )
    return summary


# 结构化 JSON 是硬要求：形状/来源不符时把校验错误回喂给模型重问一次，
# 仍不符即拒替换——绝不降级解析（缺字段或形状错会静默丢上下文信息）。
_SUMMARY_ATTEMPTS = 2
_RETRY_ERROR_TOKENS = 128

_RETRY_NOTE = (
    "Your previous reply was rejected: {error}\n"
    "Reply again with ONLY the JSON object the system message specifies: no "
    "markdown fence, no prose before or after it, the same nine keys, and "
    "every list field as a JSON array."
)


def _summary_payload_budget(instruction: str, budget_tokens: int) -> int:
    """正文容量扣除系统指令、消息封装，以及一次有界错误提示。"""
    overhead = estimate_messages_tokens(
        [
            {"role": "system", "content": instruction},
            {"role": "user", "content": ""},
            {"role": "user", "content": _RETRY_NOTE.format(error="")},
        ]
    )
    return budget_tokens - overhead - _RETRY_ERROR_TOKENS


async def _summarize_validated(
    summarize: Summarizer,
    *,
    instruction: str,
    payload: str,
    trajectory_len: int,
) -> CompactSummary:
    """一次摘要调用 + 结构化校验；失败时带错误重问（见 ``_SUMMARY_ATTEMPTS``）。"""
    messages = [
        {"role": "system", "content": instruction},
        {"role": "user", "content": payload},
    ]
    attempt = 0
    while True:
        raw = await summarize(messages)
        try:
            return parse_compact_summary(raw, trajectory_len=trajectory_len)
        except CompactSummaryError as exc:
            attempt += 1
            if attempt >= _SUMMARY_ATTEMPTS:
                raise
            error = await asyncio.to_thread(
                TokenEstimator.truncate_to_tokens, str(exc), _RETRY_ERROR_TOKENS
            )
            # 原轨迹仍逐字保留；坏回复不是证据，不再复制一遍挤占请求容量。
            messages = [
                {"role": "system", "content": instruction},
                {"role": "user", "content": payload},
                {"role": "user", "content": _RETRY_NOTE.format(error=error)},
            ]


def _src(entry: SummaryEntry) -> str:
    if not entry.sources:
        return ""
    return " [src: " + ",".join(str(index) for index in entry.sources) + "]"


_ENTRY_SECTIONS = (
    ("active_requests", "Active requests"),
    (
        "constraints",
        "Constraints / prohibitions / authorization boundaries / delivery criteria",
    ),
    ("corrections", "Corrections (later entries override earlier ones)"),
    ("pending", "Pending requests"),
    ("completed", "Completed work"),
    ("failed_attempts", "Failed attempts / unverified claims"),
    ("evidence", "Evidence paths / computed values"),
    ("next_actions", "Next actions"),
)


def render_compact_summary(summary: CompactSummary) -> str:
    """结构化摘要渲染为 handoff 消息正文（确定性与可读性，非校验）。"""
    lines = [f"Objective: {summary.objective.text}{_src(summary.objective)}"]
    for field, title in _ENTRY_SECTIONS:
        entries = getattr(summary, field)
        if not entries:
            continue
        lines.append(f"\n{title}:")
        for entry in entries:
            text = entry.text
            replaces = getattr(entry, "replaces", "")
            if field == "corrections" and replaces:
                text = f"{text} (replaces: {replaces})"
            lines.append(f"- {text}{_src(entry)}")
    return "\n".join(lines)


# ---------------------------------------------------------------------------
# 分段：逐字覆盖，单条超长消息切块跨段
# ---------------------------------------------------------------------------


def segment_trajectory(
    trajectory: list[dict[str, Any]], budget_tokens: int
) -> list[dict[str, Any]]:
    """把执行轨迹切成不超预算的连续区段。

    返回 [{"text", "message_indexes", "tokens"}]：text 是编号行
    （``[i] role: 全文``），message_indexes 是该段覆盖的轨迹消息序号。
    消息从不截断；单条超预算的消息文本切成连续块，每块独立成段并带续接
    标记，块长按实际 token 数缩小，不假定字符与 token 一一对应。
    """
    segments: list[dict[str, Any]] = []
    current: list[str] = []
    current_tokens = 0
    covered: list[int] = []
    # 分隔符另留两个 token，保守覆盖拼接处的分词变化。
    separator_tokens = estimate_tokens("\n\n") + 2

    def flush() -> None:
        nonlocal current, current_tokens, covered
        if current:
            text = "\n\n".join(current)
            segments.append(
                {
                    "text": text,
                    "message_indexes": list(covered),
                    "tokens": estimate_tokens(text),
                }
            )
            current = []
            current_tokens = 0
            covered = []

    for index, message in enumerate(trajectory):
        text = (
            f"[{index}] {message.get('role', '?')}: {render_message_text(message)}"
        )
        tokens = estimate_tokens(text)
        if tokens <= budget_tokens:
            combined_tokens = current_tokens + tokens
            if current:
                combined_tokens += separator_tokens
            if current and combined_tokens > budget_tokens:
                flush()
                combined_tokens = tokens
            current.append(text)
            current_tokens = combined_tokens
            covered.append(index)
            continue
        flush()
        # 单条超预算消息：切块（每块 ≤ 预算），跨段完整覆盖。
        offset = 0
        part_index = 0
        while offset < len(text):
            prefix = (
                f"[{index}] (continued, part {part_index + 1} of one long message)\n"
                if part_index else ""
            )
            # 常见文本从约 4 字符/token 起步；二分时只移动字符边界，保证无损。
            low, high = 0, min(len(text) - offset, budget_tokens * 4)
            while low < high:
                size = (low + high + 1) // 2
                if estimate_tokens(prefix + text[offset : offset + size]) <= budget_tokens:
                    low = size
                else:
                    high = size - 1
            if low == 0:
                raise ValueError("summary payload budget cannot fit a message fragment")
            body = prefix + text[offset : offset + low]
            segments.append(
                {
                    "text": body,
                    "message_indexes": [index],
                    "tokens": estimate_tokens(body),
                }
            )
            offset += low
            part_index += 1
    flush()
    return segments


async def _bounded(coro: Any, timeout: float | None) -> Any:
    """单次摘要调用的有界等待（``timeout`` 为 None/≤0 时不限时）。

    超时抛 ``TimeoutError``，由调用方按 ``segment_failed`` / ``merge_failed``
    拒替换——一次超大摘要调用绝不允许把轮次无限挂住（GH #40：挂起 10+ 分钟
    无终态）。
    """
    if timeout is not None and timeout > 0:
        return await asyncio.wait_for(coro, timeout)
    return await coro


def _batches_by_tokens(payloads: list[dict], budget_tokens: int) -> list[list[int]]:
    """把待合并的片段载荷按 token 容量切成连续批次（单条自成一档即单元素批）。"""
    batches: list[list[int]] = []
    current: list[int] = []
    for index, payload in enumerate(payloads):
        candidate = [payloads[item] for item in current] + [payload]
        tokens = estimate_tokens(json.dumps(candidate, ensure_ascii=False))
        if current and tokens > budget_tokens:
            batches.append(current)
            current = []
        current.append(index)
    if current:
        batches.append(current)
    return batches


async def _merge_partials(
    partials: list[CompactSummary],
    *,
    summarize: Summarizer,
    trajectory_len: int,
    budget_tokens: int,
    summary_timeout: float | None = None,
) -> tuple[Optional[CompactSummary], int]:
    """把逐段摘要合并成最终摘要；合并载荷超预算时分批多轮进行。

    返回 (最终摘要, 各轮被钳制的来源下标数)；单条自成一档（它自己就超预算）
    时不再单独问模型，原样进入下一轮；一轮下来没有任何合并且仍多于一条 →
    容量不足以收敛，摘要为 None（调用方拒替换，绝不丢段）。
    """
    pending = list(partials)
    clamped_total = 0
    payload_budget = await asyncio.to_thread(
        _summary_payload_budget, _MERGE_INSTRUCTION, budget_tokens
    )
    while len(pending) > 1:
        payloads = [partial.model_dump() for partial in pending]
        batches = await asyncio.to_thread(_batches_by_tokens, payloads, payload_budget)
        merged: list[CompactSummary] = []
        for batch in batches:
            if len(batch) == 1:
                merged.append(pending[batch[0]])
                continue
            payload = json.dumps(
                [payloads[index] for index in batch],
                ensure_ascii=False,
            )
            merged_summary = await _bounded(
                _summarize_validated(
                    summarize,
                    instruction=_MERGE_INSTRUCTION,
                    payload=payload,
                    trajectory_len=trajectory_len,
                ),
                summary_timeout,
            )
            clamped_total += merged_summary.clamped_sources
            merged.append(merged_summary)
        if len(merged) >= len(pending):
            return None, clamped_total
        pending = merged
    return pending[0], clamped_total


def _handoff_text(compacted_count: int, summary_text: str) -> str:
    body = (
        f"{_COMPACT_MARKER} {compacted_count} earlier messages of this session "
        "were compacted into the structured summary below; they are no longer "
        "present verbatim (user instructions included — their still-active "
        "content is in the summary). Continue the current task by calling "
        "tools; this is not a new user request and needs no acknowledgement."
    )
    return f"{body}\n{summary_text}"


async def compact_context(
    messages: list[dict[str, Any]],
    *,
    head: list[dict[str, Any]],
    notices: list[dict[str, Any]],
    summarize: Summarizer,
    context_window: int,
    max_output: int,
    trigger: str = "manual",
    old_head_len: int = 0,
    summary_timeout: float | None = None,
    token_ratio: float = 1.0,
) -> tuple[list[dict[str, Any]], dict[str, Any]]:
    """统一压缩：折叠全部轮次，返回 (候选上下文, stats)。

    ``stats["compacted"]`` 为 False 即拒替换（reason 说明原因），调用方
    不得安装候选。``old_head_len`` 是当前投影里旧 harness 前缀的消息数
    （由调用方从 prefix_meta 读出；无前缀的会话为 0）——旧前缀不进摘要
    输入，由调用方重新装配的 ``head`` 替换。``summary_timeout`` 是单次摘要
    调用的有界等待（秒；None/≤0 不限时），超时按 ``segment_failed`` /
    ``merge_failed`` 拒替换。``stats["clamped_sources"]`` 是被钳制的来源下标
    数量（见 ``parse_compact_summary``）。
    """
    base_stats: dict[str, Any] = {
        "before_messages": len(messages),
        "trigger": trigger,
    }
    # 普通请求与摘要请求共享供应商真实用量的修正，不能只修正触发时机。
    budget_tokens = int(usable_prompt_tokens(context_window, max_output) / token_ratio)
    original_trajectory = messages[old_head_len:]
    trajectory = []
    for message in original_trajectory:
        compact_content = message.get('tool_document_compact_content')
        if message.get('role') in ('system', 'tool') and isinstance(compact_content, str):
            trajectory.append({**message, 'content': compact_content})
        elif message.get('role') in ('system', 'tool') and message.get('tool_documents'):
            trajectory.append({**message, 'content': 'Previously read tool contracts: ' +
                json.dumps(message['tool_documents'], ensure_ascii=False) + '. Read current contracts with get_tool_docs.'})
        else:
            trajectory.append(message)
    if not trajectory:
        return messages, {**base_stats, "compacted": False, "reason": "nothing_to_compact"}

    payload_budget = await asyncio.to_thread(
        _summary_payload_budget, _COMPACT_INSTRUCTION, budget_tokens
    )
    if payload_budget <= 0:
        return messages, {**base_stats, "compacted": False, "reason": "summary_capacity"}
    # 分段要逐条消息计数（tiktoken）：卸载出事件循环。
    try:
        segments = await asyncio.to_thread(segment_trajectory, trajectory, payload_budget)
    except ValueError as exc:
        return messages, {
            **base_stats, "compacted": False, "reason": "summary_capacity",
            "error": str(exc),
        }
    partials: list[CompactSummary] = []
    coverage: list[dict[str, Any]] = []
    clamped_sources = 0
    for seg_index, segment in enumerate(segments):
        try:
            partial = await _bounded(
                _summarize_validated(
                    summarize,
                    instruction=_COMPACT_INSTRUCTION,
                    payload=segment["text"],
                    trajectory_len=len(trajectory),
                ),
                summary_timeout,
            )
        except asyncio.CancelledError:
            raise
        except CompactSummaryError as exc:
            return messages, {
                **base_stats,
                "compacted": False,
                "reason": "summary_invalid",
                "failed_segment": seg_index,
                "error": _exc_label(exc),
            }
        except Exception as exc:
            return messages, {
                **base_stats,
                "compacted": False,
                "reason": "segment_failed",
                "failed_segment": seg_index,
                "error": _exc_label(exc),
            }
        partials.append(partial)
        clamped_sources += partial.clamped_sources
        coverage.append(
            {
                "segment": seg_index,
                "message_indexes": segment["message_indexes"],
                "tokens": segment["tokens"],
            }
        )

    try:
        summary, merge_clamped = await _merge_partials(
            partials,
            summarize=summarize,
            trajectory_len=len(trajectory),
            budget_tokens=budget_tokens,
            summary_timeout=summary_timeout,
        )
        clamped_sources += merge_clamped
    except asyncio.CancelledError:
        raise
    except CompactSummaryError as exc:
        return messages, {
            **base_stats,
            "compacted": False,
            "reason": "summary_invalid",
            "error": _exc_label(exc),
        }
    except Exception as exc:
        return messages, {
            **base_stats,
            "compacted": False,
            "reason": "merge_failed",
            "error": _exc_label(exc),
        }
    if summary is None:
        return messages, {
            **base_stats,
            "compacted": False,
            "reason": "merge_capacity",
            "segments": len(partials),
        }

    rendered = render_compact_summary(summary)
    handoff = {
        "role": "assistant",
        "content": _handoff_text(len(trajectory), rendered),
    }
    # 缩短判据按整段替换的真实口径：新上下文里的历史只剩这条 handoff，
    # 旧前缀由调用方重新装配的 head 取代——只有 handoff 比整段轨迹短，
    # 压缩才真的缩小了上下文。
    trajectory_tokens = await asyncio.to_thread(estimate_messages_tokens, original_trajectory)
    handoff_tokens = await asyncio.to_thread(estimate_messages_tokens, [handoff])
    if handoff_tokens >= trajectory_tokens:
        return messages, {
            **base_stats,
            "compacted": False,
            "reason": "summary_not_shorter",
            "summary_tokens": handoff_tokens,
            "trajectory_tokens": trajectory_tokens,
        }

    new_context = [*head, *notices, handoff]
    return new_context, {
        **base_stats,
        "compacted": True,
        "after_messages": len(new_context),
        "handoff_index": len(head) + len(notices),
        "trajectory_messages": len(trajectory),
        "trajectory_tokens": trajectory_tokens,
        "summary_tokens": handoff_tokens,
        "summary_chars": len(rendered),
        "clamped_sources": clamped_sources,
        "segments": coverage,
    }


async def summarize_with_agent_settings(
    agent: AgentSession,
    messages: list[dict[str, Any]],
    *,
    event_log: Any = None,
    run_id: str | None = None,
) -> str:
    """Default summarizer: one non-streaming call on the agent's own model.

    每次新建 LLMClient（独立连接池），用完在 finally 里 aclose 回收。
    提供 ``event_log`` 时成功调用落一条 ``kind="summary"`` 的 llm.completed
    ——压缩成本与主链路一起进遥测（``cloudra stats tokens`` 单列），不再
    隐形。
    """
    from cloudra.infra.llm_client import LLMClient
    from cloudra.runtime_v2.adapters import legacy_default_settings

    settings = legacy_default_settings(agent)
    client = LLMClient(
        api_key=settings.api_key,
        base_url=settings.base_url,
        timeout=settings.timeout,
    )
    started = time.monotonic()
    try:
        kwargs: dict = {
            "model": settings.model,
            "messages": messages,
            "max_tokens": settings.max_tokens,
            # temperature=1: a growing set of models rejects anything else.
            "temperature": 1.0,
            "stream": False,
        }
        if settings.reasoning_effort:
            kwargs["reasoning_effort"] = settings.reasoning_effort
        # 与主 agent 请求分组统计的摘要请求标记（只记哈希/计数，不记原文）。
        from cloudra.infra.llm_client import request_fingerprint

        fingerprint = request_fingerprint(kwargs)
        logger.info(
            "llm request fingerprint kind=summary agent=%s messages=%d tools=%s",
            getattr(agent, "id", "?"),
            fingerprint["message_count"],
            fingerprint["tools_hash"][:12],
        )
        response = await client.create_with_retry(**kwargs)
    finally:
        await client.aclose()
    if event_log is not None:
        # usage 必须 JSON 可序列化：raw response.usage 是 openai SDK 的
        # CompletionUsage 对象，直接进事件会让 event_writer 的 json 落盘
        # 抛 EventPersistenceError，堵死整条持久化管道（/compact 500、
        # 后续写命令全部失效）。client.last_usage 是 _extract_usage 转换
        # 过的安全 dict；fake/异常形态再兜底到 raw dict / model_dump。
        usage = getattr(client, "last_usage", None) or {}
        if not usage:
            raw_usage = getattr(response, "usage", None)
            if isinstance(raw_usage, dict):
                usage = dict(raw_usage)
            elif raw_usage is not None and hasattr(raw_usage, "model_dump"):
                usage = raw_usage.model_dump(exclude_none=True)
        event_log.append(
            "llm.completed",
            stream="agent",
            project_id=agent.project_id,
            session_id=agent.id,
            run_id=run_id,
            data={
                "model": settings.model,
                "usage": usage,
                "finish_reason": getattr(response, "finish_reason", None),
                "latency_ms": int((time.monotonic() - started) * 1000),
                "kind": "summary",
            },
        )
    choices = getattr(response, "choices", None) or []
    if not choices:
        return ""
    return getattr(getattr(choices[0], "message", None), "content", None) or ""
