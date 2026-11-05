"""Loomy /v1/* 转发实现（供 dispatch.py 调用）。

## 三个协议都要实现

    /v1/chat/completions   OpenAI
    /v1/messages           Anthropic
    /v1/responses          Responses
    /v1/models
    /v1/balance

## 鉴权 / 选号 / 记账（本次修复）

改造前这里同样没有 Key 校验、没有账号绑定、不写用量日志、不占租约。
现在统一走 `admin.platform.shared`：

    authenticate()      鉴权 + 配额 + 哨兵暂停
    select_account()    平台 + 区域 + Key 归属 + 冷却 + 在途
    record_usage()      写带 platform 的 usage_logs

## 流式

Loomy 上游只有非流式接口。`stream: true` 时把完整结果**合成为 SSE 帧**
返回 —— 客户端按 SSE 解析不会因为收到一个 JSON 就崩掉。
"""
from __future__ import annotations

import json
import logging
import time

from starlette.background import BackgroundTask
from starlette.responses import JSONResponse, StreamingResponse

from admin.platform import shared
from admin.platform.loomy.core import client
from admin.platform.loomy.services import accounts as loomy_accounts

logger = logging.getLogger("admin.platform.loomy.gateway")

#: 拦截路径（dispatch 据此判断要不要转交）
PATHS = (
    "/v1/chat/completions",
    "/v1/messages",
    "/v1/messages/count_tokens",
    "/v1/responses",
    "/v1/models",
    "/v1/balance",
)

PUBLIC = "loomy"
MAX_ATTEMPTS = 3


async def _body_of(request) -> dict:
    """读 JSON body；GET/HEAD 无 body，直接返回空（读了会卡住）。"""
    if request.scope.get("method", "GET").upper() in ("GET", "HEAD", "OPTIONS"):
        return {}
    cached = request.scope.get("_wb_body")
    if isinstance(cached, bytes) and cached:
        try:
            data = json.loads(cached)
            return data if isinstance(data, dict) else {}
        except (ValueError, UnicodeDecodeError):
            return {}
    try:
        data = await request.json()
    except Exception:  # noqa: BLE001
        return {}
    return data if isinstance(data, dict) else {}


def _realm(request) -> str:
    _storage, realm, _spec = shared.locate(request, PUBLIC)
    return realm or "cn"


def _client_ip(request) -> str:
    try:
        from admin.client_ip import request_ip

        return request_ip(request)
    except Exception:  # noqa: BLE001
        return ""


def _fail(exc: client.UpstreamError) -> JSONResponse:
    # **把上游原始错误完整记下来**：Loomy 的 400 只回「请求失败（HTTP 400）」，
    # 看不出到底哪里不合法。detail 里是上游原文，必须落日志才排得动。
    try:
        logger.warning("Loomy 上游失败 kind=%s status=%s msg=%s detail=%s",
                       getattr(exc, "kind", ""), getattr(exc, "status", ""),
                       str(getattr(exc, "message", ""))[:200],
                       str(getattr(exc, "detail", ""))[:600])
    except Exception:  # noqa: BLE001
        pass
    status = exc.status or 502
    if status < 400 or status > 599:
        status = 502
    return JSONResponse(
        {"error": {"type": exc.kind, "code": exc.code or "upstream_error",
                    "message": exc.message}},
        status_code=status)


#: 上游只认这三个角色。别的角色进来后**不能原样透传**。
#: 上游（OpenAI 兼容 /chat/completions）接受的角色。
#:
#: 2026-11-05 修正：官方客户端打同一上游端点的 498 条真实请求体里，
#: `tool` 消息（175 条）与 assistant `tool_calls`（122 条）**原样透传，
#: 490/490 全部 200** —— 之前「上游只认三种角色」的判断是错的，
#: 把 tool 转成 user 文本反而导致工具调用不生效。
_UPSTREAM_ROLES = frozenset({"system", "user", "assistant", "tool"})


def normalize_messages(raw) -> list[dict]:
    """把 messages 归一成上游能接受的样子。

    ## 为什么必须做

    `developer` 是 OpenAI 较新的角色，DSH 这类 harness 在**开推理时**
    会用它承载系统提示（还把整段 system prompt 塞进去），上游不认，
    需要归一成 `system`。

    ## 归一规则（改为**结构化透传**）

    * `developer` -> `system`（它本来就是系统提示的语义）
    * `tool` -> **原样保留**（含 `tool_call_id` / `name`），上游实测接受；
      老式 `function` 角色没有 call id 结构，归一到 `tool` 并保留凭据
    * assistant 的 `tool_calls` -> **原样保留**（不再压成 JSON 文本块）。
      之前转文本的后果：模型把上一轮调用读成「一段描述」，
      参数经常缺引号/少括号，客户端解析失败直接中断
    * 未知角色 -> 丢弃
    * `system` **全部前置**（中途出现的 system 会失去指令权重）
    * content 数组仍取文本块（上游文本协议）；assistant 工具调用消息的
      `content: null` 保留 —— 那是标准 OpenAI 形状
    """
    if not isinstance(raw, list):
        return []
    systems: list[dict] = []
    others: list[dict] = []
    for item in raw:
        if not isinstance(item, dict):
            continue
        role = str(item.get("role") or "").strip().lower()
        if role == "developer":
            role = "system"
        elif role == "function":
            # 老式 function 角色语义等同工具结果。上游实测接受 role=tool，
            # 所以归一到 tool 并保留调用标识，不再降级成 user 文本
            # （降级会让模型把结果当成又一条用户消息，重复发起同一调用）。
            role = "tool"
        if role not in _UPSTREAM_ROLES:
            continue
        content = item.get("content")
        if isinstance(content, list):
            # 兼容 parts 数组：只取文本块
            parts = []
            for block in content:
                if isinstance(block, dict) and block.get("type") == "text":
                    parts.append(str(block.get("text") or ""))
                elif isinstance(block, str):
                    parts.append(block)
            content = "".join(parts)
        # content=None 只允许标准 OpenAI 形状
        # `{"role":"assistant","content":null,"tool_calls":[...]}`；
        # 其余空消息直接丢，避免上游把空输入当非法请求。
        _has_calls = isinstance(item.get("tool_calls"), list)
        if content is None and not (role == "assistant" and _has_calls):
            continue
        message = {"role": role, "content": content}
        if role == "tool":
            # 工具结果**原样透传**（含调用标识）：丢掉 tool_call_id 的话
            # 模型不知道结果对应哪次调用，会重复调用。
            _tcid = item.get("tool_call_id")
            if _tcid:
                message["tool_call_id"] = str(_tcid)
            elif item.get("name"):
                # function 角色没有 tool_call_id，用 name 兜住配对凭据
                message["tool_call_id"] = str(item["name"])
            if item.get("name"):
                message["name"] = str(item["name"])
        if role == "assistant" and _has_calls:
            # assistant 的工具调用**原样保留**（不再压成 JSON 文本块）：
            # 转文本会让模型把调用读成「一段描述」，参数经常缺引号/少括号。
            # 唯一例外：协议要求 arguments 是字符串；客户端传对象时序列化回去。
            calls = []
            for call in item["tool_calls"]:
                if not isinstance(call, dict):
                    continue
                c = dict(call)
                fn = c.get("function")
                if isinstance(fn, dict) and not isinstance(fn.get("arguments"), str):
                    fn = dict(fn)
                    fn["arguments"] = json.dumps(fn.get("arguments"), ensure_ascii=False)
                    c["function"] = fn
                calls.append(c)
            message["tool_calls"] = calls
        if role == "system":
            systems.append(message)
        else:
            others.append(message)
    return systems + others

def _apply_no_think(body: dict) -> dict:
    """关掉推理链的三层保险（对非 reasoning 模型是 noop）。

    上游 reasoning 模型会**无视 max_tokens 跑满思考链**，
    导致 `finish_reason: length` 且 `content: ""` —— 看起来像「空回复」，
    其实是正文还没开始就被截断了。
    """
    out = dict(body)
    params = dict(out.get("chat_template_kwargs") or {})
    params.setdefault("enable_thinking", False)
    out["chat_template_kwargs"] = params
    out.setdefault("enable_thinking", False)

    # **`max_tokens` 必须放大**。
    #
    # Loomy 的 DeepSeek-V4.1-Flash 是**只能推理**的模型：
    # 实测 `enable_thinking:false`、`chat_template_kwargs`、`/no_think`
    # 三种关思考手段**全部无效**，它一定先跑完思考链才出正文。
    #
    # 后果：客户端给 `max_tokens: 32` 时，32 个 token 全被 reasoning 吃掉，
    # `finish_reason: length` 且 `content: ""` —— 看起来像「模型不回复」。
    # 实测 max_tokens=200 就正常出正文了。
    #
    # 所以给一个**思考预算下限**：客户端要得少也补到 512，
    # 但不超过 8192（避免要长文时被额外收费）。
    # **`max_tokens` 必须按输入长度动态放大**。
    #
    # Loomy 的 DeepSeek-V4.1 只能推理，先跑完思考链才出正文。实测：
    #   短提示 + max_tokens=100  -> 正文 13 字（512 下限兜住了）
    #   长提示 + max_tokens=512  -> finish_reason=length，**正文 0 字**
    #     （512 token 全被思考吃掉，usage.reasoning_tokens=512）
    #
    # 所以下限要跟输入规模挂钩：输入越长、思考越久。这里按「输入字符数的
    # 2 倍 + 512」估算思考预算，并给足正文空间。
    try:
        want = int(out.get("max_tokens") or 0)
    except (TypeError, ValueError):
        want = 0
    # 输入规模（字符数，中文按 1 算，够用）
    _chars = 0
    for _m in out.get("messages") or []:
        _c = _m.get("content")
        if isinstance(_c, str):
            _chars += len(_c)
        elif isinstance(_c, list):
            for _b in _c:
                if isinstance(_b, dict):
                    _chars += len(str(_b.get("text") or ""))
    # 思考预算：**Loomy 的思考链会吃掉几千到上万 token**。
    #
    # 实测同一段提示词：
    #   max_tokens=4000   -> finish=length，正文 0 字（全被思考吃光）
    #   max_tokens=8000   -> finish=length，正文 6402 字（还是被截）
    #   max_tokens=16000  -> finish=stop，  正文 9069 字  ✅
    #
    # 所以下限必须够大：**给 16384**（多数上游的单次输出上限），
    # 不能只给 4096 —— 那等于把慢思考模型永久截断，表现是「回复到一半停住」
    # 或「正文 0 字」，用户很难判断是模型问题还是网关问题。
    # 客户端显式要得更多时，放宽到 32768。
    _floor = 16384 + min(8192, _chars * 2)
    if want < _floor:
        out["max_tokens"] = _floor
    elif want > 32768:
        out["max_tokens"] = 32768

    # `/no_think` 前缀对 Loomy **无效**（实测它会把这三个字当正文念出来），
    # 所以这里不再拼接，避免污染用户输入。
    messages = normalize_messages(out.get("messages") or [])
    for index in range(len(messages) - 1, -1, -1):
        item = messages[index]
        if not isinstance(item, dict) or item.get("role") != "user":
            continue
        content = item.get("content")
        if isinstance(content, str) and not content.lstrip().startswith("/no_think"):
            messages[index] = {**item, "content": "/no_think " + content}
        break
    out["messages"] = messages
    return out


def _attempt(db, request, key, body: dict, realm: str):
    """选号 + 租约 + 调上游（换号重试）。"""
    model = str(body.get("model") or "")
    exclude: set[int] = set()
    last_error: client.UpstreamError | None = None
    for _ in range(MAX_ATTEMPTS):
        account = shared.select_account(
            db, storage=loomy_accounts.PLATFORM, realm=realm, key=key,
            model=model, exclude_ids=exclude)
        if account is None:
            break
        if not shared.lease(account):
            exclude.add(account.id)
            continue
        started = time.perf_counter()
        try:
            data = loomy_accounts.ensure_token(db, account)
            result = client.chat_completions(
                loomy_accounts.token_of(data), realm, _apply_no_think(body),
                account_id=int(account.id or 0))
            return result, account, started
        except client.UpstreamError as exc:
            shared.release(account)
            shared.note_failure(
                db, account, kind=exc.kind, detail=exc.detail or exc.message,
                status=exc.status, model=model, public_platform=PUBLIC,
                cool_seconds=(600 if exc.kind in ("auth", "quota_exceeded") else 0))
            last_error = exc
            if not exc.retryable():
                break
            # **400「请重试」类错误不要立刻换号**：DashScope 的瞬时 400 与
            # 账号无关，换号也一样失败，反而把唯一可用账号排除掉。
            # 先短暂退避、同账号再试一次（上游通常几百毫秒就恢复）。
            if exc.status == 400:
                time.sleep(0.8)
                continue
            exclude.add(account.id)
        except Exception as exc:  # noqa: BLE001
            shared.release(account)
            logger.exception("Loomy 调用失败 acc=%s", account.id)
            last_error = client.UpstreamError(str(exc), kind="network")
            exclude.add(account.id)
            continue
    if last_error is not None:
        raise last_error
    raise shared.PlatformRejected(
        503, "Loomy 没有可用账号（请先在控制台导入并确认状态为启用）",
        kind="server_error", code="no_available_account",
        headers={"Retry-After": "3"})


def _bill(key, account, model, result, *, request, started=None, error="",
          stats: dict | None = None):
    try:
        from admin.db import SessionLocal

        usage = (result or {}).get("usage") or {}
        elapsed = int((time.perf_counter() - started) * 1000) if started else None
        # **分段耗时**：`client._request` 在 `urlopen` 返回处记了首字节时间，
        # 那里才是真正「开始有响应」的时刻。之前把 ttfb 和 latency 都写成
        # 总耗时，`latency - ttfb = 0`，TPS 只能退回整段计算 —— 于是
        # 真实 214 tok/s 被算成 44 tok/s（差一个量级）。
        # **优先用调用方显式传入的 stats**：`_bill` 在流结束后的另一个
        # 协程里跑，contextvar 在这里读不到生成器里设的值（这正是之前
        # `ttfb == latency`、TPS 永远算不出来的原因）。
        ttfb = total = 0
        if isinstance(stats, dict):
            ttfb = int(stats.get("ttfb_ms") or 0)
            total = int(stats.get("total_ms") or 0)
        if not ttfb and not total:
            try:
                ttfb = int(client.LAST_TTFB_MS.get() or 0)
                total = int(client.LAST_TOTAL_MS.get() or 0)
            except Exception:  # noqa: BLE001
                ttfb = total = 0
        if not (0 < ttfb <= (total or elapsed or 0)):
            ttfb = 0
        latency = max(total, elapsed or 0) or None
        # 改成**真流式**后，`ttfb`（首帧到达）与 `latency`（最后一帧）
        # 天然有区分度，`latency - ttfb` 就是真实的纯解码耗时，
        # TPS 可以直接算。不再需要「只记 ttfb」那种回避做法。
        if not ttfb:
            ttfb = latency
        with SessionLocal() as db:
            shared.record_usage(
                db,
                key_id=int(getattr(key, "id", 0) or 0),
                account_id=int(getattr(account, "id", 0) or 0),
                model=model or str((result or {}).get("model") or ""),
                usage=usage, public_platform=PUBLIC,
                storage=loomy_accounts.PLATFORM,
                error_kind=error, client_ip=_client_ip(request),
                use_case="loomy-chat", seq=1,
                ttfb_ms=ttfb, latency_ms=latency)
    except Exception:  # noqa: BLE001
        logger.exception("Loomy 记账失败")


async def _forward(body: dict, request, *, usage=None) -> JSONResponse:
    """鉴权 -> 选号 -> 上游 -> 记账。"""
    from admin.db import SessionLocal

    realm = _realm(request)
    db = SessionLocal()
    try:
        key = shared.authenticate(db, request, platform=_public(request))
        try:
            result, account, started = _attempt(db, request, key, body, realm)
        except shared.PlatformRejected:
            raise
        except client.UpstreamError as exc:
            return _fail(exc)
        shared.release(account)
        shared.note_success(account)
        try:
            db.commit()
        except Exception:  # noqa: BLE001
            db.rollback()
        _bill(key, account, str(body.get("model") or ""), result,
              request=request, started=started)
        return JSONResponse(result)
    finally:
        db.close()


def _public(request) -> str:
    return shared.public_platform_of(request, PUBLIC)


async def chat_completions(request):
    """对话入口：**流式请求走真流式转发**。

    ## 历史坑（已修）

    这里原来是「伪流式」：先发非流式请求拿到**完整结果**，再切块合成 SSE。
    注释写的理由是「上游只有非流式」，但那是错的 —— 实测上游 `stream: true`
    返回 `text/event-stream`，首帧 1.6 秒就到。

    伪流式的代价：
      · 客户端先干等几十秒（等于把 TTFT 变成整个生成时间），
        再一瞬间收完整篇 —— 完全不像是流式，长任务还会撞网关总时限；
      · `ttfb` 与 `latency` 天然相等，TPS 算不出来（只能记「—」）；
      · 观感是「卡住了」，实际是上游早就开始吐字了。

    现在：`client.chat_stream` 逐帧读上游、`_sse_from_chunks` 逐帧转协议、
    `StreamingResponse` 逐帧下发 —— 与直连上游的时序基本一致。
    """
    body = await _body_of(request)
    if not body.get("stream"):
        return await _forward(body, request)
    return await _forward_stream(body, request)


async def _forward_stream(body: dict, request):
    """真流式：选号 -> 上游 SSE -> 逐帧转发 -> 收尾记账。"""
    from admin.db import SessionLocal

    realm = _realm(request)
    db = SessionLocal()
    # ⚠️ 关闭必须是幂等的：正常路径由生成器的 finally 关（那时流已结束），
    # 异常/提前返回路径由下面的 finally 关，两条路径都可能触发。
    closed = {"done": False}

    def close_db() -> None:
        if closed["done"]:
            return
        closed["done"] = True
        try:
            db.close()
        except Exception:  # noqa: BLE001 - 关闭失败不该掩盖真正的错误
            pass

    try:
        # ⚠️ `authenticate()` 必须在 try 内：它会对无效 API Key 抛
        # HTTPException。原来它写在 try 之前，于是「匿名请求打流式端点」
        # 这条最容易被触发的路径**必然泄漏一个 Session** ——
        # 实测 60 次无效 Key 就能把连接池打满，之后普通查询也 30s 超时，
        # 全站 DB 不可用，只能重启。
        # （raccoon 的同一处早已用 try/finally 修好，loomy 漏了。）
        key = shared.authenticate(db, request, platform=_public(request))
        return await _forward_stream_inner(
            db, body, request, realm, key, close_db)
    except BaseException:
        close_db()
        raise


async def _forward_stream_inner(db, body, request, realm, key, close_db):
    model = str(body.get("model") or "")
    # 分段耗时容器：**必须在调用 client.chat_stream 之前定义**。
    # 它由上游流式读取器填 ttfb/total，再交给 _bill 记账。
    stats: dict = {}
    exclude: set[int] = set()
    account = None
    chunks = None
    last_error = None
    started = time.perf_counter()
    for _ in range(MAX_ATTEMPTS):
        account = shared.select_account(
            db, storage=loomy_accounts.PLATFORM, realm=realm, key=key,
            model=model, exclude_ids=exclude)
        if account is None:
            break
        if not shared.lease(account):
            exclude.add(account.id)
            continue
        try:
            data = loomy_accounts.ensure_token(db, account)
            chunks = client.chat_stream(
                loomy_accounts.token_of(data), realm, _apply_no_think(body),
                account_id=int(account.id or 0), stats=stats)
            break
        except client.UpstreamError as exc:
            shared.release(account)
            shared.note_failure(
                db, account, kind=exc.kind, detail=exc.detail or exc.message,
                status=exc.status, model=model, public_platform=PUBLIC,
                cool_seconds=(600 if exc.kind in ("auth", "quota_exceeded") else 0))
            last_error = exc
            exclude.add(account.id)
            if not exc.retryable():
                break
        except Exception as exc:  # noqa: BLE001
            shared.release(account)
            logger.exception("Loomy 流式调用失败 acc=%s", account.id)
            last_error = client.UpstreamError(str(exc), kind="network")
            exclude.add(account.id)

    if chunks is None:
        close_db()
        if last_error is not None:
            return _fail(last_error)
        raise shared.PlatformRejected(
            503, "Loomy 没有可用账号（请先在控制台导入并确认状态为启用）",
            kind="server_error", code="no_available_account",
            headers={"Retry-After": "3"})

    holder: dict = {}
    # ⚠️ 流式清理必须幂等，且必须有一个**不依赖生成器 finally** 的兜底。
    #
    # 为什么：ASGI spec 2.3 下客户端断连时 uvicorn 会 cancel 任务，
    # 而 starlette 0.46.2 的 `stream_response` 既没有 `aclose()` 也没有
    # `finally` —— 生成器的 finally 只能在**垃圾回收时**才跑到。
    # 结果：客户端提前断开 → 租约不归还 → `MAX_IN_FLIGHT` 被吃满 →
    # 该账号 `full=True` 永久退出号池，只有重启才恢复。
    # 实测：3 次「断在响应开始前」即吃满 3/3，等 5 秒 + 强制 gc 仍是 3。
    #
    # raccoon 已用 `BackgroundTask(cleanup)` 修好同一问题，这里照做。
    cleaned = {"done": False}

    def cleanup() -> None:
        if cleaned["done"]:
            return
        cleaned["done"] = True
        try:
            shared.release(account)
            shared.note_success(account)
            db.commit()
        except Exception:  # noqa: BLE001
            try:
                db.rollback()
            except Exception:  # noqa: BLE001
                pass
        try:
            _bill(key, account, model, {"usage": holder.get("usage") or {}},
                  request=request, started=started, stats=stats)
        except Exception:  # noqa: BLE001 - 记账失败不该影响连接关闭
            logger.exception("Loomy 流式记账失败 acc=%s", getattr(account, "id", "?"))
        close_db()

    def generator():
        try:
            yield from _sse_from_chunks(chunks, model, holder)
        except client.UpstreamError as exc:
            yield ("data: %s\n\n" % json.dumps(
                {"error": {"message": exc.message, "type": exc.kind}},
                ensure_ascii=False)).encode()
        finally:
            cleanup()

    return StreamingResponse(
        generator(), media_type="text/event-stream",
        headers={"Cache-Control": "no-cache", "X-Accel-Buffering": "no"},
        # 兜底：客户端断开 / task 被取消时，Starlette 仍会跑 background
        background=BackgroundTask(cleanup))


def _sse_from_chunks(chunks, model: str, holder: dict):
    """把上游 chunk 逐帧转成 OpenAI SSE 并产出**字节**。

    `holder['usage']` 收集最后一帧的 usage（含积分），供收尾记账与
    「客户端显示消耗积分」共用。
    """
    chunk_id = "chatcmpl-loomy"
    created = int(time.time())
    saw_reasoning = False

    def frame(delta: dict, finish=None, usage: dict | None = None) -> bytes:
        payload = {
            "id": chunk_id, "object": "chat.completion.chunk",
            "created": created, "model": model,
            "choices": [{"index": 0, "delta": delta, "finish_reason": finish}],
        }
        if usage is not None:
            payload["usage"] = usage
            payload["choices"] = []
        return ("data: %s\n\n" % json.dumps(payload, ensure_ascii=False)).encode()

    usage_acc: dict = {}
    # **工具调用的协议完整性**（客户端跑任务时中断就出在这里）：
    #   1. `tool_calls[].index` 必须存在且连续 —— 上游偶尔省略 index，
    #      客户端按 index 拼 arguments 会错位，拼出来的 JSON 是坏的；
    #   2. `finish_reason` 必须与**最后一个 tool_calls 分片同一帧**发出。
    #      原来先发一个空 delta 帧、再单独发 finish_reason，严格解析的客户端
    #      （DSH / Codex / VS Code 系）会认为工具调用不完整 → 直接中断任务；
    #   3. `arguments` 必须是能 json.loads 的完整串。上游截断时给半截
    #      `{"path": "/tm`，客户端一解析就抛错 —— 这里补成 `{}` 并记日志，
    #      让流程能继续（宁可少一个参数，也不要整个任务崩掉）。
    #
    # 合并所有 tool_calls 分片，等流结束再一次性发出：工具调用本来就不是
    # 增量消费的，客户端要的是「完整调用 + finish_reason」，不是逐字流。
    pending_calls: dict[int, dict] = {}
    saw_tool_call = False
    finish_out = None

    for chunk in chunks:
        if isinstance(chunk.get("usage"), dict) and chunk["usage"]:
            usage_acc.update(chunk["usage"])
        for choice in (chunk.get("choices") or []):
            if not isinstance(choice, dict):
                continue
            delta = choice.get("delta") or {}
            out: dict = {}
            if delta.get("reasoning_content"):
                out["reasoning_content"] = delta["reasoning_content"]
                saw_reasoning = True
            if delta.get("content"):
                out["content"] = delta["content"]
            for tc in (delta.get("tool_calls") or []):
                if not isinstance(tc, dict):
                    continue
                saw_tool_call = True
                idx = tc.get("index")
                if not isinstance(idx, int):
                    idx = len(pending_calls)
                slot = pending_calls.setdefault(
                    idx, {"id": None, "name": None, "arguments": ""})
                if tc.get("id"):
                    slot["id"] = tc["id"]
                fn = tc.get("function") if isinstance(tc.get("function"), dict) else {}
                if fn.get("name"):
                    slot["name"] = (slot["name"] or "") + str(fn["name"])
                if fn.get("arguments"):
                    slot["arguments"] += str(fn["arguments"])
            if choice.get("finish_reason"):
                finish_out = str(choice["finish_reason"])
            # 有正文/思考就逐帧发；工具调用留到最后合并发（见上）
            if out:
                yield frame(out)

    if saw_tool_call:
        # index 归一成 0..n-1，保证连续（客户端按它顺序建数组）
        merged = []
        for new_idx, idx in enumerate(sorted(pending_calls)):
            slot = pending_calls[idx]
            args = slot["arguments"] or "{}"
            try:
                json.loads(args)
            except Exception:  # noqa: BLE001 - 上游截断/拼错，兜成空对象
                import logging
                logging.getLogger("loomy").warning(
                    "tool_call arguments 不是合法 JSON，已兜底: %r", args[:200])
                args = "{}"
            merged.append({
                "index": new_idx,
                "id": slot["id"] or ("call_%d_%s" % (new_idx, int(time.time() * 1000))),
                "type": "function",
                "function": {"name": slot["name"] or "unknown", "arguments": args},
            })
        # **finish_reason 与 tool_calls 同一帧**（关键修复）
        yield frame({"tool_calls": merged}, "tool_calls")
        finish_out = "tool_calls"
    elif finish_out:
        yield frame({}, finish_out)

    # 收尾：带上整合好的 usage + 积分（客户端底部显示消耗要用）
    final_usage = _usage_with_credit(usage_acc, model)
    holder["usage"] = final_usage
    yield frame({}, None, usage=final_usage)
    yield b"data: [DONE]\n\n"


def _usage_with_credit(usage: dict, model: str) -> dict:
    """usage 里补齐 `credit` / `credits` / `cost` 三个同义键。

    ⚠️ **必须以原始 usage 为底**，不能只挑 prompt/completion/total 重造：
    那样 `cached_tokens` / `prompt_tokens_details` / `cache_read_input_tokens`
    会被整段丢掉，客户端与面板的「缓存命中」恒为 0（这就是 Loomy 命中率为 0
    的真正原因，与有没有账号无关）。
    """
    src = usage if isinstance(usage, dict) else {}
    out = dict(src)                      # 原样保留所有字段（含缓存）
    out["prompt_tokens"] = int(src.get("prompt_tokens") or 0)
    out["completion_tokens"] = int(src.get("completion_tokens") or 0)
    out["total_tokens"] = int(src.get("total_tokens") or 0)
    # 缓存命中补齐成各家客户端认的写法（幂等；源里没有就一个都不加）
    try:
        from upstream_compat import normalize_usage_cache

        normalize_usage_cache(out)
    except Exception:  # noqa: BLE001 - 补齐失败不影响主流程
        pass
    credit = 0.0
    try:
        raw = (usage or {}).get("credit")
        credit = float(raw) if isinstance(raw, (int, float)) else 0.0
    except (TypeError, ValueError):
        credit = 0.0
    if credit <= 0:
        try:
            from admin.db import SessionLocal as _SL
            from admin.platform.shared import credits_for as _cf

            toks = out["total_tokens"] or out["completion_tokens"]
            with _SL() as _db:
                credit = _cf(_db, loomy_accounts.PLATFORM, model, toks)
        except Exception:  # noqa: BLE001
            credit = 0.0
    if credit:
        out.update({"credit": credit, "credits": credit, "cost": credit})
    return out


def _sse_from_chat(result: dict):
    chunk_id = str(result.get("id") or "chatcmpl-loomy")
    model = str(result.get("model") or "")
    created = int(result.get("created") or time.time())
    choice = (result.get("choices") or [{}])[0]
    message = choice.get("message") or {}
    text = str(message.get("content") or "")
    reasoning = str(message.get("reasoning_content") or "")

    # 终点帧要带 usage：客户端底部显示「消耗 N 积分」读的就是它，
    # 不带的话 Loomy 的对话永远显示不出消耗。
    usage = result.get("usage") if isinstance(result.get("usage"), dict) else {}
    credit = 0.0
    try:
        credit = float(usage.get("credit") or usage.get("credits") or 0)
    except (TypeError, ValueError):
        credit = 0.0
    if credit <= 0:
        # 上游没算积分时按倍率补一个（`_bill` 里已算过同样的值）
        try:
            from admin.db import SessionLocal
            from admin.platform.shared import credits_for

            toks = (usage.get("total_tokens")
                    or usage.get("completion_tokens") or 0)
            with SessionLocal() as _db:
                credit = credits_for(_db, loomy_accounts.PLATFORM, model, toks)
        except Exception:  # noqa: BLE001
            credit = 0.0

    def frame(delta: dict, finish=None, with_usage: bool = False):
        payload = {
            "id": chunk_id, "object": "chat.completion.chunk",
            "created": created, "model": model,
            "choices": [{"index": 0, "delta": delta,
                         "finish_reason": finish}]}
        if with_usage:
            # 同样保留上游原始字段（缓存命中在这条路径上也不能丢）
            _u = dict(usage) if isinstance(usage, dict) else {}
            _u["prompt_tokens"] = int(_u.get("prompt_tokens") or 0)
            _u["completion_tokens"] = int(_u.get("completion_tokens") or 0)
            _u["total_tokens"] = int(_u.get("total_tokens") or 0)
            _u["credit"] = _u["credits"] = _u["cost"] = credit
            try:
                from upstream_compat import normalize_usage_cache

                normalize_usage_cache(_u)
            except Exception:  # noqa: BLE001
                pass
            payload["usage"] = _u
        return ("data: %s\n\n" % json.dumps(payload, ensure_ascii=False)).encode()

    yield frame({"role": "assistant"})
    if reasoning:
        yield frame({"reasoning_content": reasoning})

    # **tool_calls 必须转发且协议完整**：harness 客户端靠它决定下一步做什么。
    #
    # 这条是 Loomy 的**真实路径**（上游只有非流式，网关自己合成 SSE），
    # 所以这里的坑最要命。原来有三个问题：
    #   1. `tool_calls` 与 `finish_reason` **分成两帧**发 —— 严格客户端
    #      （DSH / Codex / VS Code 系）要求两者同帧，否则判定调用不完整，
    #      直接中断任务（这正是「跑任务经常报错中断」的主因）；
    #   2. 原样透传上游的 `tool_calls`，**补 `index`** 缺失时客户端按 index
    #      拼参数会错位，拼出来的 JSON 是坏的；
    #   3. 不校验 `arguments` 是否合法 JSON —— 上游给半截串就直接抛错。
    #
    # 现在：归一 index、校验参数（坏则兜成 {}）、与 finish_reason 同帧。
    raw_calls = message.get("tool_calls")
    merged_calls = []
    if isinstance(raw_calls, list):
        for i, tc in enumerate(raw_calls):
            if not isinstance(tc, dict):
                continue
            fn = tc.get("function") if isinstance(tc.get("function"), dict) else {}
            args = fn.get("arguments")
            if isinstance(args, dict):
                args = json.dumps(args, ensure_ascii=False)
            if not isinstance(args, str) or not args.strip():
                args = "{}"
            try:
                json.loads(args)
            except Exception:  # noqa: BLE001 - 上游截断/拼错
                import logging
                logging.getLogger("loomy").warning(
                    "upstream tool_call arguments 非法，已兜底: %r", args[:200])
                args = "{}"
            merged_calls.append({
                "index": i,
                "id": tc.get("id") or ("call_%d_%s" % (i, int(time.time() * 1000))),
                "type": "function",
                "function": {"name": (fn.get("name") or "unknown"), "arguments": args},
            })

    if text:
        yield frame({"content": text})
    if merged_calls:
        # **finish_reason 与 tool_calls 同一帧**
        yield frame({"tool_calls": merged_calls}, "tool_calls")
    else:
        yield frame({}, str(choice.get("finish_reason") or "stop"))
    # **始终补一个 usage 终点帧**（带积分），客户端据此显示「消耗 N 积分」。
    # 原来只在 `result["usage"]` 非空时发，且原样透传 —— Loomy 的 usage 里
    # 没有 credit，客户端就永远显示不出消耗。
    yield frame({}, None, with_usage=True)
    yield b"data: [DONE]\n\n"


def _anthropic_to_openai(body: dict) -> dict:
    """Anthropic 请求体 → OpenAI 请求体。

    委托给 `protocol_bridge.anthropic_to_openai`。

    本地旧实现只挑 `type == "text"` 的 content 块，**完全丢掉**
    `tools` / `tool_use` / `tool_result` —— 于是 Claude Code 系客户端在
    执行工具的那一轮发上来的工具结果变成空正文，任务直接卡死。
    桥的实现覆盖：tools 定义、assistant 的 tool_use → tool_calls、
    user 的 tool_result → role="tool"、图片块、tool_choice。
    """
    from admin.platform import protocol_bridge

    out = protocol_bridge.anthropic_to_openai(body)
    return _apply_no_think(out)


def _anthropic_usage_of(usage) -> dict:
    """OpenAI usage → Anthropic usage（含缓存读取/写入两个单列字段）。

    Anthropic 协议把缓存命中的输入 token 单独列在
    `cache_read_input_tokens`，Claude Code 等客户端据此显示「缓存读取」。
    漏了它，客户端命中率恒为 0，而网关侧账目是对的 —— 必须整份透出。
    """
    try:
        from upstream_compat import anthropic_usage_from

        out = anthropic_usage_from(usage)
        if out is not None:
            return out
    except Exception:  # noqa: BLE001
        pass
    u = usage if isinstance(usage, dict) else {}
    return {"input_tokens": int(u.get("prompt_tokens") or 0),
            "output_tokens": int(u.get("completion_tokens") or 0),
            "cache_read_input_tokens": 0,
            "cache_creation_input_tokens": 0}


def _openai_to_anthropic(result: dict, model: str) -> dict:
    """OpenAI 响应 → Anthropic message 结构。"""
    choice = (result.get("choices") or [{}])[0]
    message = choice.get("message") or {}
    text = str(message.get("content") or "")
    usage = result.get("usage") or {}
    stop = {"length": "max_tokens", "tool_calls": "tool_use"}.get(
        str(choice.get("finish_reason") or ""), "end_turn")
    return {
        "id": "msg_" + str(result.get("id") or "")[:24],
        "type": "message",
        "role": "assistant",
        "model": model,
        "content": [{"type": "text", "text": text}] if text else [],
        "stop_reason": stop,
        "usage": _anthropic_usage_of(usage),
    }


async def messages(request):
    """Anthropic 协议。**流式请求真流式转发**，非流式才聚合。"""
    body = await _body_of(request)
    normalized = _anthropic_to_openai(body)
    model = str(body.get("model") or "")
    if not body.get("stream"):
        normalized["stream"] = False
        response = await _forward(normalized, request)
        if getattr(response, "status_code", 200) >= 400:
            return response
        try:
            payload = json.loads(response.body)
        except Exception:  # noqa: BLE001
            return response
        return JSONResponse(_openai_to_anthropic(payload, model))
    # 流式：上游逐帧 -> 转 Anthropic 事件 -> 立即下发
    return await _forward_stream_anthropic(normalized, request, model)


async def _forward_stream_anthropic(body: dict, request, model: str):
    """把上游 OpenAI chunk 流翻成 Anthropic 事件流。

    委托给 `protocol_bridge.anthropic_stream_relay`。

    本地旧实现的两个致命遗漏（都会让 agent 型客户端在工具那一步停住）：
      * `piece = delta.get("content") or delta.get("reasoning_content") or ""`
        —— **从不读 `delta["tool_calls"]`**，工具调用被静默丢弃；
      * `stop_reason` 硬编码 `"end_turn"`，客户端据此判断「助手结束了回合
        但没有调用工具」，任务直接终止。
    桥的实现输出正确的 `tool_use` 内容块
    （content_block_start -> input_json_delta -> content_block_stop）并把
    stop_reason 映射成 `tool_use`，另外补了思考块、空闲心跳与错误帧。
    """
    from admin.platform import protocol_bridge

    inner = await _forward_stream(body, request)
    if getattr(inner, "status_code", 200) >= 400:
        return inner
    return protocol_bridge.anthropic_stream_relay(inner, model, prefix="msg_loomy")


async def count_tokens(request):
    """本地估算（上游没有这个接口）。"""
    body = await _body_of(request)
    parts = []
    if isinstance(body.get("system"), str):
        parts.append(body["system"])
    for message in body.get("messages") or []:
        if isinstance(message, dict):
            content = message.get("content")
            parts.append(content if isinstance(content, str) else str(content or ""))
    text = "\n".join(parts)
    cjk = sum(1 for ch in text if "\u4e00" <= ch <= "\u9fff")
    return JSONResponse({"input_tokens": cjk + max(1, (len(text) - cjk) // 4)})


def _openai_to_responses(result: dict, model: str) -> dict:
    """OpenAI chat.completion → Responses 结构。"""
    choice = (result.get("choices") or [{}])[0]
    message = choice.get("message") or {}
    text = str(message.get("content") or "")
    usage = result.get("usage") or {}
    output = []
    if text:
        output.append({
            "type": "message",
            "id": "msg_" + str(result.get("id") or "")[:20],
            "role": "assistant",
            "content": [{"type": "output_text", "text": text}],
        })
    reasoning = str(message.get("reasoning_content") or "")
    return {
        "id": "resp_" + str(result.get("id") or "")[:20],
        "object": "response",
        "created_at": int(result.get("created") or 0),
        "model": model or result.get("model") or "",
        "status": "completed" if choice.get("finish_reason") == "stop" else "incomplete",
        "output": output,
        "output_text": text,
        "reasoning_summary": reasoning[:2000] if reasoning else "",
        "usage": {
            "input_tokens": int(usage.get("prompt_tokens") or 0),
            "output_tokens": int(usage.get("completion_tokens") or 0),
            "total_tokens": int(usage.get("total_tokens") or 0),
        },
    }


async def responses(request):
    """OpenAI Responses 协议。**流式请求真流式转发**。"""
    body = await _body_of(request)
    normalized = dict(body)
    raw_input = body.get("input")
    if isinstance(raw_input, str):
        normalized["messages"] = [{"role": "user", "content": raw_input}]
    elif isinstance(raw_input, list):
        normalized["messages"] = raw_input
    normalized.setdefault("max_tokens", body.get("max_output_tokens") or 4096)
    model = str(body.get("model") or "")
    if not body.get("stream"):
        normalized["stream"] = False
        response = await _forward(normalized, request)
        if getattr(response, "status_code", 200) >= 400:
            return response
        try:
            payload = json.loads(response.body)
        except Exception:  # noqa: BLE001
            return response
        return JSONResponse(_openai_to_responses(payload, model))
    return await _forward_stream_responses(normalized, request, model)


async def _forward_stream_responses(body: dict, request, model: str):
    """把上游流翻成 Responses 事件流（`response.output_text.delta`）。"""
    inner = await _forward_stream(body, request)
    if getattr(inner, "status_code", 200) >= 400:
        return inner

    async def relay():
        resp_id = "resp_loomy_" + str(int(time.time() * 1000))
        started = False
        async for frame in inner.body_iterator:
            text = frame.decode("utf-8", "replace") if isinstance(frame, bytes) else str(frame)
            for line in text.split("\n"):
                line = line.strip()
                if not line.startswith("data:"):
                    continue
                payload = line[5:].strip()
                if payload in ("", "[DONE]"):
                    continue
                try:
                    chunk = json.loads(payload)
                except ValueError:
                    continue
                choice = (chunk.get("choices") or [{}])[0]
                delta = choice.get("delta") or {}
                piece = delta.get("content") or delta.get("reasoning_content") or ""
                if not piece:
                    if choice.get("finish_reason") and started:
                        yield ("data: %s\n\n" % json.dumps(
                            {"type": "response.completed",
                             "response": {"id": resp_id, "object": "response",
                                          "status": "completed", "model": model}},
                            ensure_ascii=False)).encode()
                    continue
                if not started:
                    started = True
                    yield ("data: %s\n\n" % json.dumps(
                        {"type": "response.created",
                         "response": {"id": resp_id, "object": "response",
                                      "status": "in_progress", "model": model,
                                      "output": []}},
                        ensure_ascii=False)).encode()
                yield ("data: %s\n\n" % json.dumps(
                    {"type": "response.output_text.delta", "item_id": resp_id,
                     "output_index": 0, "content_index": 0, "delta": piece},
                    ensure_ascii=False)).encode()

    return StreamingResponse(
        relay(), media_type="text/event-stream",
        headers={"Cache-Control": "no-cache", "X-Accel-Buffering": "no"})


async def list_models(request):
    """/v1/models —— 只返回能调的模型；无号时回落数据库目录。"""
    from admin.db import SessionLocal

    with SessionLocal() as db:
        shared.authenticate(db, request, platform=PUBLIC)
        realm = _realm(request)
        account = shared.select_account(
            db, storage=loomy_accounts.PLATFORM, realm=realm,
            key=shared.key_row(db, request))
        if account is None:
            return JSONResponse({
                "object": "list", "data": shared.catalog_from_db(
                    db, loomy_accounts.PLATFORM),
                "note": "号池没有可用 Loomy 账号，仅返回配置目录"})
        try:
            data = loomy_accounts.ensure_token(db, account)
            models = client.fetch_models(loomy_accounts.token_of(data), realm,
                                         account_id=int(account.id or 0))
        except client.UpstreamError as exc:
            return _fail(exc)
    return JSONResponse({"object": "list", "data": models})


async def balance(request):
    from admin.db import SessionLocal

    with SessionLocal() as db:
        shared.authenticate(db, request, platform=PUBLIC)
        realm = _realm(request)
        account = shared.select_account(
            db, storage=loomy_accounts.PLATFORM, realm=realm,
            key=shared.key_row(db, request))
        if account is None:
            return JSONResponse({"platform": PUBLIC, "realm": realm,
                                 "reachable": False, "models": 0,
                                 "note": "号池没有可用账号"}, status_code=503)
        try:
            data = loomy_accounts.ensure_token(db, account)
            quota = client.fetch_quota(loomy_accounts.token_of(data), realm,
                                       account_id=int(account.id or 0))
        except client.UpstreamError as exc:
            return _fail(exc)
    return JSONResponse({"platform": PUBLIC, "realm": realm, **quota})


_HANDLERS = {
    "/v1/chat/completions": chat_completions,
    "/v1/messages": messages,
    "/v1/messages/count_tokens": count_tokens,
    "/v1/responses": responses,
    "/v1/models": list_models,
    "/v1/balance": balance,
}


async def dispatch(request, path: str):
    """`PlatformDispatchMiddleware` 的唯一入口（**必须 async**）。"""
    handler = _HANDLERS.get(path)
    if handler is None:
        return JSONResponse(
            {"error": {"message": "Loomy 不支持 %s" % path,
                        "type": "invalid_request_error"}},
            status_code=404)
    try:
        return await handler(request)
    except shared.PlatformRejected as exc:
        if path in ("/v1/messages", "/v1/messages/count_tokens"):
            return exc.anthropic()
        return exc.openai()
