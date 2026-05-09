import hashlib
import json
import time
import uuid
from datetime import datetime, timezone
from typing import Any, Dict, List, Optional, TypedDict

from langgraph.graph import END, START, StateGraph

from backend.core.database import AsyncSessionLocal
from backend.core.exceptions import ModelGatewayException
from backend.core.logging import logger
from backend.core.security import decrypt_api_key
from backend.models.constants import ActionType, ArcErrorCode, ExecutionState, ExecutionStatus, TerminationReason
from backend.models.schemas import (
    Action,
    AuthContext,
    ConversationHistoryMessage,
    ExecutionErrorModel,
    ExecutionResult,
    ExecutionStepLogContract,
    FinalAnswerPolicyDecision,
    GatewayResponse,
    GatewayToolCall,
    IntentClassificationResult,
    Message,
    ModelConfig,
    Observation,
    PolicyGateDecision,
    ReactStep,
    RetrievalPolicy,
    TokenUsage,
    ToolObservation,
    ToolObservationError,
)
from backend.services.agent_runtime_assembler import ResolvedAgentRuntime
from backend.services.agent_service import agent_service
from backend.services.context_budget_manager import context_budget_manager
from backend.services.knowledge_service import knowledge_service
from backend.services.policy_gate import policy_gate
from backend.services.retrieval_policy_service import retrieval_policy_service
from backend.services.tool_need_classifier import tool_need_classifier
from backend.services.tool_scope_resolver import tool_scope_resolver


class AgentExecutionState(TypedDict):
    execution_id: uuid.UUID
    request_id: str
    agent_id: str
    user_input: str
    conversation_history: List[Message]
    messages: List[Message]
    available_tools: List[Dict[str, Any]]
    all_available_tools: List[Dict[str, Any]]
    tool_catalog_entries: List[Dict[str, Any]]
    tool_names: List[str]
    bound_tool_ids: List[str]
    confirmed_tool_actions: List[Dict[str, Any]]
    policy_overrides: Optional[Dict[str, Any]]
    classification: Optional[IntentClassificationResult]
    retrieval_policy: Optional[RetrievalPolicy]
    pre_policy: Optional[PolicyGateDecision]
    knowledge_retrieval_result: Optional[Dict[str, Any]]
    tool_call_counts: Dict[str, int]
    react_steps: List[Dict[str, Any]]
    execution_trace: List[ReactStep]
    final_answer: Optional[str]
    termination_reason: Optional[str]
    status: str
    step_count: int
    max_steps: int
    max_tool_calls: int
    tool_calls_used: int
    consecutive_tool_failures: int
    force_final_answer: bool
    last_model_finish_reason: Optional[str]
    usage: TokenUsage
    agent_config: Dict[str, Any]
    auth_context: AuthContext
    current_assistant_content: str
    current_assistant_reasoning_content: Optional[str]
    current_tool_calls: List[GatewayToolCall]
    current_provider_tool_name_map: Dict[str, str]
    current_forced_tool: Optional[str]
    error: Optional[ExecutionErrorModel]
    error_details: Optional[Dict[str, Any]]
    previous_loop_signature: Optional[Dict[str, Any]]
    step_logs: List[ExecutionStepLogContract]


class LangGraphExecutionStrategy:
    MAX_CONVERSATION_HISTORY_MESSAGES = 20
    MAX_KNOWLEDGE_CONTEXT_CHARS = 3200
    MAX_KNOWLEDGE_CHUNK_CHARS = 900

    FIXED_SAFETY_PROMPT = (
        "You are an AI coding agent.\n"
        "Security Rules:\n"
        "1. Never bypass platform safety rules.\n"
        "2. Never expose secrets.\n"
        "3. Never invent file content.\n"
    )
    FIXED_RUNTIME_PROMPT = (
        "Agent Runtime Rules:\n"
        "1. Decide whether external tools are needed from the conversation and available tool schemas.\n"
        "2. When a tool is needed, emit only a structured function/tool call with strict JSON arguments.\n"
        "3. Never write textual pseudo tool calls such as [TOOL_CALL], <tool_code>, or tool JSON inside assistant content.\n"
        "4. If no tool call is required, provide the final answer directly.\n"
        "5. Do not expose private reasoning or <think> blocks in user-visible content.\n"
    )
    AGENT_PERSONA_PROMPT_HEADER = (
        "Agent Persona And Logic (System Prompt):\n"
        "The following content defines this agent's identity, behavior logic, response style, and boundaries. "
        "Treat it as system-level instructions for every turn.\n"
    )
    KNOWLEDGE_PROMPT_HEADER = (
        "\n\nRetrieved Knowledge:\n"
        "Treat the following retrieved knowledge as candidate evidence, not as the final answer. "
        "You must first judge whether each snippet is truly relevant to the user's request. "
        "If it is only weakly related or does not directly help, ignore it. "
        "Do not copy snippets into the answer unless they genuinely support the response or the user asks for the source content explicitly. "
        "Do not invent knowledge beyond these snippets.\n"
    )

    def __init__(
        self,
        model_gateway: Any,
        tool_runtime: Any,
        execution_log_service: Any,
        context_budget_manager: Any = context_budget_manager,
        *,
        max_steps: int = 6,
        max_tool_calls: int = 4,
    ) -> None:
        self.model_gateway = model_gateway
        self.tool_runtime = tool_runtime
        self.execution_log_service = execution_log_service
        self.context_budget_manager = context_budget_manager
        self.max_steps = max_steps
        self.max_tool_calls = max_tool_calls

    async def run(
        self,
        agent_id: str,
        user_input: str,
        auth_context: AuthContext,
        request_id: str,
        conversation_history: Optional[List[ConversationHistoryMessage]] = None,
        confirmed_tool_actions: Optional[List[Dict[str, Any]]] = None,
        policy_overrides: Optional[Dict[str, Any]] = None,
        execution_id: Optional[uuid.UUID] = None,
        start_log: bool = True,
    ) -> ExecutionResult:
        execution_id = execution_id or uuid.uuid4()

        async with AsyncSessionLocal() as db:
            agent = await agent_service.get_agent_raw(db, uuid.UUID(agent_id))
        if agent is None:
            raise ValueError(f"Agent not found: {agent_id}")

        agent_cfg = agent.config or {}
        if not agent_cfg.get("llm_model_name"):
            raise ValueError("Agent model config is incomplete")

        runtime = await self.tool_runtime.resolve_agent_runtime(
            agent_id=str(agent.id),
            agent_config=agent_cfg,
            user_input=user_input,
        )

        if start_log:
            await self.execution_log_service.start_execution(
                execution_id=execution_id,
                agent_id=agent.id,
                team_id=uuid.UUID(auth_context.team_id),
                request_id=request_id,
                initial_state=ExecutionState.INIT.value,
                input_data=user_input,
            )

        preflight_failure = await self._preflight_runtime(
            execution_id=execution_id,
            runtime=runtime,
        )
        if preflight_failure is not None:
            return preflight_failure

        available_tools_count = len(runtime.tool_schemas)
        available_tool_names = runtime.resolved_tool_names
        logger.bind(
            event="execution_debug_start",
            agent_id=str(agent.id),
            supports_tools=runtime.supports_tools,
            tools_count=available_tools_count,
            tool_names=available_tool_names,
            model_name=agent_cfg.get("llm_model_name", ""),
            unresolved_tools=runtime.unresolved_tools,
            binding_drift=runtime.binding_drift,
            resolution_source=runtime.resolution_source,
        ).info("Execution started")

        graph = self._build_graph()
        final_state = await graph.ainvoke(
            {
                "execution_id": execution_id,
                "request_id": request_id,
                "agent_id": str(agent.id),
                "user_input": user_input,
                "conversation_history": self._normalize_conversation_history(conversation_history),
                "messages": [],
                "available_tools": runtime.tool_schemas,
                "all_available_tools": runtime.tool_schemas,
                "tool_catalog_entries": runtime.tool_catalog_entries,
                "tool_names": [],
                "bound_tool_ids": runtime.bound_tool_ids or runtime.resolved_tool_names,
                "confirmed_tool_actions": confirmed_tool_actions or [],
                "policy_overrides": policy_overrides,
                "classification": None,
                "retrieval_policy": None,
                "pre_policy": None,
                "knowledge_retrieval_result": None,
                "tool_call_counts": {},
                "react_steps": [],
                "execution_trace": [],
                "final_answer": None,
                "termination_reason": None,
                "status": ExecutionStatus.PENDING.value,
                "step_count": 0,
                "max_steps": runtime.max_steps,
                "max_tool_calls": self.max_tool_calls,
                "tool_calls_used": 0,
                "consecutive_tool_failures": 0,
                "force_final_answer": False,
                "last_model_finish_reason": None,
                "usage": TokenUsage(),
                "agent_config": agent_cfg,
                "auth_context": auth_context,
                "current_assistant_content": "",
                "current_assistant_reasoning_content": None,
                "current_tool_calls": [],
                "current_provider_tool_name_map": {},
                "current_forced_tool": None,
                "error": None,
                "error_details": None,
                "previous_loop_signature": None,
                "step_logs": [],
            }
        )

        final_status = ExecutionStatus(final_state["status"])
        termination_reason_value = final_state["termination_reason"] or TerminationReason.FAILED.value
        termination_reason = TerminationReason(termination_reason_value)
        engine_final_state = ExecutionState.FINISHED if final_status == ExecutionStatus.SUCCEEDED else ExecutionState.TERMINATED

        await self.execution_log_service.complete_execution(
            execution_id=execution_id,
            status=final_status.value,
            final_state=engine_final_state.value,
            termination_reason=termination_reason.value,
            steps_used=len(final_state["react_steps"]),
            final_answer=final_state["final_answer"],
            total_token_usage=final_state["usage"],
            error=final_state["error"],
            error_details=final_state["error_details"],
            step_logs=final_state["step_logs"],
        )

        return ExecutionResult(
            execution_id=execution_id,
            final_state=engine_final_state,
            steps_used=len(final_state["react_steps"]),
            termination_reason=termination_reason,
            execution_trace=final_state["execution_trace"],
            final_answer=final_state["final_answer"],
            total_token_usage=final_state["usage"],
            status=final_status,
            summary=final_state["final_answer"] or "",
            artifacts=[],
            error=final_state["error"],
            step_logs=final_state["step_logs"],
        )

    async def _preflight_runtime(
        self,
        *,
        execution_id: uuid.UUID,
        runtime: ResolvedAgentRuntime,
    ) -> Optional[ExecutionResult]:
        if runtime.tool_schemas and not runtime.supports_tools:
            error = ExecutionErrorModel(
                error_code=ArcErrorCode.MODEL_CAPABILITY_MISMATCH.value,
                error_source="runtime",
                error_message="Model does not support tool calling.",
            )
            return await self._fail_before_graph(
                execution_id=execution_id,
                final_answer="执行失败：模型不支持工具调用。",
                error=error,
            )

        if runtime.unavailable_requested_tools:
            missing = ", ".join(runtime.unavailable_requested_tools)
            error = ExecutionErrorModel(
                error_code=ArcErrorCode.INVALID_TOOL_CALL.value,
                error_source="runtime",
                error_message=f"Requested tools are not bound to the agent or do not exist: {missing}",
            )
            return await self._fail_before_graph(
                execution_id=execution_id,
                final_answer=f"执行失败：当前 Agent 未绑定这些工具或工具不存在：{missing}。",
                error=error,
            )

        if runtime.supports_tools and (runtime.configured_tools or runtime.requested_tool_names) and not runtime.tool_schemas:
            details: List[str] = []
            if runtime.unresolved_tools:
                details.append(f"unresolved={','.join(runtime.unresolved_tools)}")
            if runtime.binding_drift:
                details.append(f"binding_drift={json.dumps(runtime.binding_drift, ensure_ascii=False)}")
            error = ExecutionErrorModel(
                error_code=ArcErrorCode.INVALID_TOOL_CALL.value,
                error_source="runtime",
                error_message=(
                    "Agent requested tool usage but resolved runtime tool set is empty."
                    + (f" ({'; '.join(details)})" if details else "")
                ),
            )
            return await self._fail_before_graph(
                execution_id=execution_id,
                final_answer="执行失败：Agent 已声明工具，但运行时未解析到任何可执行工具。",
                error=error,
            )

        return None

    async def _fail_before_graph(
        self,
        *,
        execution_id: uuid.UUID,
        final_answer: str,
        error: ExecutionErrorModel,
    ) -> ExecutionResult:
        await self.execution_log_service.complete_execution(
            execution_id=execution_id,
            status=ExecutionStatus.FAILED.value,
            final_state=ExecutionState.TERMINATED.value,
            termination_reason=TerminationReason.FAILED.value,
            steps_used=0,
            final_answer=final_answer,
            total_token_usage=TokenUsage(),
            error=error,
            error_details=None,
        )
        return ExecutionResult(
            execution_id=execution_id,
            final_state=ExecutionState.TERMINATED,
            steps_used=0,
            termination_reason=TerminationReason.FAILED,
            execution_trace=[],
            final_answer=final_answer,
            total_token_usage=TokenUsage(),
            status=ExecutionStatus.FAILED,
            summary=final_answer,
            artifacts=[],
            error=error,
            step_logs=[],
        )

    def _build_graph(self):
        graph = StateGraph(AgentExecutionState)
        graph.add_node("prepare_context", self.prepare_context)
        graph.add_node("call_model", self.call_model)
        graph.add_node("execute_tools", self.execute_tools)
        graph.add_node("finalize_answer", self.finalize_answer)
        graph.add_node("terminate_by_limit", self.terminate_by_limit)
        graph.add_edge(START, "prepare_context")
        graph.add_conditional_edges(
            "prepare_context",
            self.route_after_prepare_context,
            {
                "call_model": "call_model",
                "finalize_answer": "finalize_answer",
                "terminate_by_limit": "terminate_by_limit",
            },
        )
        graph.add_conditional_edges(
            "call_model",
            self.route_after_model,
            {
                "execute_tools": "execute_tools",
                "finalize_answer": "finalize_answer",
                "terminate_by_limit": "terminate_by_limit",
            },
        )
        graph.add_edge("execute_tools", "call_model")
        graph.add_edge("finalize_answer", END)
        graph.add_edge("terminate_by_limit", END)
        return graph.compile()

    def route_after_prepare_context(self, state: AgentExecutionState) -> str:
        if state["status"] in {ExecutionStatus.FAILED.value, ExecutionStatus.TERMINATED.value}:
            return "terminate_by_limit"
        if state["current_assistant_content"].strip() or state["final_answer"]:
            return "finalize_answer"
        return "call_model"

    async def prepare_context(self, state: AgentExecutionState) -> Dict[str, Any]:
        agent_cfg = state["agent_config"]
        all_tool_names = self._extract_tool_names(state["all_available_tools"])
        agent_persona_prompt = self._extract_agent_persona_prompt(agent_cfg)
        classification = tool_need_classifier.classify(
            state["user_input"],
            agent_config=agent_cfg,
            tool_catalog_summary=all_tool_names,
        )
        retrieval_policy = retrieval_policy_service.resolve(classification)
        pre_policy = policy_gate.evaluate_pre_policy(
            classification=classification,
            retrieval_policy=retrieval_policy,
            bound_tool_ids=state["bound_tool_ids"],
            tool_catalog_entries=state["tool_catalog_entries"],
            confirmed_tool_actions=state["confirmed_tool_actions"],
        )
        allowed_tools = tool_scope_resolver.resolve(
            classification=classification,
            tool_schemas=state["all_available_tools"],
            tool_catalog_entries=state["tool_catalog_entries"],
            confirmed_tool_actions=state["confirmed_tool_actions"],
        )
        tool_names = self._extract_tool_names(allowed_tools)
        step_logs = list(state["step_logs"])
        self._append_step_log(
            step_logs=step_logs,
            execution_id=state["execution_id"],
            step_index=self._next_step_log_index(step_logs),
            phase="intent_classification",
            tool_id=None,
            status="success",
            payload={
                **classification.model_dump(),
                "input_preview": state["user_input"][:300],
                "classifier_version": tool_need_classifier.VERSION,
            },
        )
        self._append_step_log(
            step_logs=step_logs,
            execution_id=state["execution_id"],
            step_index=self._next_step_log_index(step_logs),
            phase="pre_policy_gate",
            tool_id=None,
            status="success",
            payload={
                **pre_policy.model_dump(),
                "bound_tool_ids": state["bound_tool_ids"],
                "tool_risk_metadata": self._tool_risk_metadata_for_log(state["tool_catalog_entries"]),
                "policy_version": policy_gate.VERSION,
            },
        )

        if pre_policy.requires_user_confirmation:
            final_answer = "该操作需要用户确认后才能继续执行。请确认具体工具动作与参数后重试。"
            self._append_step_log(
                step_logs=step_logs,
                execution_id=state["execution_id"],
                step_index=self._next_step_log_index(step_logs),
                phase="tool_policy_gate",
                tool_id=None,
                status="error",
                payload={
                    "gate_name": "PrePolicyGate",
                    "decision": "blocked",
                    "reason_code": ArcErrorCode.TOOL_CONFIRMATION_REQUIRED.value,
                    "reason_message": "High-risk tool intent requires user confirmation.",
                    "safe_fallback": final_answer,
                    "policy_version": policy_gate.VERSION,
                },
            )
            return {
                "available_tools": [],
                "tool_names": [],
                "classification": classification,
                "retrieval_policy": retrieval_policy,
                "pre_policy": pre_policy,
                "step_logs": step_logs,
                "current_assistant_content": final_answer,
                "final_answer": final_answer,
                "status": ExecutionStatus.RUNNING.value,
            }

        knowledge_retrieval = await self._retrieve_knowledge_details(state, retrieval_policy=retrieval_policy)
        knowledge_context = str(knowledge_retrieval.get("context", ""))
        system_prompt = (
            f"{self.FIXED_SAFETY_PROMPT}\n"
            f"{self.FIXED_RUNTIME_PROMPT}\n"
            f"{self.AGENT_PERSONA_PROMPT_HEADER}"
            f"{agent_persona_prompt}"
        )
        if not allowed_tools:
            system_prompt = (
                f"{system_prompt}\n"
                "Tool Availability:\n"
                "No executable tool schemas are attached to this turn. Do not attempt or describe tool calls. "
                "If the user asks for information that requires external tools, say the tool is unavailable in this run.\n"
            )
        if classification.intent_type == "KB_REQUIRED" and knowledge_retrieval.get("matched"):
            system_prompt = (
                f"{system_prompt}\n"
                "Knowledge Grounding Rules:\n"
                "The user request requires retrieved knowledge. Answer only from the retrieved evidence. "
                "Include the provided source label in the final answer. If the evidence is insufficient, say so explicitly.\n"
            )
        if knowledge_context:
            system_prompt = f"{system_prompt}{self.KNOWLEDGE_PROMPT_HEADER}{knowledge_context}"
        self._append_step_log(
            step_logs=step_logs,
            execution_id=state["execution_id"],
            step_index=self._next_step_log_index(step_logs),
            phase="knowledge_retrieval",
            tool_id=None,
            status="success",
            payload=knowledge_retrieval,
        )
        retrieval_gate_payload = self._evaluate_retrieval_gate_payload(
            classification=classification,
            retrieval_policy=retrieval_policy,
            retrieval_result=knowledge_retrieval,
        )
        self._append_step_log(
            step_logs=step_logs,
            execution_id=state["execution_id"],
            step_index=self._next_step_log_index(step_logs),
            phase="retrieval_policy_gate",
            tool_id=None,
            status="error" if retrieval_gate_payload.get("must_return_without_model") else "success",
            payload=retrieval_gate_payload,
        )
        if retrieval_gate_payload.get("must_return_without_model"):
            final_answer = str(retrieval_gate_payload["safe_fallback"])
            return {
                "available_tools": allowed_tools,
                "messages": [
                    Message(role="system", content=system_prompt),
                    *state["conversation_history"],
                    Message(role="user", content=state["user_input"]),
                ],
                "tool_names": tool_names,
                "classification": classification,
                "retrieval_policy": retrieval_policy,
                "pre_policy": pre_policy,
                "knowledge_retrieval_result": knowledge_retrieval,
                "step_logs": step_logs,
                "current_assistant_content": final_answer,
                "final_answer": final_answer,
                "error": ExecutionErrorModel(
                    error_code=ArcErrorCode.KNOWLEDGE_REQUIRED_BUT_NOT_FOUND.value,
                    error_source="knowledge_policy",
                    error_message="Required knowledge was not found.",
                ),
                "status": ExecutionStatus.RUNNING.value,
            }
        return {
            "available_tools": allowed_tools,
            "messages": [
                Message(role="system", content=system_prompt),
                *state["conversation_history"],
                Message(role="user", content=state["user_input"]),
            ],
            "tool_names": tool_names,
            "classification": classification,
            "retrieval_policy": retrieval_policy,
            "pre_policy": pre_policy,
            "knowledge_retrieval_result": knowledge_retrieval,
            "step_logs": step_logs,
            "status": ExecutionStatus.RUNNING.value,
        }

    async def call_model(self, state: AgentExecutionState) -> Dict[str, Any]:
        if state["step_count"] >= state["max_steps"]:
            return {
                "status": ExecutionStatus.TERMINATED.value,
                "termination_reason": TerminationReason.MAX_STEPS_REACHED.value,
                "final_answer": "执行终止：达到最大步数限制。",
                "last_model_finish_reason": "max_steps",
            }

        agent_cfg = state["agent_config"]
        runtime_cfg = agent_cfg.get("runtime_config") or {}
        model_config = ModelConfig(
            model=agent_cfg.get("llm_model_name", ""),
            temperature=runtime_cfg.get("temperature", 0.7),
            max_tokens=runtime_cfg.get("max_tokens"),
        )
        call_tools = [] if state["force_final_answer"] else state["available_tools"]
        forced_tool_name = None
        tool_choice = None
        step_logs = list(state["step_logs"])
        model_step_index = self._next_step_log_index(step_logs)
        context_budget = self.context_budget_manager.fit(
            messages=state["messages"],
            tools=call_tools,
            model_name=model_config.model,
            max_completion_tokens=model_config.max_tokens,
            runtime_config=runtime_cfg,
        )
        context_budget_report = context_budget.report.model_dump()
        effective_max_tokens = model_config.max_tokens
        if isinstance(model_config.max_tokens, int) and model_config.max_tokens > context_budget.report.reserved_completion_tokens:
            effective_max_tokens = context_budget.report.reserved_completion_tokens
        provider_model_config = model_config.model_copy(update={"max_tokens": effective_max_tokens})

        logger.bind(
            event="execution_debug_before_model_call",
            execution_id=str(state["execution_id"]),
            step_index=model_step_index,
            messages_count=len(context_budget.messages),
            original_messages_count=len(state["messages"]),
            tools_attached=bool(context_budget.tools),
            tool_names=state["tool_names"] if context_budget.tools else [],
            forced_tool_name=forced_tool_name,
            context_budget=context_budget_report,
        ).info("Calling model gateway")

        try:
            streamed_content_parts: List[str] = []
            last_stream_update_at = 0.0

            async def update_streaming_content(delta: str) -> None:
                nonlocal last_stream_update_at
                streamed_content_parts.append(delta)
                now = time.monotonic()
                content = "".join(streamed_content_parts)
                content, _events = policy_gate.sanitize_final_answer(content)
                if now - last_stream_update_at < 0.2 and len(delta) < 24:
                    return
                last_stream_update_at = now
                await self.execution_log_service.update_streaming_answer(
                    execution_id=state["execution_id"],
                    content=content,
                )

            model_resp: GatewayResponse = await self.model_gateway.call(
                messages=context_budget.messages,
                tools=context_budget.tools,
                config=provider_model_config,
                provider_url=agent_cfg.get("llm_provider_url", ""),
                api_key=decrypt_api_key(agent_cfg.get("llm_api_key_encrypted", "")),
                tool_choice=tool_choice,
                on_content_delta=update_streaming_content,
            )
            if streamed_content_parts:
                streamed_content, _events = policy_gate.sanitize_final_answer(
                    model_resp.content or "".join(streamed_content_parts)
                )
                await self.execution_log_service.update_streaming_answer(
                    execution_id=state["execution_id"],
                    content=streamed_content,
                )
        except ModelGatewayException as exc:
            error_payload = (exc.data or {}).get("error", {})
            raw_error_details = error_payload.get("details")
            error_details = raw_error_details if isinstance(raw_error_details, dict) else None
            error = ExecutionErrorModel(
                error_code=str(error_payload.get("code", ArcErrorCode.NETWORK_ERROR.value)),
                error_source="gateway",
                error_message=str(error_payload.get("message", exc.message)),
            )
            self._append_step_log(
                step_logs=step_logs,
                execution_id=state["execution_id"],
                step_index=model_step_index,
                phase="model_call",
                tool_id=None,
                status="error",
                payload={
                    "model": model_config.model,
                    "temperature": model_config.temperature,
                    "max_tokens": provider_model_config.max_tokens,
                    "requested_max_tokens": model_config.max_tokens,
                    "messages_count": len(context_budget.messages),
                    "original_messages_count": len(state["messages"]),
                    "tools_attached": bool(context_budget.tools),
                    "available_tool_names": state["tool_names"] if context_budget.tools else [],
                    "forced_tool_name": forced_tool_name,
                    "finish_reason": "error",
                    "context_budget": context_budget_report,
                    "gateway_error": {
                        "error_source": error.error_source,
                        "error_code": error.error_code,
                        "error_message": error.error_message,
                        "details": error_details,
                    },
                },
            )
            return {
                "status": ExecutionStatus.FAILED.value,
                "termination_reason": TerminationReason.FAILED.value,
                "final_answer": f"执行失败：{error.error_message}",
                "error": error,
                "error_details": error_details,
                "current_assistant_content": "",
                "current_assistant_reasoning_content": None,
                "current_tool_calls": [],
                "last_model_finish_reason": "error",
                "step_logs": step_logs,
            }

        usage = TokenUsage(
            prompt_tokens=state["usage"].prompt_tokens + model_resp.token_usage.prompt_tokens,
            completion_tokens=state["usage"].completion_tokens + model_resp.token_usage.completion_tokens,
            total_tokens=state["usage"].total_tokens + model_resp.token_usage.total_tokens,
            usage_estimated=state["usage"].usage_estimated or model_resp.token_usage.usage_estimated,
        )
        tool_calls = list(model_resp.tool_calls or ([] if model_resp.tool_call is None else [model_resp.tool_call]))
        logger.bind(
            event="execution_debug_after_model_call",
            execution_id=str(state["execution_id"]),
            step_index=model_step_index,
            finish_reason=model_resp.finish_reason,
            tool_calls_present=bool(tool_calls),
            tool_call_count=len(tool_calls),
            raw_returned_function_names=[tool_call.function_name for tool_call in tool_calls],
        ).info("Model gateway returned")

        self._append_step_log(
            step_logs=step_logs,
            execution_id=state["execution_id"],
            step_index=model_step_index,
            phase="model_call",
            tool_id=None,
            status="error" if model_resp.error else "success",
            payload={
                "model": model_config.model,
                "temperature": model_config.temperature,
                "max_tokens": provider_model_config.max_tokens,
                "requested_max_tokens": model_config.max_tokens,
                "messages_count": len(context_budget.messages),
                "original_messages_count": len(state["messages"]),
                "tools_attached": bool(context_budget.tools),
                "available_tool_names": state["tool_names"] if context_budget.tools else [],
                "forced_tool_name": forced_tool_name,
                "context_budget": context_budget_report,
                "content_preview": (model_resp.content or "")[:1200],
                "tool_calls": [tool_call.model_dump() for tool_call in tool_calls],
                "finish_reason": model_resp.finish_reason,
            },
        )

        updates: Dict[str, Any] = {
            "usage": usage,
            "current_assistant_content": model_resp.content or "",
            "current_assistant_reasoning_content": model_resp.reasoning_content,
            "current_tool_calls": tool_calls,
            "current_provider_tool_name_map": (
                model_resp.provider_tool_name_to_internal_id
                if model_resp.provider_tool_name_to_internal_id
                else {tool_call.function_name: tool_call.function_name for tool_call in tool_calls}
            ),
            "current_forced_tool": forced_tool_name,
            "last_model_finish_reason": model_resp.finish_reason,
            "step_count": state["step_count"] + 1,
            "step_logs": step_logs,
            "error_details": state["error_details"],
        }

        if model_resp.finish_reason == "length":
            updates.update(
                {
                    "status": ExecutionStatus.TERMINATED.value,
                    "termination_reason": TerminationReason.MODEL_OUTPUT_TRUNCATED.value,
                    "final_answer": (model_resp.content or "").strip(),
                }
            )
            return updates

        if model_resp.finish_reason == "stop" and not tool_calls:
            return updates

        if model_resp.finish_reason == "tool_calls" and tool_calls:
            return updates

        error_message = "执行失败：模型返回了不支持的结束类型。"
        error = ExecutionErrorModel(
            error_code=ArcErrorCode.NETWORK_ERROR.value,
            error_source="gateway",
            error_message=f"Unsupported finish_reason: {model_resp.finish_reason}",
        )
        if model_resp.finish_reason == "tool_calls" and not tool_calls:
            error_message = "执行失败：模型返回了无效的工具调用。"
            error = ExecutionErrorModel(
                error_code=ArcErrorCode.INVALID_TOOL_CALL.value,
                error_source="model_parser",
                error_message="finish_reason 为 tool_calls 但未返回 tool_calls 数据。",
            )
        elif model_resp.finish_reason == "stop":
            error_message = "执行失败：模型未生成最终答案。"
            error = ExecutionErrorModel(
                error_code=ArcErrorCode.NETWORK_ERROR.value,
                error_source="gateway",
                error_message="Model stopped without content or tool calls.",
            )

        updates.update(
            {
                "status": ExecutionStatus.FAILED.value,
                "termination_reason": TerminationReason.FAILED.value,
                "final_answer": error_message,
                "error": error,
            }
        )
        return updates

    def route_after_model(self, state: AgentExecutionState) -> str:
        if state["status"] in {ExecutionStatus.FAILED.value, ExecutionStatus.TERMINATED.value}:
            return "terminate_by_limit"
        if state["current_tool_calls"]:
            return "execute_tools"
        if state["current_assistant_content"].strip():
            return "finalize_answer"
        return "terminate_by_limit"

    async def execute_tools(self, state: AgentExecutionState) -> Dict[str, Any]:
        messages = list(state["messages"])
        if state["current_tool_calls"]:
            messages.append(
                Message(
                    role="assistant",
                    content=state["current_assistant_content"] or "",
                    tool_calls=state["current_tool_calls"],
                )
            )

        react_steps = list(state["react_steps"])
        execution_trace = list(state["execution_trace"])
        step_logs = list(state["step_logs"])
        consecutive_tool_failures = state["consecutive_tool_failures"]
        tool_calls_used = state["tool_calls_used"]
        tool_call_counts = dict(state["tool_call_counts"])
        force_final_answer = state["force_final_answer"]
        previous_loop_signature = state["previous_loop_signature"]

        for tool_call in state["current_tool_calls"]:
            if tool_calls_used >= state["max_tool_calls"]:
                return {
                    "messages": messages,
                    "react_steps": react_steps,
                    "execution_trace": execution_trace,
                    "step_logs": step_logs,
                    "status": ExecutionStatus.TERMINATED.value,
                    "termination_reason": TerminationReason.FAILED.value,
                    "final_answer": "执行终止：达到最大工具调用次数限制。",
                    "current_assistant_reasoning_content": None,
                    "current_tool_calls": [],
                }

            try:
                arguments = json.loads(tool_call.function_arguments)
            except Exception:
                error = ExecutionErrorModel(
                    error_code=ArcErrorCode.INVALID_TOOL_CALL.value,
                    error_source="model_parser",
                    error_message="function.arguments 解析失败，无法进入 tool call。",
                )
                return {
                    "messages": messages,
                    "react_steps": react_steps,
                    "execution_trace": execution_trace,
                    "step_logs": step_logs,
                    "status": ExecutionStatus.FAILED.value,
                    "termination_reason": TerminationReason.FAILED.value,
                    "final_answer": "执行失败：模型返回了非法的 function.arguments。",
                    "error": error,
                    "current_assistant_reasoning_content": None,
                    "current_tool_calls": [],
                }

            if not isinstance(arguments, dict):
                error = ExecutionErrorModel(
                    error_code=ArcErrorCode.INVALID_TOOL_CALL.value,
                    error_source="model_parser",
                    error_message="function.arguments 必须是 JSON object。",
                )
                return {
                    "messages": messages,
                    "react_steps": react_steps,
                    "execution_trace": execution_trace,
                    "step_logs": step_logs,
                    "status": ExecutionStatus.FAILED.value,
                    "termination_reason": TerminationReason.FAILED.value,
                    "final_answer": "执行失败：模型返回的 function.arguments 不是对象。",
                    "error": error,
                    "current_assistant_reasoning_content": None,
                    "current_tool_calls": [],
                }

            provider_tool_name = tool_call.function_name
            tool_id = state["current_provider_tool_name_map"].get(provider_tool_name)
            if not tool_id:
                error = ExecutionErrorModel(
                    error_code=ArcErrorCode.INVALID_TOOL_CALL.value,
                    error_source="model_parser",
                    error_message="Unknown provider tool name",
                )
                return {
                    "messages": messages,
                    "react_steps": react_steps,
                    "execution_trace": execution_trace,
                    "step_logs": step_logs,
                    "status": ExecutionStatus.FAILED.value,
                    "termination_reason": TerminationReason.FAILED.value,
                    "final_answer": "执行失败：模型返回了未知工具名。",
                    "error": error,
                    "error_details": {"provider_tool_name": provider_tool_name},
                    "current_assistant_reasoning_content": None,
                    "current_tool_calls": [],
                }

            step_index = self._next_step_log_index(step_logs)
            tool_policy = policy_gate.evaluate_tool_call(
                tool_id=tool_id,
                arguments=arguments,
                classification=state["classification"],
                pre_policy=state["pre_policy"],
                bound_tool_ids=state["bound_tool_ids"],
                tool_catalog_entries=state["tool_catalog_entries"],
                tool_call_counts=tool_call_counts,
                max_tool_calls=state["max_tool_calls"],
                total_tool_calls_used=tool_calls_used,
                confirmed_tool_actions=state["confirmed_tool_actions"],
            )
            self._append_step_log(
                step_logs=step_logs,
                execution_id=state["execution_id"],
                step_index=step_index,
                phase="tool_policy_gate",
                tool_id=tool_id,
                status="success" if tool_policy.allowed else "error",
                payload={
                    "gate_name": "ToolPolicyGate",
                    "decision": "allowed" if tool_policy.allowed else "blocked",
                    "reason_code": tool_policy.reason_code,
                    "reason_message": tool_policy.reason_message,
                    "input_summary": {"provider_tool_name": provider_tool_name, "resolved_tool_id": tool_id},
                    "arguments_hash": policy_gate.arguments_hash(arguments),
                    "arguments_summary": self._summarize_tool_arguments(arguments),
                    "safe_fallback": "Tool call was blocked by policy." if not tool_policy.allowed else None,
                    "policy_version": policy_gate.VERSION,
                },
            )
            if not tool_policy.allowed:
                observation = ToolObservation(
                    tool_id=tool_id,
                    ok=False,
                    content_type="error",
                    content=None,
                    error=ToolObservationError(
                        code=tool_policy.reason_code or ArcErrorCode.TOOL_BLOCKED_BY_POLICY.value,
                        message=tool_policy.reason_message or "Tool call was blocked by policy.",
                    ),
                )
                messages.append(
                    Message(
                        role="tool",
                        name=tool_id,
                        tool_call_id=tool_call.id,
                        content=json.dumps(
                            {
                                "ok": False,
                                "error": observation.error.model_dump() if observation.error else None,
                            },
                            ensure_ascii=False,
                        ),
                    )
                )
                consecutive_tool_failures += 1
                force_final_answer = True
                if tool_policy.terminal:
                    return {
                        "messages": messages,
                        "react_steps": react_steps,
                        "execution_trace": execution_trace,
                        "step_logs": step_logs,
                        "status": ExecutionStatus.FAILED.value,
                        "termination_reason": TerminationReason.FAILED.value,
                        "final_answer": f"执行失败：{observation.error.message if observation.error else '工具调用被策略拦截。'}",
                        "error": ExecutionErrorModel(
                            error_code=observation.error.code if observation.error else ArcErrorCode.TOOL_BLOCKED_BY_POLICY.value,
                            error_source="tool_policy",
                            error_message=observation.error.message if observation.error else "Tool call was blocked by policy.",
                        ),
                        "current_assistant_reasoning_content": None,
                        "current_tool_calls": [],
                    }
                continue

            tool_calls_used += 1
            tool_call_counts[tool_id] = tool_call_counts.get(tool_id, 0) + 1
            self._append_step_log(
                step_logs=step_logs,
                execution_id=state["execution_id"],
                step_index=step_index,
                phase="tool_call",
                tool_id=tool_id,
                status="success",
                payload={
                    "provider_tool_name": provider_tool_name,
                    "resolved_tool_id": tool_id,
                    "arguments": arguments,
                },
            )
            logger.bind(
                event="tool_runtime_execute",
                execution_id=str(state["execution_id"]),
                step_index=step_index,
                provider_tool_name=provider_tool_name,
                resolved_internal_tool_id=tool_id,
                tool_id=tool_id,
                arguments=arguments,
            ).info("Executing tool runtime")
            observation = await self._execute_tool(
                tool_id=tool_id,
                arguments=arguments,
                auth_context=state["auth_context"],
                request_id=state["request_id"],
                agent_id=state["agent_id"],
                execution_id=state["execution_id"],
                step_index=step_index,
                step_logs=step_logs,
            )
            consecutive_tool_failures = consecutive_tool_failures + 1 if not observation.ok else 0

            tool_payload = {
                "ok": observation.ok,
                "content": observation.content,
                "result": observation.content,
                "error": observation.error.model_dump() if observation.error else None,
            }
            messages.append(
                Message(
                    role="tool",
                    name=tool_id,
                    tool_call_id=tool_call.id,
                    content=json.dumps(tool_payload, ensure_ascii=False),
                )
            )

            error = (
                ExecutionErrorModel(
                    error_code=observation.error.code,
                    error_source="tool",
                    error_message=observation.error.message,
                )
                if observation.error
                else None
            )
            react_step = ReactStep(
                step_index=step_index,
                thought=(state["current_assistant_content"] or "").strip() or None,
                action=Action(type=ActionType.TOOL_CALL, tool_id=tool_id, arguments=arguments),
                observation=Observation(ok=observation.ok, content=observation.content, error=observation.error),
                state_before=ExecutionState.ACTING,
                state_after=ExecutionState.OBSERVING,
                error=error,
            )
            execution_trace.append(react_step)
            react_steps.append(
                {
                    "step_index": step_index,
                    "thought": react_step.thought,
                    "action": {
                        "type": ActionType.TOOL_CALL.value,
                        "tool_id": tool_id,
                        "arguments": arguments,
                    },
                    "observation": tool_payload,
                }
            )
            await self.execution_log_service.append_react_step(
                execution_id=state["execution_id"],
                request_id=state["request_id"],
                step_index=step_index,
                state_before=ExecutionState.ACTING.value,
                state_after=ExecutionState.OBSERVING.value,
                thought=react_step.thought,
                action=react_steps[-1]["action"],
                observation=tool_payload,
                step_status="failed" if error else "success",
                error_code=error.error_code if error else None,
                error_source=error.error_source if error else None,
                error_message=error.error_message if error else None,
            )

            result_hash = self._hash_content(observation.content)
            current_signature = {"tool_id": tool_id, "arguments": arguments, "hash": result_hash}
            if (
                previous_loop_signature is not None
                and previous_loop_signature["tool_id"] == current_signature["tool_id"]
                and previous_loop_signature["arguments"] == current_signature["arguments"]
                and previous_loop_signature["hash"] == current_signature["hash"]
            ):
                return {
                    "messages": messages,
                    "react_steps": react_steps,
                    "execution_trace": execution_trace,
                    "step_logs": step_logs,
                    "status": ExecutionStatus.TERMINATED.value,
                    "termination_reason": TerminationReason.FAILED.value,
                    "final_answer": "执行终止：触发 Loop Protection（相同工具、相同参数、相同结果）。",
                    "previous_loop_signature": current_signature,
                    "current_assistant_reasoning_content": None,
                    "current_tool_calls": [],
                }
            previous_loop_signature = current_signature
            if consecutive_tool_failures >= 2:
                force_final_answer = True

        return {
            "messages": messages,
            "react_steps": react_steps,
            "execution_trace": execution_trace,
            "step_logs": step_logs,
            "tool_calls_used": tool_calls_used,
            "tool_call_counts": tool_call_counts,
            "consecutive_tool_failures": consecutive_tool_failures,
            "force_final_answer": force_final_answer,
            "previous_loop_signature": previous_loop_signature,
            "current_assistant_reasoning_content": None,
            "current_tool_calls": [],
        }

    async def finalize_answer(self, state: AgentExecutionState) -> Dict[str, Any]:
        final_answer = (state["current_assistant_content"] or state["final_answer"] or "").strip()
        tool_call_history = [
            step.get("action", {}).get("tool_id")
            for step in state["react_steps"]
            if isinstance(step.get("action"), dict) and step.get("action", {}).get("tool_id")
        ]
        final_policy: FinalAnswerPolicyDecision = policy_gate.evaluate_final_answer(
            final_answer=final_answer,
            classification=state["classification"],
            retrieval_result=state["knowledge_retrieval_result"],
            tool_call_history=tool_call_history,
        )
        if not final_policy.accepted and final_policy.safe_final_answer:
            final_answer = final_policy.safe_final_answer
        execution_trace = list(state["execution_trace"])
        execution_trace.append(
            ReactStep(
                step_index=len(state["react_steps"]) + 1,
                thought="final_answer",
                action=Action(type=ActionType.FINISH, final_answer=final_answer),
                observation=Observation(ok=True, content={"final_answer": final_answer}, error=None),
                state_before=ExecutionState.THINKING,
                state_after=ExecutionState.FINISHED,
            )
        )
        step_logs = list(state["step_logs"])
        self._append_step_log(
            step_logs=step_logs,
            execution_id=state["execution_id"],
            step_index=self._next_step_log_index(step_logs),
            phase="final_answer_policy_gate",
            tool_id=None,
            status="success" if final_policy.accepted else "error",
            payload={
                **final_policy.model_dump(),
                "policy_version": policy_gate.VERSION,
            },
        )
        self._append_step_log(
            step_logs=step_logs,
            execution_id=state["execution_id"],
            step_index=self._next_step_log_index(step_logs),
            phase="final_answer",
            tool_id=None,
            status="success",
            payload={"final_answer": final_answer},
        )
        return {
            "final_answer": final_answer,
            "status": ExecutionStatus.SUCCEEDED.value if final_policy.accepted or final_policy.safe_final_answer else ExecutionStatus.FAILED.value,
            "termination_reason": TerminationReason.SUCCESS.value if final_policy.accepted or final_policy.safe_final_answer else TerminationReason.FAILED.value,
            "execution_trace": execution_trace,
            "step_logs": step_logs,
        }

    async def terminate_by_limit(self, state: AgentExecutionState) -> Dict[str, Any]:
        if state["status"] == ExecutionStatus.FAILED.value:
            return {}
        if state["termination_reason"] == TerminationReason.MODEL_OUTPUT_TRUNCATED.value:
            return {
                "status": ExecutionStatus.TERMINATED.value,
                "final_answer": state["final_answer"] or state["current_assistant_content"].strip(),
            }
        if state["status"] != ExecutionStatus.TERMINATED.value:
            return {
                "status": ExecutionStatus.TERMINATED.value,
                "termination_reason": TerminationReason.MAX_STEPS_REACHED.value,
                "final_answer": state["final_answer"] or "执行终止：达到最大步数限制。",
            }
        return {}

    async def _execute_tool(
        self,
        tool_id: str,
        arguments: Dict[str, Any],
        auth_context: AuthContext,
        request_id: str,
        agent_id: str,
        execution_id: uuid.UUID,
        step_index: int,
        step_logs: List[ExecutionStepLogContract],
    ) -> ToolObservation:
        try:
            result = await self.tool_runtime.execute_tool(
                tool_id=tool_id,
                arguments=arguments,
                context={
                    "user_id": auth_context.user_id,
                    "team_id": auth_context.team_id,
                    "request_id": request_id,
                    "agent_id": agent_id,
                    "execution_id": str(execution_id),
                },
            )
            parsed_content, content_type = self._normalize_tool_result(result)
            observation = ToolObservation(
                tool_id=tool_id,
                ok=True,
                content_type=content_type,
                content=parsed_content,
                error=None,
            )
            self._append_step_log(
                step_logs=step_logs,
                execution_id=execution_id,
                step_index=step_index,
                phase="observation",
                tool_id=tool_id,
                status="success",
                payload=observation.model_dump(),
            )
            return observation
        except Exception as exc:
            observation = ToolObservation(
                tool_id=tool_id,
                ok=False,
                content_type="error",
                content=None,
                error=ToolObservationError(code="TOOL_EXECUTION_ERROR", message=str(exc)),
            )
            self._append_step_log(
                step_logs=step_logs,
                execution_id=execution_id,
                step_index=step_index,
                phase="observation",
                tool_id=tool_id,
                status="error",
                payload={"error": str(exc)},
            )
            return observation

    @staticmethod
    def _normalize_tool_result(result: str) -> tuple[Any, str]:
        try:
            payload = json.loads(result)
            return payload, "json"
        except Exception:
            return result, "text"

    @staticmethod
    def _hash_content(content: Any) -> str:
        encoded = json.dumps(content, ensure_ascii=False, sort_keys=True, default=str)
        return hashlib.sha256(encoded.encode("utf-8")).hexdigest()

    @staticmethod
    def _summarize_tool_arguments(arguments: Dict[str, Any], *, max_chars: int = 600) -> str:
        if not arguments:
            return "{}"
        encoded = json.dumps(arguments, ensure_ascii=False, sort_keys=True, default=str)
        if len(encoded) <= max_chars:
            return encoded
        return f"{encoded[:max_chars].rstrip()}..."

    @staticmethod
    def _extract_tool_names(tools: List[Dict[str, Any]]) -> List[str]:
        tool_names = [
            str(((tool.get("function") or {}).get("name", ""))).strip()
            for tool in tools
            if isinstance(tool, dict)
        ]
        return [name for name in tool_names if name]

    @staticmethod
    def _filter_tools_by_allowed_ids(tools: List[Dict[str, Any]], allowed_tool_ids: List[str]) -> List[Dict[str, Any]]:
        allowed = set(allowed_tool_ids)
        return [
            tool
            for tool in tools
            if str(((tool.get("function") or {}).get("name", ""))).strip() in allowed
        ]

    @staticmethod
    def _tool_risk_metadata_for_log(tool_catalog_entries: List[Dict[str, Any]]) -> List[Dict[str, Any]]:
        return [
            {
                "tool_id": entry.get("id"),
                "risk_level": entry.get("risk_level"),
                "side_effect": entry.get("side_effect"),
                "requires_confirmation": entry.get("requires_confirmation"),
                "allowed_intents": entry.get("allowed_intents"),
                "domains": entry.get("domains"),
                "max_calls_per_run": entry.get("max_calls_per_run"),
            }
            for entry in tool_catalog_entries
        ]

    @staticmethod
    def _evaluate_retrieval_gate_payload(
        *,
        classification: IntentClassificationResult,
        retrieval_policy: RetrievalPolicy,
        retrieval_result: Dict[str, Any],
    ) -> Dict[str, Any]:
        matched = bool(retrieval_result.get("matched"))
        if retrieval_result.get("error") and retrieval_policy.required:
            return {
                "can_continue_to_model": False,
                "must_return_without_model": True,
                "reason_code": ArcErrorCode.KNOWLEDGE_RETRIEVAL_FAILED.value,
                "safe_fallback": "知识库检索失败，无法回答必须依赖知识库的问题。请稍后重试。",
                "policy_version": policy_gate.VERSION,
            }
        if classification.intent_type == "KB_REQUIRED" and not matched:
            safe_fallback = (
                f"当前知识库未检索到与「{retrieval_result.get('query') or ''}」直接匹配的内容。\n"
                "已检索范围：当前 Agent 知识库。\n"
                "请上传或补充对应校规/制度文档后重试。"
            )
            retrieval_result["knowledge_miss_answer"] = safe_fallback
            return {
                "can_continue_to_model": False,
                "must_return_without_model": True,
                "knowledge_miss": {
                    "reason_code": ArcErrorCode.KNOWLEDGE_REQUIRED_BUT_NOT_FOUND.value,
                    "query": retrieval_result.get("query"),
                    "near_misses": retrieval_result.get("near_misses", False),
                },
                "safe_fallback": safe_fallback,
                "policy_version": policy_gate.VERSION,
            }
        return {
            "can_continue_to_model": True,
            "must_return_without_model": False,
            "injected_evidence": retrieval_result.get("knowledge_hits", []),
            "retrieval_optional_miss": classification.intent_type == "KB_OPTIONAL" and not matched,
            "policy_version": policy_gate.VERSION,
        }

    @staticmethod
    def _extract_agent_persona_prompt(agent_config: Dict[str, Any]) -> str:
        description = agent_config.get("description")
        if isinstance(description, str) and description.strip():
            return description.strip()

        legacy_system_prompt = agent_config.get("system_prompt")
        if isinstance(legacy_system_prompt, str):
            return legacy_system_prompt.strip()

        return ""

    @staticmethod
    def _truncate_knowledge_context_items(items: List[Any]) -> tuple[List[Dict[str, Any]], str, int, int]:
        blocks: List[str] = []
        metadata: List[Dict[str, Any]] = []
        total_original_chars = 0
        remaining_chars = LangGraphExecutionStrategy.MAX_KNOWLEDGE_CONTEXT_CHARS

        for index, item in enumerate(items, start=1):
            original_content = item.content or ""
            total_original_chars += len(original_content)
            if remaining_chars <= 0:
                break

            content_limit = min(LangGraphExecutionStrategy.MAX_KNOWLEDGE_CHUNK_CHARS, remaining_chars)
            injected_content = original_content[:content_limit]
            remaining_chars -= len(injected_content)
            was_truncated = len(injected_content) < len(original_content)
            suffix = "\n[内容已截断]" if was_truncated else ""
            citation_label = getattr(item, "citation_label", "") or f"{item.title} / 片段 {index}"
            blocks.append(f"[{index}] {citation_label}\n{injected_content}{suffix}")
            metadata.append(
                {
                    "document_id": str(item.document_id),
                    "chunk_id": str(item.chunk_id),
                    "title": item.title,
                    "score": item.score,
                    "match_type": getattr(item, "match_type", "keyword"),
                    "document_type": getattr(item, "document_type", "other"),
                    "article_no": getattr(item, "article_no", None),
                    "article_label": getattr(item, "article_label", None),
                    "section_path": getattr(item, "section_path", []),
                    "page_no": getattr(item, "page_no", None),
                    "citation_label": citation_label,
                    "is_direct_evidence": getattr(item, "is_direct_evidence", True),
                    "content_preview": injected_content[:400],
                    "original_content_chars": len(original_content),
                    "injected_content_chars": len(injected_content),
                    "truncated": was_truncated,
                }
            )

        return metadata, "\n\n".join(blocks), total_original_chars, LangGraphExecutionStrategy.MAX_KNOWLEDGE_CONTEXT_CHARS - remaining_chars

    @staticmethod
    async def _retrieve_knowledge_details(
        state: AgentExecutionState,
        *,
        retrieval_policy: RetrievalPolicy | None = None,
    ) -> Dict[str, Any]:
        retrieval_policy = retrieval_policy or RetrievalPolicy(retrieval_mode="optional_hybrid", limit=4, min_score=2.0)
        if retrieval_policy.retrieval_mode == "none":
            return {
                "query": state["user_input"],
                "retrieval_mode": "none",
                "matched": False,
                "matched_count": 0,
                "near_misses": False,
                "knowledge_hits": [],
                "context": "",
                "original_context_chars": 0,
                "injected_context_chars": 0,
                "context_truncated": False,
                "latency_ms": 0,
                "error": None,
            }
        started = time.monotonic()
        try:
            async with AsyncSessionLocal() as db:
                results = await knowledge_service.search(
                    db,
                    agent_id=uuid.UUID(state["agent_id"]),
                    team_id=uuid.UUID(state["auth_context"].team_id),
                    query=state["user_input"],
                    limit=retrieval_policy.limit,
                    retrieval_mode=retrieval_policy.retrieval_mode,
                )
                knowledge_hits, context, original_chars, injected_chars = LangGraphExecutionStrategy._truncate_knowledge_context_items(results)
                matched = len(results) > 0
                if retrieval_policy.retrieval_mode == "exact_clause":
                    matched = any(hit.get("match_type") == "exact_clause" and hit.get("is_direct_evidence") for hit in knowledge_hits)
                return {
                    "query": state["user_input"],
                    "retrieval_mode": retrieval_policy.retrieval_mode,
                    "matched": matched,
                    "matched_count": len(results),
                    "near_misses": bool(results) and not matched,
                    "knowledge_hits": knowledge_hits,
                    "context": context,
                    "original_context_chars": original_chars,
                    "injected_context_chars": injected_chars,
                    "context_truncated": injected_chars < original_chars,
                    "latency_ms": int((time.monotonic() - started) * 1000),
                    "error": None,
                }
        except Exception as exc:
            logger.bind(
                event="knowledge_retrieval_failed",
                execution_id=str(state["execution_id"]),
                agent_id=state["agent_id"],
                error=str(exc),
            ).warning("Knowledge retrieval failed")
            return {
                "query": state["user_input"],
                "retrieval_mode": retrieval_policy.retrieval_mode,
                "matched": False,
                "matched_count": 0,
                "near_misses": False,
                "knowledge_hits": [],
                "context": "",
                "latency_ms": int((time.monotonic() - started) * 1000),
                "error": str(exc),
            }

    @staticmethod
    async def _retrieve_knowledge_context(state: AgentExecutionState) -> str:
        details = await LangGraphExecutionStrategy._retrieve_knowledge_details(state)
        return str(details.get("context", ""))

    @classmethod
    def _normalize_conversation_history(
        cls,
        conversation_history: Optional[List[ConversationHistoryMessage]],
    ) -> List[Message]:
        if not conversation_history:
            return []

        normalized: List[Message] = []
        for item in conversation_history:
            content = item.content.strip()
            if not content:
                continue
            normalized.append(Message(role=item.role, content=content))

        return normalized[-cls.MAX_CONVERSATION_HISTORY_MESSAGES :]

    @staticmethod
    def _next_step_log_index(step_logs: List[ExecutionStepLogContract]) -> int:
        if not step_logs:
            return 1
        return max(log.step_index for log in step_logs) + 1

    @staticmethod
    def _append_step_log(
        step_logs: List[ExecutionStepLogContract],
        execution_id: uuid.UUID,
        step_index: int,
        phase: str,
        tool_id: Optional[str],
        status: str,
        payload: Dict[str, Any],
    ) -> None:
        step_logs.append(
            ExecutionStepLogContract(
                execution_id=str(execution_id),
                step_index=step_index,
                phase=phase,  # type: ignore[arg-type]
                tool_id=tool_id,
                status=status,  # type: ignore[arg-type]
                payload=payload,
                timestamp=datetime.now(timezone.utc).isoformat(),
            )
        )
