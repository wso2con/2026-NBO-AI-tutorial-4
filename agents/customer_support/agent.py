"""Customer Support Agent: general queries, account info, loan status.

FastAPI service exposing POST /chat.

LLM and MCP each have two modes, switched purely by which env vars are
set — no code change, no separate "stage" build:

- LLM: direct OpenAI (OPENAI_API_KEY) vs. Agent Manager's LLM gateway
  (LLM_GATEWAY_BASE_URL/LLM_GATEWAY_API_KEY). See _build_llm().
- MCP: direct, ungoverned connection (MCP_SERVER_URL) vs. Agent Manager's
  MCP gateway, in one of two auth modes: a shared API Key
  (MCP_GATEWAY_URL + MCP_GATEWAY_API_KEY, no per-agent identity) or this
  agent's own AgentID client-credentials (MCP_GATEWAY_URL + AMP_AGENTID_*,
  per-agent tool policy). See _build_mcp_client(). Direct mode loads every
  tool with no restriction — this agent can call open_account/
  transfer_money even though it's outside its intended scope. AgentID
  gateway mode lets Agent Manager enforce per-agent tool policy
  server-side (e.g. denying those same calls for this agent's identity) —
  we don't hardcode any of that here.
"""

from __future__ import annotations

import base64
import hashlib
import json
import logging
import os
from contextlib import asynccontextmanager
from typing import Any

import requests
from dotenv import load_dotenv
from fastapi import FastAPI, Request
from fastapi.middleware.cors import CORSMiddleware
from langchain_core.messages import AIMessage, BaseMessage, HumanMessage
from langchain_mcp_adapters.client import MultiServerMCPClient
from langchain_openai import ChatOpenAI
from langgraph.prebuilt import create_react_agent
from pydantic import BaseModel

from instrumentation import init_instrumentation, instrument_tool
from system_prompt import SYSTEM_PROMPT

load_dotenv()
init_instrumentation()

logging.basicConfig(level=logging.INFO, format="%(asctime)s %(levelname)s %(message)s")
log = logging.getLogger("customer-support-agent")

LLM_MODEL = os.environ.get("LLM_MODEL", "gpt-4o-mini")

GOVERNANCE_DENIAL_MESSAGE = (
    "That action isn't available to me — it may be restricted by policy, or "
    "something else went wrong. Please try again or contact an Account Assistant."
)

SESSIONS: dict[str, list[BaseMessage]] = {}


def _build_llm() -> ChatOpenAI:
    """Build a ChatOpenAI client.

    Local verification mode: if LLM_GATEWAY_BASE_URL is unset, call OpenAI
    directly using OPENAI_API_KEY (standard Authorization: Bearer auth) —
    no Agent Manager involved. Set LLM_GATEWAY_BASE_URL to switch back to
    gateway mode.

    Gateway mode: the gateway authenticates via an `API-Key` header, not
    `Authorization: Bearer`. The openai SDK sets `Authorization` from
    `api_key` by default and does not stop just because `API-Key` is also
    present in `default_headers`, so `Authorization` must be blanked
    explicitly. The SDK also rejects an empty `api_key` as "missing
    credentials" before `default_headers` ever applies, hence the
    non-empty sentinel value.
    """
    gateway_base_url = os.environ.get("LLM_GATEWAY_BASE_URL")
    if not gateway_base_url:
        return ChatOpenAI(model=LLM_MODEL, api_key=os.environ["OPENAI_API_KEY"])

    gateway_key = os.environ["LLM_GATEWAY_API_KEY"]
    return ChatOpenAI(
        model=LLM_MODEL,
        base_url=gateway_base_url,
        api_key="unused",
        default_headers={"API-Key": gateway_key, "Authorization": ""},
    )


def _mint_agentid_token(mcp_gateway_url: str) -> str:
    """Mint an AgentID access token via OAuth 2.0 client-credentials, scoped
    to this specific MCP server via the `resource` parameter (RFC 8707) -
    the tool's URL is the resource, so it must be known before minting the
    token, not just before calling the tool. This agent has its own
    AMP_AGENTID_CLIENT_ID/SECRET, so it mints its own token and Agent
    Manager enforces tool policy per that identity, not per a shared secret.
    """
    client_id = os.environ["AMP_AGENTID_CLIENT_ID"]
    client_secret = os.environ["AMP_AGENTID_CLIENT_SECRET"]
    token_endpoint = os.environ["AMP_AGENTID_TOKEN_ENDPOINT"]
    scopes = os.environ.get("AMP_AGENTID_SCOPES")

    data = {"grant_type": "client_credentials", "resource": mcp_gateway_url}
    if scopes:
        data["scope"] = scopes

    token_response = requests.post(
        token_endpoint,
        auth=(client_id, client_secret),
        data=data,
        timeout=30,
    )
    token_response.raise_for_status()
    return token_response.json()["access_token"]


def _build_mcp_client() -> MultiServerMCPClient:
    """Build an MCP client.

    Direct mode: if MCP_GATEWAY_URL is unset, connect straight to
    MCP_SERVER_URL with no authentication - no Agent Manager involved, no
    tool-access policy. Every tool the server exposes is available.

    Gateway mode, API Key: if MCP_GATEWAY_URL and MCP_GATEWAY_API_KEY are
    both set, calls go through Agent Manager's MCP gateway authenticated
    with a shared `x-api-key` header - matching the MCP server's default
    API Key security scheme (note: this is a different header name than
    the LLM gateway's `API-Key`). No per-agent identity, so no per-agent
    tool policy either - every agent using the same key gets the same
    access.

    Gateway mode, AgentID: if MCP_GATEWAY_URL is set and
    MCP_GATEWAY_API_KEY is not, calls go through Agent Manager's MCP
    gateway authenticated with this agent's own AgentID client-credentials
    as a Bearer token - see _mint_agentid_token(). This is what lets Agent
    Manager enforce tool policy per this agent's own identity.
    """
    mcp_gateway_url = os.environ.get("MCP_GATEWAY_URL")
    if not mcp_gateway_url:
        return MultiServerMCPClient(
            {
                "accounts": {
                    "url": os.environ["MCP_SERVER_URL"],
                    "transport": "streamable_http",
                }
            }
        )

    api_key = os.environ.get("MCP_GATEWAY_API_KEY")
    headers = (
        {"x-api-key": api_key}
        if api_key
        else {"Authorization": f"Bearer {_mint_agentid_token(mcp_gateway_url)}"}
    )
    return MultiServerMCPClient(
        {
            "accounts": {
                "url": mcp_gateway_url,
                "transport": "streamable_http",
                "headers": headers,
            }
        }
    )


_agent = None


async def _get_agent():
    global _agent
    if _agent is None:
        client = _build_mcp_client()
        tools = [instrument_tool(t) for t in await client.get_tools()]
        _agent = create_react_agent(_build_llm(), tools=tools, prompt=SYSTEM_PROMPT)
    return _agent


@asynccontextmanager
async def lifespan(app: FastAPI):
    await _get_agent()
    log.info("READY %s", _ready_payload())
    yield


app = FastAPI(title="ACME Bank Customer Support Agent", lifespan=lifespan)
app.add_middleware(
    CORSMiddleware,
    allow_origins=["*"],
    allow_methods=["GET", "POST", "OPTIONS"],
    allow_headers=["*"],
)


class ChatRequest(BaseModel):
    message: str
    session_id: str
    context: dict[str, Any] | None = None


class ChatResponse(BaseModel):
    response: str


def _ready_payload() -> dict[str, Any]:
    return {
        "ok": True,
        "model": LLM_MODEL,
        "llm_governed": bool(os.environ.get("LLM_GATEWAY_BASE_URL")),
        "mcp_governed": bool(os.environ.get("MCP_GATEWAY_URL")),
        "agent": "customer_support",
        "port": 8000,
    }


@app.get("/")
def root() -> dict[str, Any]:
    return {
        "service": "ACME Bank Customer Support Agent",
        "tip": "POST /chat with {message, session_id, context}. GET /health for status.",
    }


@app.get("/health")
def health() -> dict[str, Any]:
    return _ready_payload()


# Confirmed via header-name discovery logging: the gateway forwards the
# caller's OAuth identity token in this header (not `Authorization`).
IDENTITY_HEADER = "x-forwarded-authorization"


def _decode_jwt_claims(token: str) -> dict[str, Any] | None:
    """Decode a JWT's payload claims without verifying the signature.

    This is for logging/debugging identity only - never use the returned
    claims to make an authorization decision, since they're unverified.
    """
    parts = token.removeprefix("Bearer ").strip().split(".")
    if len(parts) != 3:
        return None
    payload = parts[1]
    padded = payload + "=" * (-len(payload) % 4)
    try:
        return json.loads(base64.urlsafe_b64decode(padded))
    except (ValueError, json.JSONDecodeError):
        return None


def _log_identity_header(request: Request, sid: str) -> None:
    """Log the caller identity (username, org_id) from the Asgardeo access
    token forwarded in x-forwarded-authorization. Claims are unverified
    (no signature check here) - fine for log correlation, not for
    authorization decisions. Never logs the raw token itself.
    """
    token = request.headers.get(IDENTITY_HEADER)
    if not token:
        log.info("session=%s no %s header present", sid, IDENTITY_HEADER)
        return

    claims = _decode_jwt_claims(token)
    if claims is None:
        log.warning("session=%s %s present but not a decodable JWT", sid, IDENTITY_HEADER)
        return

    log.info(
        "session=%s caller username=%s org_id=%s",
        sid, claims.get("username"), claims.get("org_id"),
    )


def _leaf_causes(exc: BaseException) -> list[BaseException]:
    """Flatten a (possibly nested) ExceptionGroup down to its leaf exceptions.

    agent.ainvoke() runs MCP tool calls via asyncio.TaskGroup internally
    (langgraph / langchain-mcp-adapters), so a single tool failure —
    including an Agent Manager gateway denial — surfaces here wrapped in
    an ExceptionGroup rather than as the original exception.
    """
    if isinstance(exc, BaseExceptionGroup):
        leaves: list[BaseException] = []
        for sub in exc.exceptions:
            leaves.extend(_leaf_causes(sub))
        return leaves
    return [exc]


def _final_text(messages: list[BaseMessage]) -> str:
    for msg in reversed(messages):
        if isinstance(msg, AIMessage):
            content = msg.content
            if isinstance(content, str):
                return content.strip()
            if isinstance(content, list):
                parts = [
                    block.get("text", "") if isinstance(block, dict) else str(block)
                    for block in content
                ]
                return "".join(parts).strip()
    return ""


@app.post("/chat", response_model=ChatResponse)
async def chat(req: ChatRequest, request: Request) -> ChatResponse:
    if not req.message.strip():
        return ChatResponse(response="How can I help you today?")

    sid = req.session_id or "_anonymous_"
    _log_identity_header(request, sid)
    turn: list[BaseMessage] = [HumanMessage(content=req.message)]
    history = SESSIONS.get(sid, []) + turn

    try:
        agent = await _get_agent()
        result = await agent.ainvoke({"messages": history})
        history = result["messages"]
        reply = _final_text(history) or "I'm not sure how to help with that."
    except Exception as e:
        # Exact error shape for an Agent Manager MCP policy denial is
        # unverified — this is the catch-all a denied open_account/
        # transfer_money call is expected to land in when MCP_GATEWAY_URL
        # is set. In direct mode (no gateway), this instead just means a
        # real error reaching the MCP server.
        #
        # agent.ainvoke() fans out MCP calls via asyncio.TaskGroup
        # internally, so failures arrive wrapped in an ExceptionGroup —
        # unwrap it so the log shows the real cause(s), not just
        # "1 sub-exception (...)".
        causes = _leaf_causes(e)
        cause_summary = "; ".join(f"{type(c).__name__}: {c}" for c in causes)
        if os.environ.get("MCP_GATEWAY_URL"):
            log.warning(
                "session=%s possible governance denial or error: %s",
                sid, cause_summary, exc_info=e,
            )
            reply = GOVERNANCE_DENIAL_MESSAGE
        else:
            log.exception("session=%s error: %s", sid, cause_summary)
            reply = "I'm having trouble reaching our systems. Please try again in a moment."

    SESSIONS[sid] = history
    return ChatResponse(response=reply)
