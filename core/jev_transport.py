"""海龟汤插件自带的 Jev（TypeSafe SystemOne）传输层。

实现逻辑对齐 astrbot_plugin_oven_multi / astrbot_plugin_angel_heart 的同名模块
（各插件各自独立分发，不跨插件 import），按 Jev API 文档
（https://jevmodel.org/zh/docs/）对齐以下行为：

- 本地预检请求体（问题数/名称/长度/选项数上限），避免必然被 422 拒绝的往返；
- 带 Idempotency-Key：同一输入的重试复用原计费记录，不会重复扣费；
- 按文档错误码映射状态（401/402/422/429/502）并解析错误体；
- 记录 X-Tokens-Remaining（结算后余额）供面板展示。
"""

from __future__ import annotations

import asyncio
import copy
import hashlib
import json
import math
import re
import time
import uuid
from collections import deque
from datetime import timezone
from email.utils import parsedate_to_datetime

import aiohttp

# ── 文档约定的网关与校验上限 ────────────────────────────────────────────
# 两个网关的请求体完全一致：换网关 = 换 base URL + 换 Bearer key。
GATEWAYS = {
    "jevmodel": "https://jevmodel.org",
    "typesafe": "https://api.typesafe.ai",
}

MAX_QUESTIONS = 8
MAX_STATE_CHARS = 1_000_000
MAX_INSTRUCTIONS_CHARS = 1_800
MAX_CRITERIA_CHARS = 2_000
MAX_QUESTION_NAME_CHARS = 64
MIN_CHOICE_OPTIONS = 2
MAX_CHOICE_OPTIONS = 20
MIN_SCORE_LEVELS = 2
MAX_SCORE_LEVELS = 10
RATE_LIMIT_PER_MINUTE = 120
RATE_LIMIT_WINDOW_SEC = 60.0

# 文档只说明 score 是「可为小数」的有序光谱，未约定 0 基还是 1 基；
# 这里只做宽松区间校验，落在哪一级由 jev_judge 按等级顺序映射。
SCORE_RANGE_SLACK = 1

# 问题名是标识符：字母、数字和下划线。
_NAME_RE = re.compile(r"^[A-Za-z0-9_]+$")

def probability(node):
    value = node.get("noul") if isinstance(node, dict) else None
    return (
        value
        if type(value) in (int, float) and math.isfinite(value) and 0 <= value <= 1
        else None
    )


DEFAULT_TIMEOUT_SEC = 8


def budget_seconds(cfg) -> float:
    """Jev 判读的总预算（秒）。

    传输层、判读层与 main.py 的外层守卫共用这一个口径：三层各算各的会让外层
    先掐断内层请求，用户只看到「超时」，看不到上游到底慢在哪。
    """
    value = cfg.get("timeout_sec") if isinstance(cfg, dict) else None
    try:
        budget = float(value or DEFAULT_TIMEOUT_SEC)
    except (TypeError, ValueError):
        budget = DEFAULT_TIMEOUT_SEC
    return max(1.0, min(20.0, budget))


def normalize_base_url(base):
    """把用户填的接口地址收敛成完整的 /v1/systemone 端点。"""
    base = str(base or "").strip().rstrip("/")
    if not base:
        base = GATEWAYS["jevmodel"]
    if base.endswith("/v1/systemone"):
        return base
    if base.endswith("/v1"):
        return base + "/systemone"
    return base + "/v1/systemone"


def serialized_length(value) -> int:
    """按文档的口径估算序列化长度（文档以序列化后的字符数设限）。"""
    try:
        return len(json.dumps(value, ensure_ascii=False, separators=(",", ":")))
    except (TypeError, ValueError):
        return 0


# json.dumps 最坏情况下的转义膨胀：控制字符会展开成 \uXXXX（6 字符）。
_MAX_ESCAPE_EXPANSION = 6


def _raw_len(value) -> int:
    """粗估 value 序列化前的字符数（只用于判断「会不会超限」）。"""
    if isinstance(value, str):
        return len(value)
    if isinstance(value, dict):
        return sum(len(str(k)) + _raw_len(v) for k, v in value.items())
    if isinstance(value, (list, tuple)):
        return sum(_raw_len(v) for v in value)
    return len(str(value))


def _may_exceed(value, limit: int) -> bool:
    """保守判断：value 序列化后是否有可能超过上限。

    文档按序列化后的字符数设限，而序列化最多把一个字符膨胀成 6 个
    （控制字符的转义序列）。raw 长度小到膨胀 6 倍都够不着上限时，
    就不必真去 dumps 一遍算精确长度——预检每次要序列化 5 份数据，
    这是纯浪费。判断只会「跳过必然通过」的检查，不会放过真正的超限。
    """
    return _MAX_ESCAPE_EXPANSION * _raw_len(value) + 16 > limit


def validate_request(state, questions) -> list[str]:
    """本地预检请求体，返回问题清单（空列表＝本地校验通过）。

    规则照搬文档的校验器；提前拦下必然 422 的请求，省一次往返与一次额度预留。
    """
    problems: list[str] = []
    if not isinstance(questions, dict) or not questions:
        return ["questions 必须是非空对象"]

    if len(questions) > MAX_QUESTIONS:
        problems.append(f"一次请求最多 {MAX_QUESTIONS} 个问题（当前 {len(questions)} 个）")

    if _may_exceed(state, MAX_STATE_CHARS):
        state_len = serialized_length(state)
        if state_len > MAX_STATE_CHARS:
            problems.append(
                f"state 序列化后 {state_len} 字符，超过上限 {MAX_STATE_CHARS}"
            )

    for name, question in questions.items():
        if (
            not isinstance(name, str)
            or not _NAME_RE.match(name)
            or len(name) > MAX_QUESTION_NAME_CHARS
        ):
            problems.append(
                f"问题名 {name!r} 非法：只允许字母、数字和下划线，最长 {MAX_QUESTION_NAME_CHARS} 字符"
            )
        if not isinstance(question, dict):
            problems.append(f"问题 {name!r} 必须是对象")
            continue

        qtype = question.get("type")
        instructions = question.get("instructions")
        if not isinstance(instructions, str) or not instructions.strip():
            problems.append(f"问题 {name!r} 缺少 instructions")
        elif len(instructions) > MAX_INSTRUCTIONS_CHARS:
            problems.append(
                f"问题 {name!r} 的 instructions {len(instructions)} 字符，"
                f"超过上限 {MAX_INSTRUCTIONS_CHARS}"
            )

        criteria = question.get("criteria")
        if qtype == "choice":
            if not isinstance(criteria, dict) or not criteria:
                problems.append(f"问题 {name!r} 是 choice，criteria 必须是非空对象")
            elif not MIN_CHOICE_OPTIONS <= len(criteria) <= MAX_CHOICE_OPTIONS:
                problems.append(
                    f"问题 {name!r} 的 choice 选项数为 {len(criteria)}，"
                    f"应为 {MIN_CHOICE_OPTIONS}-{MAX_CHOICE_OPTIONS}"
                )
        elif qtype == "score":
            if not isinstance(criteria, list) or not criteria:
                problems.append(f"问题 {name!r} 是 score，criteria 必须是非空数组")
            elif not MIN_SCORE_LEVELS <= len(criteria) <= MAX_SCORE_LEVELS:
                problems.append(
                    f"问题 {name!r} 的 score 级数为 {len(criteria)}，"
                    f"应为 {MIN_SCORE_LEVELS}-{MAX_SCORE_LEVELS}"
                )
        elif qtype == "noul":
            if criteria is not None and not isinstance(criteria, dict):
                problems.append(f"问题 {name!r} 是 noul，criteria 只能是对象或省略")
        elif qtype == "box":
            pass  # box 只用 instructions，不接受 criteria
        else:
            problems.append(f"问题 {name!r} 的 type {qtype!r} 不受支持")

        if criteria is not None and _may_exceed(criteria, MAX_CRITERIA_CHARS):
            criteria_len = serialized_length(criteria)
            if criteria_len > MAX_CRITERIA_CHARS:
                problems.append(
                    f"问题 {name!r} 的 criteria 序列化后 {criteria_len} 字符，"
                    f"超过上限 {MAX_CRITERIA_CHARS}"
                )
    return problems


def new_idempotency_key() -> str:
    """为一次逻辑调用生成幂等键（文档上限 100 字符）。

    键必须区分「同一次调用的重试」与「另一次独立调用」：按内容派生会让两条
    内容相同的消息互相冲突（服务端返回 409）。一次调用内固定复用同一个键，
    重试才不会重复计费。

    前缀用 soup-（与 oven_multi 的 oven-、angel_heart 的 angel- 区分），
    同一个网关上多个插件的请求不会互相命中同一把键。
    """
    return f"soup-{uuid.uuid4().hex}"


# 文档的错误码语义（见「错误与重试」）：429 与 502 用退避重试，其余不重试。
RETRYABLE_STATUS = {409, 429, 502, 503, 529}

_STATUS_BY_HTTP = {
    401: "unauthorized",
    402: "insufficient_credits",
    409: "conflict",
    422: "invalid_request",
    429: "rate_limited",
    502: "upstream_error",
    503: "overloaded",
    529: "overloaded",
}


def error_status(http_status: int) -> str:
    """把 HTTP 状态码映射成可读状态（未列出的按通用错误处理）。"""
    return _STATUS_BY_HTTP.get(int(http_status), "error")


def parse_error(payload) -> tuple[str, str]:
    """解析文档的错误包 {"error": {"type": ..., "message": ...}}。"""
    if not isinstance(payload, dict):
        return "", ""
    error = payload.get("error")
    if not isinstance(error, dict):
        return "", ""
    return str(error.get("type") or ""), str(error.get("message") or "")


class JevClient:
    def __init__(self):
        self.session = None
        self.cache = {}
        self.failures = {}
        self.inflight = {}
        self.closed = False
        self.tokens_remaining = None
        self.hits = {}
        self.metrics = dict.fromkeys(
            (
                "requests",
                "cache_hits",
                "coalesced",
                "errors",
                "cancelled",
                "backoff_skips",
                "busy_skips",
                "rate_limited",
                "input_tokens",
                "output_tokens",
                "request_chars",
            ),
            0,
        )
        self.last = {"status": "idle"}

    def status(self):
        return (
            self.metrics
            | {
                "inflight": len(self.inflight),
                "tokens_remaining": self.tokens_remaining,
                "last": self.last.copy(),
            }
        )

    async def close(self):
        self.closed = True
        tasks = [entry["task"] for entry in self.inflight.values()]
        for task in tasks:
            task.cancel()
        await asyncio.gather(*tasks, return_exceptions=True)
        self.inflight.clear()
        if self.session is not None and not self.session.closed:
            await self.session.close()
        self.session = None

    async def evaluate(self, cfg, state, questions, idem=None):
        if self.closed:
            return {"status": "closed"}
        # cfg / state / questions 在传输层全程只读，深拷贝纯属浪费：
        # state 可达百万字符，深拷贝一次要按 MB 级复制。
        cfg = dict(cfg)
        if not str(cfg.get("api_key") or "").strip():
            return {"status": "unconfigured"}

        problems = validate_request(state, questions)
        if problems:
            return {
                "status": "invalid_request",
                "retryable": False,
                "problems": problems,
                "error_message": "；".join(problems),
            }

        base = str(cfg.get("base_url") or GATEWAYS["jevmodel"])
        url = normalize_base_url(base)
        signature = hashlib.sha256(
            json.dumps([url, cfg.get("model"), cfg.get("api_key")]).encode()
        ).hexdigest()
        timeout = budget_seconds(cfg)
        model = cfg.get("model") or "jev-latest"
        payload = {
            "model": model,
            "state": state,
            "questions": questions,
        }
        # 只序列化一次：缓存键、字节计数与实际请求体共用同一份 JSON 文本。
        # 之前同一份 state 要 dumps 三遍（键、计数、aiohttp 自己再序列化）。
        payload_json = json.dumps(
            payload, ensure_ascii=False, separators=(",", ":")
        )
        idem = idem or new_idempotency_key()
        key = hashlib.sha256(
            f"{signature}|{timeout}|".encode() + payload_json.encode()
        ).hexdigest()
        now = time.monotonic()
        cached = self.cache.get(key)
        if cached and now - cached[0] < 30:
            self.metrics["cache_hits"] += 1
            result = copy.deepcopy(cached[1]) | {"cache_hit": True, "seconds": 0}
            self.last = {k: v for k, v in result.items() if k != "answers"}
            return result
        failures, until = self.failures.get(signature, (0, 0))
        if now < until:
            self.metrics["backoff_skips"] += 1
            self.last = {
                "status": "backoff",
                "retry_after": math.ceil(until - now),
                "retryable": True,
            }
            return self.last.copy()

        # 文档限流：每个 key 每分钟 120 次。本地先拦一道，省掉必然被 429 的往返。
        hits = self.hits.setdefault(signature, deque())
        while hits and now - hits[0] > RATE_LIMIT_WINDOW_SEC:
            hits.popleft()
        if len(self.hits) > 64:
            self.hits.pop(next(iter(self.hits)))
        if len(hits) >= RATE_LIMIT_PER_MINUTE:
            wait = int(RATE_LIMIT_WINDOW_SEC - (now - hits[0])) + 1
            self.metrics["rate_limited"] += 1
            self.last = {
                "status": "rate_limited",
                "retry_after": wait,
                "retryable": True,
            }
            return self.last.copy()

        entry = self.inflight.get(key)
        if entry is None:
            # Bound sockets/work rather than queueing old chat decisions.
            if len(self.inflight) >= 8:
                self.metrics["busy_skips"] += 1
                return {"status": "busy"}
            hits.append(now)  # 真正发出请求才计入限流窗口
            task = asyncio.create_task(
                self._request(
                    url, cfg, payload, payload_json, timeout, signature, key, model, idem
                )
            )
            entry = {"task": task, "waiters": 0}
            self.inflight[key] = entry
        else:
            self.metrics["coalesced"] += 1
        entry["waiters"] += 1
        try:
            # One caller being superseded must not cancel another current caller.
            return copy.deepcopy(await asyncio.shield(entry["task"]))
        finally:
            entry["waiters"] -= 1
            if not entry["waiters"]:
                if self.inflight.get(key) is entry:
                    self.inflight.pop(key)
                if not entry["task"].done():
                    entry["task"].cancel()
                    await asyncio.gather(entry["task"], return_exceptions=True)

    async def _request(
        self, url, cfg, payload, payload_json, timeout, signature, key, model, idem
    ):
        if self.session is None or self.session.closed:
            self.session = aiohttp.ClientSession(
                json_serialize=lambda value: json.dumps(
                    value, ensure_ascii=False, separators=(",", ":")
                )
            )
        self.metrics["requests"] += 1
        self.metrics["request_chars"] += len(payload_json)
        started = time.monotonic()
        result = {"status": "error"}
        delay = 0
        # 同一次逻辑调用的重试复用同一把键，不会重复扣费
        idempotency = idem
        try:
            async with self.session.post(
                url,
                # 直接发已序列化的请求体：与 aiohttp 的 json= 走同一份字节，
                # 但不用让它再 dumps 一遍。
                data=payload_json.encode(),
                headers={
                    "Authorization": "Bearer " + str(cfg["api_key"]),
                    "Content-Type": "application/json",
                    "Idempotency-Key": idempotency,
                },
                timeout=aiohttp.ClientTimeout(total=timeout),
                allow_redirects=False,
            ) as response:
                if response.status == 200:
                    data = await response.json(content_type=None)
                    if valid_answers(data, payload["questions"]):
                        result = {
                            "status": "ready",
                            "answers": data["answers"],
                            "model": str(data.get("model") or ""),
                            "cache_hit": False,
                            "retryable": False,
                        }
                        usage = data.get("usage")
                        if isinstance(usage, dict):
                            result["usage"] = {
                                k: v
                                for k, v in usage.items()
                                if k in ("input_tokens", "output_tokens")
                                and type(v) is int
                                and v >= 0
                            }
                        remaining = response.headers.get("X-Tokens-Remaining")
                        if remaining is not None:
                            try:
                                self.tokens_remaining = int(str(remaining).strip())
                            except (TypeError, ValueError):
                                pass
                    else:
                        result = {"status": "invalid_answer", "retryable": False}
                else:
                    body = await response.json(content_type=None)
                    error_type, error_message = parse_error(body)
                    result = {
                        "status": error_status(response.status),
                        "http_status": response.status,
                        "retryable": response.status in RETRYABLE_STATUS,
                        "error_type": error_type,
                        "error_message": error_message,
                    }
                    if response.status in (400, 401, 402, 403, 404, 422):
                        # 请求本身有问题（认证/余额/校验），短时间内重试没有意义
                        delay = 300
                    elif response.status == 429:
                        delay = retry_after(response.headers.get("Retry-After")) or 60
                    elif response.status in (502, 503, 529):
                        # 上游故障：文档说明已退款，短暂退避后重试是安全的
                        delay = 2
        except asyncio.CancelledError:
            self.metrics["cancelled"] += 1
            raise
        except (aiohttp.ClientError, ValueError, TimeoutError):
            result = {"status": "error", "retryable": True}
        if result["status"] == "ready":
            self.failures.pop(signature, None)
            if len(self.cache) >= 128:
                self.cache.pop(next(iter(self.cache)))
            # 缓存里存原件即可：evaluate() 返回给调用方前会深拷贝一份，
            # 调用方改不到缓存。之前这里再拷一次，纯属重复。
            self.cache[key] = (time.monotonic(), result)
            for name, value in result.get("usage", {}).items():
                self.metrics[name] += value
        else:
            self.metrics["errors"] += 1
            failures = self.failures.get(signature, (0, 0))[0] + 1
            if len(self.failures) >= 32:
                self.failures.pop(next(iter(self.failures)))
            if result.get("status") in ("error", "upstream_error", "overloaded", "conflict"):
                # 临时故障：退避窗口按秒级递增，本轮预算内仍可重试
                delay = max(delay, min(30, 2**min(5, failures)))
            self.failures[signature] = (failures, time.monotonic() + delay)
            result.setdefault("retryable", False)
            result["retry_after"] = int(delay)
        result["seconds"] = round(time.monotonic() - started, 3)
        self.last = {k: v for k, v in result.items() if k != "answers"}
        return result


def valid_answers(data, questions):
    if not isinstance(data, dict) or not isinstance(data.get("answers"), dict):
        return False
    for name, question in questions.items():
        answer = data["answers"].get(name)
        if not isinstance(answer, dict) or answer.get("type") != question.get("type"):
            return False
        if question.get("type") == "noul" and probability(answer) is None:
            return False
        if question.get("type") in ("choice", "score"):
            if probability({"noul": answer.get("confidence")}) is None:
                return False
            criteria = question.get("criteria") or {}
            if question["type"] == "choice" and (
                not isinstance(answer.get("choice"), str)
                or answer["choice"] not in criteria
            ):
                return False
            if question["type"] == "score":
                value = answer.get("score")
                # 文档未约定 score 的起点（0 基还是 1 基），这里只做宽松区间校验：
                # 落在哪一级由 jev_judge 按等级顺序映射，避免误判整个响应无效。
                limit = len(criteria) - 1 + SCORE_RANGE_SLACK
                if (
                    type(value) not in (int, float)
                    or not math.isfinite(value)
                    or not 0 <= value <= limit
                ):
                    return False
    return bool(questions)


def retry_after(value):
    """Honor a server's overload delay without sleeping on a foreground turn."""
    if not value:
        return 0
    try:
        seconds = float(value)
    except ValueError:
        try:
            stamp = parsedate_to_datetime(value)
            if stamp.tzinfo is None:
                stamp = stamp.replace(tzinfo=timezone.utc)
            seconds = stamp.timestamp() - time.time()
        except (TypeError, ValueError, OverflowError):
            return 0
    return min(3600, max(0, seconds)) if math.isfinite(seconds) else 0
