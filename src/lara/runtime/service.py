from __future__ import annotations

import asyncio
import hashlib
import json
import os
import time
import warnings
from collections.abc import Sequence
from dataclasses import replace
from html import escape
from pathlib import Path
from typing import TYPE_CHECKING, Any, Mapping, cast

from pygent import (
    AIMessage,
    IdempotencyPolicy,
    ModelCallLayer,
    ModelGroup,
    Module,
    PygentAgent,
    ToolAuthorizationDecision,
    ToolAuthorizationRequest,
    ToolKit,
    ToolMessage,
    ToolSideEffect,
    UserMessage,
    freeze_json_object,
    tool,
)
from pygent import (
    Context as PygentContext,
)
from pygent.agent import (
    REACT_PROJECTION_OPERATION_KIND,
    ReplaceMessageProjection,
    encode_react_projection_operation,
)
from pygent.llm import ModelResourceRef
from pygent.runtime import (
    CapacityPolicy,
    CapacityScope,
    DurabilityMode,
    DurabilityPolicy,
    DurableToolTaskManager,
    ExecutionAdmissionError,
    ExecutionCapacityPolicy,
    LocalRuntime,
    SQLiteCapacityCoordinator,
    SQLiteHistoryStore,
    SQLiteModelDeploymentStore,
)
from pygent.runtime.codec import invocation_from_dict, message_to_dict
from pygent.tool import (
    AgentToolExecutor,
    ExecutorRegistry,
    LocalToolExecutor,
    SandboxExecutorSupport,
    StandardTools,
    ToolExecutionError,
    ToolSpec,
)
from pygent.tool.executors import ToolExecutionContext
from pygent.tool.mcp import (
    MCPStdioTransport,
    discover_mcp_tools,
    register_mcp_tools,
)

from lara.config import load_run_config
from lara.core.io import aclose_if_supported, plain_object, read_json, write_json
from lara.runtime.attachments import (
    ResolvedAttachment,
    build_media_blocks,
    render_attachments_xml,
    resolve_attachments,
)
from lara.runtime.bash_tasks import BashTaskObservations
from lara.runtime.reminders import ReminderService
from lara.schema import AgentSession, CaseRunRef, RunConfig
from lara.sessions import AgentMessage, CollaborationOperation, SessionManager
from lara.tracing import DIFF_TOOL_SPEC, DiffTool, EventStore

from .agent.common import (
    DEFAULT_REACT_MAX_STEPS,
    _initial_lara_context,
    _to_pygent_message,
)
from .agent.core import LARA_PROJECTION_READY_KIND, LaraAgent
from .agent.pipeline import checkpoint_conversation_message
from .agent_collaboration import (
    AGENT_COLLABORATION_TOOL_SPECS,
    visible_agent_collaboration_specs,
)
from .context import LARA_CONTEXT_CODEC, LaraContext
from .deployment import (
    LaraModelResourceResolver,
    WorkspaceToolExecutor,
)
from .eternal_conversation import (
    EternalConversationHarness,
    MemoryAgentTool,
    load_projection,
    render_memory_snapshot,
)
from .file_effects import FILE_EFFECT_TOOL_SPEC, FileEffectToolExecutor
from .model_configuration import preferred_models, preferred_profile_name

if TYPE_CHECKING:
    from lara.orchestration.session_collaboration import SessionCollaborationService

RECOVERY_CLAIM_WAIT_SECONDS = 31.0
# Pygent agent graphs declare requires_finite_deadline=True, so an unlimited
# deadline is rejected at admission; this ceiling is the practical maximum.
TURN_DEADLINE_SECONDS = 24 * 60 * 60

# Non-durable (interruptible) turns resolve their context from this registry;
# durable turns keep reading the SQLite history record.
MAX_TRACKED_TURN_CONTEXTS = 256
PROJECTION_OPERATION_METADATA_KEY = "projection_replacement_operation"
PROJECTION_INPUT_ID_METADATA_KEY = "projection_replacement_input_id"
PROJECTION_READY_INPUT_ID_METADATA_KEY = "projection_replacement_ready_input_id"
MAX_IDENTICAL_MEMORY_TOOL_REJECTIONS = 8


def _config_fingerprint(config: RunConfig) -> str:
    payload = config.to_dict()
    encoded = json.dumps(
        payload,
        ensure_ascii=False,
        sort_keys=True,
        separators=(",", ":"),
    ).encode("utf-8")
    return hashlib.sha256(encoded).hexdigest()


class _MemoryFeedbackState:
    def __init__(self) -> None:
        self.signature: tuple[tuple[str, str], ...] | None = None
        self.count = 0


class _MemoryToolFeedbackLayer(Module[AIMessage, ToolMessage]):
    trusted_live_resource_attributes = ("_feedback_state",)

    def __init__(self, tools: Module[AIMessage, ToolMessage]) -> None:
        super().__init__()
        self.tools = tools
        self._feedback_state = _MemoryFeedbackState()

    async def forward(
        self, message: AIMessage, context: Any
    ) -> tuple[ToolMessage, Any]:
        result, next_context = await self.tools(message, context)
        feedback = [
            item.error
            for item in result.results
            if item.error_kind == "validation_error" and item.error
        ]
        if feedback:
            signature = tuple(
                (call.name, repr(call.arguments)) for call in message.tool_calls
            )
            if signature == self._feedback_state.signature:
                self._feedback_state.count += 1
            else:
                self._feedback_state.signature = signature
                self._feedback_state.count = 1
            same_rejection_count = self._feedback_state.count
            if same_rejection_count >= MAX_IDENTICAL_MEMORY_TOOL_REJECTIONS:
                raise RuntimeError(
                    "publish_pending received the identical invalid payload "
                    f"{same_rejection_count} consecutive times; restart only this background "
                    "memory job with the validation failure in previous_publish_failure"
                )
            repeated = (
                f" IDENTICAL INVALID PAYLOAD REJECTION #{same_rejection_count}: "
                "you resent the same arguments. Change the rejected field before the next tool call."
                if same_rejection_count > 1
                else ""
            )
            instruction = (
                "STOP: publish_pending rejected the previous call before any write; "
                "nothing was published. NEVER resend identical arguments. Preserve all "
                "other facts. Snapshot items must be at most 500 characters; move excess "
                "detail into focused UTs. UT content must be at most 700 characters; split "
                "a larger UT across multiple focused UTs. Keep the whole batch within 8 UT "
                "changes, and call "
                "publish_pending again now."
                + repeated
                + " Validation error: "
                + " | ".join(feedback)
            )
            enhanced_results = tuple(
                replace(
                    item,
                    error=f"{instruction}\nOriginal validation error: {item.error}",
                )
                if item.error_kind == "validation_error" and item.error
                else item
                for item in result.results
            )
            result = replace(
                result,
                content="\n".join(filter(None, (result.content, instruction))),
                results=enhanced_results,
            )
        return result, next_context


def _uncovered_conversation_messages(
    history: list[dict[str, Any]], covered_through: int
) -> tuple[Any, ...]:
    """Keep the uncovered suffix, including its complete opening user turn.

    When the snapshot covers everything, retain the latest exchange so short
    follow-ups still have their immediate conversational referent.
    """
    if not 0 <= covered_through <= len(history):
        raise ValueError("memory coverage is outside the persisted conversation")
    start = covered_through
    if start == len(history) and start:
        start -= 1
    while start > 0 and history[start].get("role") != "user":
        start -= 1
    return tuple(
        message
        for item in history[start:]
        if (message := _to_pygent_message(item)) is not None
    )


class _DiffExecutor:
    def __init__(self, service: "LaraRuntimeService") -> None:
        self.service = service

    async def execute(
        self, spec: ToolSpec, call: Any, context: ToolExecutionContext
    ) -> object:
        del spec
        if context.execution_id is None:
            raise RuntimeError("managed diff execution requires an execution id")
        execution_context = await self.service._turn_context(context.execution_id)
        diff = DiffTool(
            case_run_ref=execution_context.case_run_ref,
            workspace_root=self.service.config.workspace_root,
            turn_id=execution_context.turn_id,
        )
        return await diff.forward(**plain_object(call.arguments))


class LaraRuntimeService:
    """Workspace-scoped owner of Pygent execution and deployment resources."""

    def __init__(
        self,
        config: RunConfig,
        *,
        max_live_executions: int = 32,
        max_runnable_executions: int = 4,
        max_queue_size: int = 64,
        model_max_concurrency: int = 4,
        tool_max_concurrency: int = 8,
        reminders: ReminderService | None = None,
        own_reminders: bool | None = None,
        collaboration: SessionCollaborationService | None = None,
    ) -> None:
        self.config = config
        self.collaboration = collaboration
        self.reminders = reminders or ReminderService(config)
        self._owns_reminders = (
            reminders is None if own_reminders is None else own_reminders
        )
        history_path = Path(config.runtime_durability.history_path)
        self.history_path = history_path
        model_path = history_path.with_name(
            f"model-deployments-v2-{_config_fingerprint(config)[:16]}.sqlite3"
        )
        self.model_path = model_path
        self.history = SQLiteHistoryStore(history_path)
        self.model_store = SQLiteModelDeploymentStore(model_path)
        self.capacity = (
            SQLiteCapacityCoordinator(config.runtime_capacity.coordinator_path)
            if config.runtime_capacity.scope == "deployment"
            else None
        )
        self.executor_registry = ExecutorRegistry()
        self.runtime = LocalRuntime(
            history=self.history,
            capacity_coordinator=self.capacity,
            model_deployment_store=self.model_store,
            deployment_namespace=str(Path(config.workspace_root).resolve()),
            context_codecs=(LARA_CONTEXT_CODEC,),
        )
        self.runtime.attach_executor_registry(self.executor_registry)
        self._diff_executor = _DiffExecutor(self)
        standard = StandardTools(
            workspace_root=config.workspace_root, restrict_to_workspace=False
        )
        self._standard_tools = standard
        ToolKit(
            standard.bash.bash,
            standard.bash.tool_task_get,
            standard.bash.tool_task_stop,
            standard.files.read,
            standard.files.write,
            standard.files.edit,
            standard.files.glob,
            standard.files.grep,
        ).register_into_runtime(
            self.runtime,
            executor_factory=lambda spec, handler: (
                WorkspaceToolExecutor(handler)
                if spec.sandbox_profile == "workspace"
                else LocalToolExecutor(handler)
            ),
        )
        self.runtime.register_tool(FILE_EFFECT_TOOL_SPEC, FileEffectToolExecutor())
        self.runtime.register_tool(DIFF_TOOL_SPEC, self._diff_executor)
        collaboration_executor = AgentToolExecutor(
            invoke=self._execute_agent_collaboration
        )
        setattr(
            collaboration_executor,
            "sandbox_support",
            SandboxExecutorSupport(
                profiles=("agent",),
                durable_reconnect=True,
                deployment_fingerprint="lara:agent-collaboration:v1",
            ),
        )
        for spec in AGENT_COLLABORATION_TOOL_SPECS:
            self.runtime.register_tool(spec, collaboration_executor)
        self.bash_tasks = BashTaskObservations(
            config, self.runtime, history_path.with_suffix(".bash-observations"),
        )
        self.task_manager = DurableToolTaskManager(
            self.history, self.executor_registry, emit=self._on_tool_task_event,
        )
        self.runtime.attach_tool_task_manager(self.task_manager)
        self.model_resolver = LaraModelResourceResolver()
        self.runtime.register_model_resource_resolver(self.model_resolver)
        scope = (
            CapacityScope.DEPLOYMENT
            if config.runtime_capacity.scope == "deployment"
            else CapacityScope.RUNTIME_INSTANCE
        )
        self.binding = self.runtime.create_binding(
            name="lara-agent",
            execution_capacity=ExecutionCapacityPolicy(
                scope=scope,
                max_live_executions=max_live_executions,
                max_runnable_executions=max_runnable_executions,
                max_queue_size=max_queue_size,
                max_waiters=max_live_executions + max_queue_size,
                max_child_depth=max(8, config.delegation.max_depth + 2),
                max_children_per_execution=max(
                    1024, (config.max_steps if config.max_steps > 0 else 128) * 16
                ),
                max_external_wait_seconds=config.runtime_approvals.timeout_seconds,
            ),
            model_capacity=CapacityPolicy.limited(
                max_concurrency=model_max_concurrency,
                max_queue_size=max_queue_size,
                capacity_key="lara-api-model",
                scope=scope,
            ),
            tool_capacity=CapacityPolicy.limited(
                max_concurrency=tool_max_concurrency,
                max_queue_size=max_queue_size,
                capacity_key="lara-api-tool",
                scope=scope,
            ),
            durability=DurabilityPolicy(
                DurabilityMode(
                    DurabilityMode.DISABLED.value
                    if config.runtime_steering.mode == "immediate"
                    else config.runtime_durability.mode
                )
            ),
        )
        self.external_tools: tuple[ToolSpec, ...] = visible_agent_collaboration_specs(
            config,
            collaboration_available=collaboration is not None,
        )
        self._turn_contexts: dict[str, LaraContext] = {}
        self.warnings: list[str] = []
        self._initialized = False
        self._initializing_task: asyncio.Task[None] | None = None
        self._closed = False
        self.memory_harness = EternalConversationHarness(
            config.eternal_conversation,
            run_agent=self._run_memory_agent,
        )
        template = (
            LaraAgent(
                config,
                external_tools=self.external_tools,
                managed_model=True,
                model_group_name=config.resolved_agent.default_model_group,
                memory_harness=self.memory_harness,
                reminders=self.reminders,
                bash_tasks=self.bash_tasks,
            )
            if config.resolved_agent is not None and config.model_config is not None
            else None
        )
        self._agent_definitions: dict[tuple[int, bool, str], LaraAgent] = (
            {
                (
                    id(config),
                    False,
                    config.resolved_agent.default_model_group,
                ): template
            }
            if template is not None and config.resolved_agent is not None
            else {}
        )
        self._model_invokers: dict[str, Any] = (
            {config.resolved_agent.alias: template.llm}
            if template is not None and config.resolved_agent is not None
            else {}
        )

    async def _execute_agent_collaboration(
        self,
        spec: ToolSpec,
        call: Any,
        context: ToolExecutionContext,
    ) -> object:
        collaboration = self.collaboration
        if collaboration is None:
            raise RuntimeError("Agent collaboration is unavailable in this runtime")
        actor = await self._agent_tool_context(context)
        arguments = plain_object(call.arguments)
        name = spec.definition.name
        submission_id = str(call.idempotency_key or call.call_id)
        if name == "agent_start":
            agent_alias = str(arguments["agent"])
            if agent_alias not in self.config.delegation.allowed_agents:
                raise PermissionError(
                    f"collaboration with agent {agent_alias!r} is not allowed"
                )
            child_config = self._child_agent_config(agent_alias)
            operation = await collaboration.start(
                config=child_config,
                manager=SessionManager(child_config),
                source_session_id=actor.session_id,
                message=str(arguments["task"]),
                submission_id=submission_id,
            )
            return operation.to_dict()
        if name == "agent_send":
            target_session_id = str(arguments["session_id"])
            if not await collaboration.related_sessions(
                config=self.config,
                first_session_id=actor.session_id,
                second_session_id=target_session_id,
            ):
                raise PermissionError("Agent sessions are not related collaborators")
            message = await collaboration.send(
                config=self.config,
                manager=SessionManager(self.config),
                source_session_id=actor.session_id,
                source_agent_alias=self.config.agent_alias,
                target_session_id=target_session_id,
                message=str(arguments["message"]),
                submission_id=submission_id,
            )
            return message.to_dict()
        if name == "agent_list":
            operations = await collaboration.list_operations(
                config=self.config,
                session_id=actor.session_id,
            )
            return {"operations": [operation.to_dict() for operation in operations]}
        if name == "agent_status":
            collaboration_id = str(arguments["collaboration_id"])
            return await self._agent_collaboration_status(
                collaboration, collaboration_id, actor.session_id
            )
        if name == "agent_wait":
            timeout = float(arguments.get("timeout_seconds", 30))
            if not 0 < timeout <= 120:
                raise ValueError(
                    "timeout_seconds must be greater than 0 and at most 120"
                )
            has_single = "collaboration_id" in arguments
            multiple = "collaboration_ids" in arguments
            if has_single == multiple:
                raise ValueError(
                    "provide exactly one of collaboration_id or collaboration_ids"
                )
            collaboration_ids = (
                tuple(str(item) for item in arguments["collaboration_ids"])
                if multiple
                else (str(arguments["collaboration_id"]),)
            )
            if not 1 <= len(collaboration_ids) <= 32:
                raise ValueError(
                    "collaboration_ids must contain between 1 and 32 items"
                )
            if len(set(collaboration_ids)) != len(collaboration_ids):
                raise ValueError("collaboration_ids must be unique")
            return await self._wait_for_agent_collaborations(
                collaboration,
                collaboration_ids,
                actor.session_id,
                timeout=timeout,
                multiple=multiple,
            )
        raise ValueError(f"unsupported Agent collaboration tool {name!r}")

    def _track_turn_context(self, execution_id: str, context: LaraContext) -> None:
        """Remember one execution context for non-durable (interruptible) turns.

        Durable turns resolve their context from the SQLite history record;
        interruptible turns have no history row, so tool executors read the
        context captured at start here.
        """

        self._turn_contexts[execution_id] = context
        while len(self._turn_contexts) > MAX_TRACKED_TURN_CONTEXTS:
            self._turn_contexts.pop(next(iter(self._turn_contexts)), None)

    async def _turn_context(self, execution_id: str) -> LaraContext:
        tracked = self._turn_contexts.get(execution_id)
        if tracked is not None:
            return tracked
        record = await self.history.get_execution(execution_id)
        if record is None:
            raise RuntimeError(f"execution {execution_id!r} has no resolvable context")
        _, decoded = invocation_from_dict(
            record.input,
            registry=self.runtime.context_codec_registry,
        )
        if not isinstance(decoded, LaraContext):
            raise TypeError("execution context is not a LaraContext")
        return decoded

    async def _agent_tool_context(self, context: ToolExecutionContext) -> LaraContext:
        if context.execution_id is None:
            raise RuntimeError("Agent collaboration requires an execution id")
        return await self._turn_context(context.execution_id)

    async def _agent_collaboration_status(
        self,
        collaboration: SessionCollaborationService,
        collaboration_id: str,
        actor_session_id: str,
    ) -> dict[str, Any]:
        item = await collaboration.item_status(
            config=self.config,
            collaboration_id=collaboration_id,
        )
        self._require_collaboration_access(item, actor_session_id)
        return item.to_dict()

    async def _wait_for_agent_collaborations(
        self,
        collaboration: SessionCollaborationService,
        collaboration_ids: tuple[str, ...],
        actor_session_id: str,
        *,
        timeout: float,
        multiple: bool,
    ) -> dict[str, Any]:
        items = tuple(
            await asyncio.gather(
                *(
                    collaboration.item_status(
                        config=self.config,
                        collaboration_id=collaboration_id,
                    )
                    for collaboration_id in collaboration_ids
                )
            )
        )
        for item in items:
            self._require_collaboration_access(item, actor_session_id)
        if any(item.done for item in items):
            completed = items
            timed_out = False
        else:
            for item in items:
                if isinstance(item, CollaborationOperation):
                    child_config = self._child_agent_config(item.agent_alias)
                    await collaboration.resume_operation(
                        config=child_config,
                        manager=SessionManager(child_config),
                        operation_id=item.operation_id,
                    )
            completed, timed_out = await collaboration.wait_any(
                config=self.config,
                collaboration_ids=collaboration_ids,
                timeout=timeout,
            )
            for item in completed:
                self._require_collaboration_access(item, actor_session_id)
        if not multiple:
            return {**completed[0].to_dict(), "timed_out": timed_out}
        return {
            "ready": [item.to_dict() for item in completed if item.done],
            "pending": [item.to_dict() for item in completed if not item.done],
            "timed_out": timed_out,
        }

    @classmethod
    def _require_collaboration_access(
        cls,
        item: AgentMessage | CollaborationOperation,
        actor_session_id: str,
    ) -> None:
        if isinstance(item, AgentMessage):
            cls._require_message_access(item, actor_session_id)
        else:
            cls._require_operation_access(item, actor_session_id)

    @staticmethod
    def _require_operation_access(
        operation: CollaborationOperation, actor_session_id: str
    ) -> None:
        if actor_session_id not in {
            operation.source_session_id,
            operation.target_session_id,
        }:
            raise PermissionError("Agent operation is outside this collaboration")

    @staticmethod
    def _require_message_access(message: AgentMessage, actor_session_id: str) -> None:
        if actor_session_id not in {
            message.source_session_id,
            message.target_session_id,
        }:
            raise PermissionError("Agent message is outside this collaboration")

    async def _on_tool_task_event(self, kind: str, data: Mapping[str, Any]) -> None:
        # Delegate through self.bash_tasks so a replaced observation instance
        # (restore path) is still the event target.
        await self.bash_tasks.on_tool_task_event(kind, data)

    async def initialize(self) -> None:
        if self._closed:
            raise RuntimeError("LaraRuntimeService is closed")
        if self._initialized:
            return
        if self._initializing_task is None:
            self._initializing_task = asyncio.create_task(self._initialize_once())
        try:
            await asyncio.shield(self._initializing_task)
        except BaseException:
            if self._initializing_task.done():
                self._initializing_task = None
            raise

    async def _initialize_once(self) -> None:
        for path in (
            self.history_path,
            Path(self.config.runtime_capacity.coordinator_path),
        ):
            path.parent.mkdir(parents=True, exist_ok=True)
        await self.history.open()
        discovered = list(self.external_tools)
        visible_names: set[str] = {
            "bash",
            "read",
            "write",
            "edit",
            "glob",
            "grep",
            "diff",
            *(spec.definition.name for spec in discovered),
        }
        for server in self.config.mcp_servers:
            try:
                transport = self._mcp_transport(server)
                specs = await discover_mcp_tools(
                    transport,
                    namespace=server.name,
                    timeout=server.timeout,
                )
                for spec in specs:
                    name = spec.definition.name
                    if name in visible_names:
                        raise ValueError(
                            f"duplicate MCP model-visible tool name: {name}"
                        )
                    visible_names.add(name)
                register_mcp_tools(self.executor_registry, transport, specs)
                discovered.extend(specs)
            except Exception as exc:
                if server.required:
                    raise RuntimeError(
                        f"required MCP server {server.name!r} failed: {exc}"
                    ) from exc
                message = f"optional MCP server {server.name!r} skipped: {exc}"
                self.warnings.append(message)
                warnings.warn(message, RuntimeWarning, stacklevel=2)
        self.external_tools = tuple(discovered)
        await self.bash_tasks.restore()
        self._initialized = True

    def _mcp_transport(self, server: Any) -> Any:
        if server.transport != "stdio":
            raise ValueError(
                f"MCP transport {server.transport!r} is unsupported by the installed Pygent; "
                "use stdio"
            )
        env = {name: os.environ[name] for name in server.env_from if name in os.environ}
        return MCPStdioTransport(
            server.command,
            args=server.args,
            env=env,
            cwd=server.cwd,
        )

    def new_agent(
        self,
        *,
        interactive_approvals: bool,
        model_group_name: str | None = None,
        config: RunConfig | None = None,
    ) -> LaraAgent:
        effective_config = config or self.config
        resolved = effective_config.resolved_agent
        if resolved is None:
            raise ValueError("resolved agent configuration is required")
        selected_group = model_group_name or resolved.default_model_group
        key = (id(effective_config), interactive_approvals, selected_group)
        existing = self._agent_definitions.get(key)
        if existing is not None:
            return existing
        invoker = (
            self._model_invokers.get(resolved.alias) if resolved is not None else None
        )
        agent = LaraAgent(
            effective_config,
            resolved_agent=effective_config.resolved_agent,
            external_tools=self.external_tools,
            managed_model=True,
            model_group_name=selected_group,
            interactive_approvals=interactive_approvals,
            model_invoker=invoker,
            memory_harness=self.memory_harness,
            reminders=self.reminders,
            bash_tasks=self.bash_tasks,
        )
        if resolved is not None and agent.llm is not None:
            self._model_invokers.setdefault(resolved.alias, agent.llm)
        self._agent_definitions[key] = agent
        return agent

    def _child_agent_config(self, alias: str) -> RunConfig:
        if alias == self.config.agent_alias:
            return RunConfig.from_dict(self.config.to_dict())
        return load_run_config(
            workspace_root=self.config.workspace_root,
            agent_alias=alias,
            max_steps=self.config.max_steps,
            context_window=self.config.context_window,
        )

    async def bind(self, module: Any, agent: LaraAgent) -> Any:
        await self.initialize()
        bound = self.binding.bind(module)
        if agent.llm is not None and (
            module is agent or getattr(module, "agent", None) is agent
        ):
            requirement = ModelGroup.deferred(name=f"lara:{agent.model_group_name}")
            handle = bound.model_groups.get(requirement)
            native = agent.config.model_config
            if native is None:
                raise RuntimeError("model_configuration_required")
            group = native.model_groups[agent.model_group_name]
            revision = hashlib.sha256(
                repr(
                    (
                        agent.model_group_name,
                        group.models,
                        tuple(native.connections.items()),
                    )
                ).encode("utf-8")
            ).hexdigest()
            self.model_resolver.register(revision, agent.llm)
            for index, entry in enumerate(group.models):
                await handle.ensure_profile(
                    profile=preferred_profile_name(entry.key),
                    models=preferred_models(
                        native, agent.model_group_name, entry.key
                    ),
                    invoker=agent.llm,
                    resource_ref=ModelResourceRef(
                        resolver_id=self.model_resolver.resolver_id,
                        resource_id=f"lara:{agent.model_group_name}",
                        revision=revision,
                        capacity_owner_id=f"lara:{Path(self.config.workspace_root).resolve()}",
                        coordinator_domain=str(Path(self.config.workspace_root).resolve()),
                    ),
                    make_default=index == 0,
                    deadline=time.monotonic() + 60,
                )
        return bound

    @staticmethod
    async def _deliver_projection_replacement(
        handle: Any, context: LaraContext
    ) -> None:
        operation = context.metadata.get(PROJECTION_OPERATION_METADATA_KEY)
        if operation is None:
            return
        for key, kind, value in (
            (
                PROJECTION_INPUT_ID_METADATA_KEY,
                REACT_PROJECTION_OPERATION_KIND,
                operation,
            ),
            (PROJECTION_READY_INPUT_ID_METADATA_KEY, LARA_PROJECTION_READY_KIND, True),
        ):
            result = await handle.send_input(
                input_id=str(context.metadata[key]), kind=kind, value=value
            )
            if result.status not in {"accepted", "duplicate"}:
                raise RuntimeError(
                    f"native projection input was not delivered: {result.status}"
                )

    async def _start_agent_execution(
        self,
        bound: Any,
        message: UserMessage,
        context: LaraContext,
        *,
        execution: Any,
    ) -> Any:
        handle = await bound.start(message, context, execution=execution)
        try:
            await self._deliver_projection_replacement(handle, context)
        except BaseException:
            await handle.cancel()
            raise
        return handle

    async def start_turn(
        self,
        *,
        manager: SessionManager,
        message: str,
        run_ref: CaseRunRef,
        turn_id: str,
        interactive_approvals: bool,
        message_kind: str = "lara.chat.turn",
        message_data: dict[str, object] | None = None,
        attachments: Sequence[str] = (),
        deadline: float | None = None,
    ) -> Any:
        from pygent.runtime import ExecutionOptions

        await self.initialize()
        group_name, selected_model_key = manager.model_selection(run_ref.session_id)
        agent = self.new_agent(
            interactive_approvals=interactive_approvals,
            model_group_name=group_name,
        )
        turn_message, turn_context = await self._prepare_turn(
            manager=manager,
            run_ref=run_ref,
            message=message,
            config=self.config,
            turn_id=turn_id,
            message_kind=message_kind,
            message_data=message_data,
            attachments=attachments,
        )
        bound = await self.bind(agent, agent)
        try:
            handle = await self._start_agent_execution(
                bound,
                turn_message,
                turn_context,
                execution=ExecutionOptions(
                    request_id=run_ref.case_run_id,
                    idempotency_key=run_ref.case_run_id,
                    identity=run_ref.session_id,
                    model_calls=(
                        {
                            f"lara:{group_name}": {
                                "profile": preferred_profile_name(selected_model_key)
                            }
                        }
                        if agent.llm is not None
                        else {}
                    ),
                    deadline=deadline
                    if deadline is not None
                    else time.monotonic() + TURN_DEADLINE_SECONDS,
                ),
            )
        except BaseException:
            await self.reminders.release_initial(run_ref.session_id, turn_id)
            raise
        await self.reminders.acknowledge_initial(
            run_ref.session_id, turn_id, handle.execution_id
        )
        self._record_execution_id(run_ref, handle.execution_id)
        self._track_turn_context(handle.execution_id, turn_context)
        return handle

    async def send_steering(
        self, execution_id: str, *, input_id: str, message: str, case_run_id: str,
    ) -> Any:
        from pygent.agent import StandaloneUserMessage, SteeringMode

        handle = await self.runtime.get_execution_handle(execution_id)
        return await handle.send_input(
            input_id=input_id,
            kind=REACT_PROJECTION_OPERATION_KIND,
            value=encode_react_projection_operation(
                StandaloneUserMessage(
                    UserMessage(
                        content=message,
                        kind="lara.user.steering",
                        data={"input_id": input_id, "case_run_id": case_run_id},
                    ),
                    mode=(
                        SteeringMode.IMMEDIATE
                        if self.config.runtime_steering.mode == "immediate"
                        else SteeringMode.WAIT
                    ),
                )
            ),
        )

    async def cancel_turn(self, execution_id: str) -> bool:
        """Request cancellation of one running execution.

        Returns False when the execution already reached a terminal state.
        """

        await self.initialize()
        handle = await self.runtime.get_execution_handle(execution_id)
        return await handle.cancel()

    async def recover_turn(
        self,
        execution_id: str,
        *,
        deadline: float | None = None,
    ) -> Any:
        """Claim and resume one non-terminal durable Pygent execution."""

        await self.initialize()
        if deadline is None:
            deadline = time.monotonic() + TURN_DEADLINE_SECONDS
        stored = await self.history.get_execution(execution_id)
        if stored is None:
            raise KeyError(f"unknown durable execution {execution_id!r}")
        _, recovered_context = invocation_from_dict(
            stored.input,
            registry=self.runtime.context_codec_registry,
        )
        if not isinstance(recovered_context, LaraContext):
            raise TypeError("durable execution context is not a LaraContext")
        group_name, _ = SessionManager(self.config).model_selection(
            recovered_context.session_id
        )
        agent = self.new_agent(
            interactive_approvals=True,
            model_group_name=group_name,
        )
        bound = await self.bind(agent, agent)
        await self.runtime.recover_tool_jobs(bound)
        lease_wait_deadline = min(
            deadline,
            time.monotonic() + RECOVERY_CLAIM_WAIT_SECONDS,
        )
        while True:
            try:
                handle = await self.runtime.recover(
                    bound,
                    execution_id,
                    deadline=deadline,
                )
                stored = await self.history.get_execution(execution_id)
                if stored is None:
                    raise KeyError(f"unknown durable execution {execution_id!r}")
                _, decoded_context = invocation_from_dict(
                    stored.input,
                    registry=self.runtime.context_codec_registry,
                )
                context = cast(LaraContext, decoded_context)
                self._track_turn_context(execution_id, context)
                await self._deliver_projection_replacement(handle, context)
                return handle
            except ExecutionAdmissionError as exc:
                if (
                    "owned by another recovery attempt" not in str(exc)
                    or time.monotonic() >= lease_wait_deadline
                ):
                    raise
                await asyncio.sleep(0.1)

    async def recovery_case_run(self, execution_id: str) -> CaseRunRef:
        """Recover the application run identity stored with a Pygent invocation."""

        await self.initialize()
        stored = await self.history.get_execution(execution_id)
        if stored is None:
            raise KeyError(f"unknown durable execution {execution_id!r}")
        _, decoded_context = invocation_from_dict(
            stored.input,
            registry=self.runtime.context_codec_registry,
        )
        context = cast(LaraContext, decoded_context)
        return context.case_run_ref

    async def execute_case(
        self,
        *,
        manager: SessionManager,
        session: Any,
        case: Any,
        run_ref: CaseRunRef,
    ) -> dict[str, Any]:
        from pygent.runtime import ExecutionOptions

        await self.initialize()

        store = EventStore(run_ref)
        store.append(
            "case.started",
            actor="system",
            payload={"title": case.title},
            turn_id="turn-0001",
        )
        carry_context = case.session.get("carry_context") is not False
        if not carry_context:
            session.history = []
        inputs = case.input.get("messages")
        messages = (
            [
                str(item.get("content") or "")
                for item in inputs
                if isinstance(item, dict) and item.get("role", "user") == "user"
            ]
            if isinstance(inputs, list)
            else [str(case.input.get("content") or "")]
        )
        messages = [item for item in messages if item]
        current_message = messages[-1] if messages else ""
        checkpoint_context = LaraContext(
            session_id=run_ref.session_id,
            case_id=run_ref.case_id,
            case_run_id=run_ref.case_run_id,
            run_dir=run_ref.run_dir,
            turn_id="turn-0001",
            system_prompt=session.system_prompt,
            metadata={"persist_conversation_history": carry_context},
        )
        for index, prior in enumerate(messages[:-1]):
            prior_message = UserMessage(content=prior)
            await checkpoint_conversation_message(
                self.config,
                checkpoint_context,
                prior_message,
                boundary=f"case-input-{index}",
            )
            if not carry_context:
                session.history.append(message_to_dict(prior_message))
        if carry_context and messages[:-1]:
            session = manager.load(run_ref.session_id)
        group_name, selected_model_key = manager.model_selection(run_ref.session_id)
        agent = self.new_agent(
            interactive_approvals=False,
            model_group_name=group_name,
        )
        turn_message, turn_context = await self._prepare_turn(
            manager=manager,
            run_ref=run_ref,
            message=current_message,
            config=self.config,
            turn_id="turn-0001",
            session=session,
            carry_context=carry_context,
        )
        bound = await self.bind(agent, agent)
        try:
            handle = await self._start_agent_execution(
                bound,
                turn_message,
                turn_context,
                execution=ExecutionOptions(
                    request_id=run_ref.case_run_id,
                    idempotency_key=run_ref.case_run_id,
                    identity=run_ref.session_id,
                    model_calls=(
                        {
                            f"lara:{group_name}": {
                                "profile": preferred_profile_name(selected_model_key)
                            }
                        }
                        if agent.llm is not None
                        else {}
                    ),
                    deadline=time.monotonic() + TURN_DEADLINE_SECONDS,
                ),
            )
        except BaseException:
            await self.reminders.release_initial(run_ref.session_id, "turn-0001")
            raise
        await self.reminders.acknowledge_initial(
            run_ref.session_id,
            "turn-0001",
            handle.execution_id,
        )
        self._track_turn_context(handle.execution_id, turn_context)
        output, _ = await handle.result()
        result = plain_object(plain_object(output.data).get("result"))
        result["event_count"] = len(store.list_by_run())
        store.append(
            "case.finished",
            actor="system",
            payload={"status": result.get("status"), "error": result.get("error")},
            turn_id="turn-0001",
        )
        result["runtime_execution_id"] = handle.execution_id
        self._record_execution_id(run_ref, handle.execution_id)
        return result

    async def _prepare_turn(
        self,
        *,
        manager: SessionManager,
        run_ref: CaseRunRef,
        message: str,
        config: RunConfig,
        turn_id: str,
        session: AgentSession | None = None,
        carry_context: bool = True,
        message_kind: str = "lara.chat.turn",
        message_data: dict[str, object] | None = None,
        attachments: Sequence[str] = (),
    ) -> tuple[UserMessage, LaraContext]:
        if session is None:
            session = manager.load(run_ref.session_id)
        memory_projection = (
            load_projection(session.session_dir) if carry_context else {}
        )
        covered_through = int(memory_projection.get("covered_through") or 0)
        lara_context = LaraContext(
            session_id=session.session_id,
            case_id=run_ref.case_id,
            case_run_id=run_ref.case_run_id,
            run_dir=run_ref.run_dir,
            turn_id=turn_id,
            system_prompt=session.system_prompt,
            eternal_memory_enabled=config.eternal_conversation.enabled,
            memory_covered_through=covered_through,
            memory_projection=freeze_json_object(memory_projection),
            raw_history_location=str(
                Path(session.session_dir) / "raw-history" / "events.jsonl"
            ),
        )
        resolved_attachments: tuple[ResolvedAttachment, ...] = ()
        if message_kind != "lara.automation.trigger" and attachments:
            resolved_attachments = resolve_attachments(
                attachments, config.workspace_root
            )
        if message_kind == "lara.automation.trigger":
            wrapped = message
        else:
            lines = [
                "<user-context>",
                f"  <user-identity>{escape(config.user_identity or 'default', quote=False)}</user-identity>",
                f"  <user-message>{escape(message, quote=False)}</user-message>",
            ]
            if resolved_attachments:
                lines.append(render_attachments_xml(resolved_attachments))
            lines.append("</user-context>")
            wrapped = "\n".join(lines)
        reminder = await self.reminders.claim_initial(session.session_id, turn_id)
        dynamic_reminder = await self.reminders.collect_pending(session.session_id)
        if dynamic_reminder:
            reminder = (
                f"{reminder}\n\n{dynamic_reminder}" if reminder else dynamic_reminder
            )
        if reminder:
            wrapped = f"{wrapped}\n\n{reminder}"
        history, _ = _initial_lara_context(
            context=lara_context,
            history=session.history,
            checkpoint=session.metadata.get("agent_context"),
        )
        current = UserMessage(
            content=wrapped,
            kind=message_kind,
            data=freeze_json_object(
                {
                    "raw_content": message,
                    **(
                        {
                            "attachments": [
                                item.relative for item in resolved_attachments
                            ]
                        }
                        if resolved_attachments
                        else {}
                    ),
                    **dict(message_data or {}),
                }
            ),
            media=build_media_blocks(resolved_attachments),
        )
        metadata: dict[str, Any] = {
            "session_id": run_ref.session_id,
            "case_run_id": run_ref.case_run_id,
            "persist_conversation_history": carry_context,
            "model_group_name": session.model_group_name,
            "selected_model_key": session.selected_model_key,
        }
        if (
            config.eternal_conversation.enabled
            and carry_context
            and covered_through > 0
        ):
            snapshot = UserMessage(
                content=render_memory_snapshot(memory_projection),
                kind="lara.memory.snapshot",
                slot="lara.memory.snapshot",
            )
            replacement = ReplaceMessageProjection(
                messages=(
                    snapshot,
                    *_uncovered_conversation_messages(session.history, covered_through),
                    current,
                ),
                expected_revision=history.projection_revision + 1,
            )
            identity = (
                f"{run_ref.case_run_id}:memory-projection:"
                f"{memory_projection.get('snapshot_revision', 0)}:{covered_through}"
            )
            metadata.update(
                {
                    "projection_replacement_pending": True,
                    "projection_replacement_message_count": len(replacement.messages),
                    PROJECTION_OPERATION_METADATA_KEY: encode_react_projection_operation(
                        replacement
                    ),
                    PROJECTION_INPUT_ID_METADATA_KEY: identity,
                    PROJECTION_READY_INPUT_ID_METADATA_KEY: f"{identity}:ready",
                }
            )
        execution_context = replace(
            history,
            metadata=metadata,
        )
        return (
            current,
            execution_context,
        )

    @staticmethod
    def _record_execution_id(run_ref: CaseRunRef, execution_id: str) -> None:
        path = Path(run_ref.run_dir) / "run_metadata.json"
        metadata = read_json(path, default={})
        metadata["runtime_execution_id"] = execution_id
        write_json(path, metadata)

    async def deliver_approval(
        self, approval_id: str, *, approved: bool, comment: str = ""
    ) -> bool:
        return await self.runtime.deliver_external(
            kind="tool-approval",
            key=approval_id,
            value={"approved": approved, "comment": comment},
        )

    async def _run_memory_agent(
        self,
        alias: str,
        system_prompt: str,
        request: dict[str, Any],
        memory_tool: MemoryAgentTool,
    ) -> str:
        child_config = self._child_agent_config(alias)
        if child_config.resolved_agent is None:
            raise RuntimeError(f"background memory Agent {alias!r} is unconfigured")
        agent = LaraAgent(
            child_config,
            managed_model=False,
            model_group_name=child_config.resolved_agent.default_model_group,
        )
        try:
            layer = agent.new_model_layer()
            if agent.llm is None:
                raise RuntimeError(
                    f"background memory Agent {alias!r} has no configured model"
                )

            @tool(
                tool_id=f"lara.memory.{memory_tool.name}",
                version="1.0.0",
                side_effect=ToolSideEffect.WRITE,
                idempotency=IdempotencyPolicy.INHERENT,
                name=memory_tool.name,
                description=memory_tool.description,
                timeout=300,
                resource_key="lara-memory",
                required_permissions=("memory:write",),
            )
            async def memory_operation(payload: dict[str, Any]) -> dict[str, Any]:
                try:
                    return await memory_tool.handler(payload)
                except ValueError as exc:
                    # Extractor validation happens before publish-pending writes.
                    # Tell Pygent the failed call is safe to correct and retry;
                    # unclassified CLI failures remain conservatively unknown.
                    raise ToolExecutionError(
                        str(exc),
                        kind="validation_error",
                        code=type(exc).__name__,
                        retryable=True,
                        side_effect_committed=False,
                    ) from exc

            toolkit = ToolKit(memory_operation)

            def authorize_memory_tool(
                request: ToolAuthorizationRequest,
                context: PygentContext,
            ) -> ToolAuthorizationDecision:
                del context
                return ToolAuthorizationDecision(
                    call_id=request.call.call_id,
                    allowed=True,
                    reason_code="lara-background-memory-job",
                )

            model = ModelCallLayer(
                model_group=layer.model_group,
                retry_policy=layer.retry_policy,
                generation=replace(
                    layer.generation,
                    tool_choice="auto",
                ),
                policy=layer.policy,
                tools=toolkit.definitions,
                invoker=agent.llm,
            )
            # This is a native Pygent ReAct Agent. The background job remains
            # independent of the foreground durable execution, while validation
            # failures return through ToolResult and stay in this Agent's context.
            react_agent = PygentAgent(
                system_prompt=system_prompt,
                compression_prompt="Compress the memory job transcript without losing tool errors.",
                model=model,
                compressor=model,
                tools=_MemoryToolFeedbackLayer(
                    toolkit.local_layer(authorization_adapter=authorize_memory_tool)
                ),
                context_window_tokens=1 << 60,
                compression_context_window_tokens=1 << 60,
                max_compressions=1,
                max_steps=DEFAULT_REACT_MAX_STEPS,
                max_model_calls=DEFAULT_REACT_MAX_STEPS,
                max_tool_calls=DEFAULT_REACT_MAX_STEPS,
            )
            answer, _ = await react_agent.invoke(
                UserMessage(content=json.dumps(request, ensure_ascii=False)),
                react_agent.new_context(
                    tools=toolkit.definitions,
                    metadata={"memory_agent_alias": alias},
                ),
            )
            return answer.content
        finally:
            await agent.aclose()

    async def get_task(self, task_id: str) -> Any:
        return await self.runtime.get_tool_task(task_id)

    async def get_task_output(self, task_id: str) -> Any:
        return await self.runtime.get_tool_output(task_id)

    async def get_task_result(self, task_id: str) -> Any:
        return await self.runtime.get_tool_result(task_id)

    async def cancel_task(self, task_id: str) -> bool:
        return await self.runtime.cancel_tool_task(task_id)

    async def close(self, *, cancel: bool = True) -> None:
        if self._closed:
            return
        self._closed = True
        await self.memory_harness.close()
        await self.runtime.close(cancel=cancel)
        await self.bash_tasks.close()
        await self._standard_tools.aclose()
        for agent in self._agent_definitions.values():
            await aclose_if_supported(agent._standard_tools)
        for invoker in {
            id(value): value for value in self._model_invokers.values()
        }.values():
            await aclose_if_supported(invoker)
        if self.capacity is not None:
            await self.capacity.close(release_leases=True)
        await self.history.close()
        if self._owns_reminders:
            await self.reminders.close()


__all__ = ["LaraRuntimeService"]
