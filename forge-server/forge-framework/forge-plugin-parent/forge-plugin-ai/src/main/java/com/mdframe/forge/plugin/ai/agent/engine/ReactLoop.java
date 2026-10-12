package com.mdframe.forge.plugin.ai.agent.engine;

import com.mdframe.forge.plugin.ai.agent.engine.event.AgentEventPublisher;
import com.mdframe.forge.plugin.ai.agent.engine.tool.AgentTool;
import com.mdframe.forge.plugin.ai.agent.engine.event.AgentEvent;
import com.mdframe.forge.plugin.ai.agent.engine.event.AgentEventType;
import com.mdframe.forge.plugin.ai.agent.domain.AiAgent;
import com.mdframe.forge.plugin.ai.agent.service.AiAgentService;
import com.mdframe.forge.plugin.ai.provider.adapter.AiProviderAdapterRegistry;
import com.mdframe.forge.plugin.ai.provider.support.AiSecretCrypto;
import com.mdframe.forge.plugin.ai.invocation.AiInvocationObservation;
import com.mdframe.forge.plugin.ai.invocation.AiInvocationOutcome;
import com.mdframe.forge.plugin.ai.invocation.AiInvocationPhase;
import com.mdframe.forge.plugin.ai.invocation.service.AiModelInvocationRecorder;
import lombok.RequiredArgsConstructor;
import lombok.extern.slf4j.Slf4j;
import org.springframework.ai.chat.messages.AssistantMessage;
import org.springframework.ai.chat.messages.Message;
import org.springframework.ai.chat.messages.SystemMessage;
import org.springframework.ai.chat.messages.UserMessage;
import org.springframework.ai.chat.metadata.Usage;
import org.springframework.ai.chat.model.ChatModel;
import org.springframework.ai.chat.model.ChatResponse;
import org.springframework.ai.chat.model.MessageAggregator;
import org.springframework.ai.chat.prompt.Prompt;
import org.springframework.ai.openai.OpenAiChatModel;
import org.springframework.ai.openai.OpenAiChatOptions;
import org.springframework.ai.openai.api.OpenAiApi;
import org.springframework.ai.tool.ToolCallback;
import org.springframework.ai.tool.definition.ToolDefinition;
import org.springframework.stereotype.Component;
import reactor.core.publisher.Flux;
import reactor.core.publisher.Sinks;

import java.util.*;
import java.util.concurrent.atomic.AtomicReference;

/**
 * ReAct 循环核心。
 * 纯 ReAct 循环（推理→行动迭代），底层用 Spring AI ChatModel。
 * 不使用 Spring AI 的 ChatClient.tools() / ToolCallAdvisor——工具调用循环完全自控。
 */
@Slf4j
@Component
@RequiredArgsConstructor
public class ReactLoop {

    private final AiAgentService agentService;
    private final AgentEventPublisher eventPublisher;
    private final com.mdframe.forge.plugin.ai.agent.engine.tool.ReactToolDispatcher toolDispatcher;
    private final AiModelInvocationRecorder invocationRecorder;
    private final ReactExecutionPool executions;

    /**
     * 执行 ReAct 循环
     */
    public Flux<AgentEvent> run(ReactContext ctx) {
        return run(ctx, () -> { });
    }

    public Flux<AgentEvent> run(ReactContext ctx, Runnable beforeStart) {
        Sinks.Many<AgentEvent> sink = Sinks.many().multicast().onBackpressureBuffer();

        // 最小对话埋点（task10）：requestId 与起始时间在请求线程生成，终止时统一记录一条调用观测
        String requestId = UUID.randomUUID().toString();
        long startedAtMs = System.currentTimeMillis();
        LoopTelemetry tel = new LoopTelemetry();

        ReactCancellation cancellation = executions.start(ctx, beforeStart, () -> {
            try {
                executeLoop(ctx, sink, tel);
            } catch (Exception e) {
                if (!ctx.isCancelled()) {
                    log.error("[ReactLoop] 循环异常: sessionId={}", ctx.getSessionId(), e);
                }
                tel.outcome = ctx.isCancelled() ? AiInvocationOutcome.CANCELLED : AiInvocationOutcome.FAILED;
                tel.phase = AiInvocationPhase.STREAMING;
                AgentEvent error = AgentEvent.of(ctx.getSessionId(), ctx.getTurnIndex(),
                        AgentEventType.AGENT_END, ctx.isCancelled() ? "{\"aborted\":true}"
                                : "{\"error\":\"" + escapeJson(e.getMessage()) + "\"}");
                // 先 publish 再 emit：确保持久化监听器（不依赖客户端订阅）能收到终止事件
                eventPublisher.publish(error);
                sink.tryEmitNext(error);
            } finally {
                // 埋点在所有退出路径统一收口（正常/错误/中断），失败不影响主流程
                recordTelemetry(ctx, requestId, startedAtMs, tel);
            }
        }, sink::tryEmitComplete);

        return sink.asFlux().doOnCancel(cancellation::cancel);
    }

    ReactContext activeContext(String sessionId) {
        return executions.activeContext(sessionId);
    }

    void cancel(ReactContext context) {
        executions.cancel(context);
    }

    private void executeLoop(ReactContext ctx, Sinks.Many<AgentEvent> sink, LoopTelemetry tel) {
        // 发送 AGENT_START
        AgentEvent startEvent = AgentEvent.of(ctx.getSessionId(), 0, AgentEventType.AGENT_START,
                "{\"agentCode\":\"" + ctx.getAgentCode() + "\"}");
        eventPublisher.publish(startEvent);
        sink.tryEmitNext(startEvent);

        // 如果有图片附件但模型可能不支持视觉，发送 HINT_BLOCK
        if (ctx.getImageFileIds() != null && !ctx.getImageFileIds().isEmpty()) {
            AgentEvent visionHint = AgentEvent.of(ctx.getSessionId(), 0, AgentEventType.HINT_BLOCK,
                    "{\"hint\":\"当前对话包含图片附件，请确认模型支持视觉能力。如不支持，图片内容将被忽略。\"}");
            eventPublisher.publish(visionHint);
            sink.tryEmitNext(visionHint);
        }

        int maxIters = ctx.getMaxIters();
        int turn = ctx.getTurnIndex();
        if (!ctx.getPendingToolCalls().isEmpty()) {
            if (!toolDispatcher.dispatch(ctx, ctx.getPendingToolCalls(), sink)) {
                tel.outcome = AiInvocationOutcome.CANCELLED;
                return;
            }
            turn++;
        }

        while (turn < maxIters) {
            if (ctx.isCancelled()) {
                tel.outcome = AiInvocationOutcome.CANCELLED;
                tel.phase = AiInvocationPhase.STREAMING;
                AgentEvent stopEvent = AgentEvent.of(ctx.getSessionId(), turn, AgentEventType.AGENT_END,
                        "{\"aborted\":true}");
                eventPublisher.publish(stopEvent);
                sink.tryEmitNext(stopEvent);
                return;
            }
            ctx.setTurnIndex(turn);

            // 1. Reason: 调用 LLM（流式消费，逐块发出 TEXT/THINKING delta）
            AgentEvent modelStart = AgentEvent.of(ctx.getSessionId(), turn, AgentEventType.MODEL_CALL_START,
                    "{\"turn\":" + turn + "}");
            eventPublisher.publish(modelStart);
            sink.tryEmitNext(modelStart);
            tel.dispatched = true;

            ChatResponse chatResponse;
            try {
                // 正文按 TEXT_BLOCK_START/DELTA/END 拆分，思考按 THINKING_BLOCK_DELTA 逐块发出
                chatResponse = callModel(ctx, sink, turn);
            } catch (Exception e) {
                if (ctx.isCancelled()) {
                    throw e;
                }
                tel.outcome = AiInvocationOutcome.FAILED;
                tel.phase = AiInvocationPhase.STREAMING;
                AgentEvent error = AgentEvent.of(ctx.getSessionId(), turn, AgentEventType.MODEL_CALL_END,
                        "{\"error\":\"" + escapeJson(e.getMessage()) + "\"}");
                eventPublisher.publish(error);
                sink.tryEmitNext(error);
                break;
            }

            // MODEL_CALL_END 附带用量（决策19：token_usage 保留，同时补充 usage JSON）
            String usageJson = buildUsageJson(chatResponse);
            applyUsage(chatResponse, tel);
            String modelEndData = usageJson != null
                    ? "{\"turn\":" + turn + ",\"usage\":" + usageJson + "}"
                    : "{\"turn\":" + turn + "}";
            AgentEvent modelEnd = AgentEvent.of(ctx.getSessionId(), turn, AgentEventType.MODEL_CALL_END, modelEndData);
            eventPublisher.publish(modelEnd);
            sink.tryEmitNext(modelEnd);

            // 2. 解析 LLM 响应（正文/思考已在流式阶段逐块发出，这里只取 tool_call）
            if (chatResponse == null || chatResponse.getResult() == null) {
                break;
            }
            AssistantMessage assistant = chatResponse.getResult().getOutput();
            List<AssistantMessage.ToolCall> toolCalls = assistant.getToolCalls();

            // 3. 无 tool_call → 循环结束
            if (toolCalls == null || toolCalls.isEmpty()) {
                break;
            }

            List<com.mdframe.forge.plugin.ai.agent.engine.hitl.PendingToolCall> calls = toolCalls.stream()
                    .map(call -> new com.mdframe.forge.plugin.ai.agent.engine.hitl.PendingToolCall(call.name(), call.arguments()))
                    .toList();
            if (!toolDispatcher.dispatch(ctx, calls, sink)) {
                tel.outcome = AiInvocationOutcome.CANCELLED;
                tel.phase = AiInvocationPhase.STREAMING;
                return;
            }

            turn++;
        }

        // 超过最大轮次
        if (turn >= maxIters) {
            AgentEvent exceed = AgentEvent.of(ctx.getSessionId(), turn, AgentEventType.EXCEED_MAX_ITERS,
                    "{\"maxIters\":" + maxIters + "}");
            eventPublisher.publish(exceed);
            sink.tryEmitNext(exceed);
            tel.outcome = AiInvocationOutcome.FAILED;
        }

        // 发送 AGENT_END
        AgentEvent endEvent = AgentEvent.of(ctx.getSessionId(), turn, AgentEventType.AGENT_END,
                "{\"turns\":" + turn + "}");
        eventPublisher.publish(endEvent);
        sink.tryEmitNext(endEvent);
    }

    /**
     * 流式调用模型：底层用 {@code chatModel.stream(prompt)}，在 loop 线程用 {@code toIterable()}
     * 阻塞拉取逐块消费——正文按 TEXT_BLOCK_START/DELTA/END 拆分发出，思考内容按 THINKING_BLOCK_DELTA 发出。
     * 消费过程中用 {@link MessageAggregator} 聚合出完整响应，供上层解析 tool_call 与用量（usage）。
     *
     * <p>所有事件仍在 loop 线程发射（toIterable 在当前线程拉取，不切线程），保持“事件发布均在
     * loop 线程”的不变量，与 HTTP 客户端连接生命周期无关。</p>
     */
    private ChatResponse callModel(ReactContext ctx, Sinks.Many<AgentEvent> sink, int turn) {
        ChatModel chatModel = ctx.getChatModel();

        // 工具声明：仅当 Agent 实际绑定了可用工具（当前=绑定知识库→rag_search）时才向模型声明工具。
        // 普通对话 Agent（无绑定）不带工具选项，行为与之前完全一致，零回归。
        // internalToolExecutionEnabled(false)：只声明不由 Spring AI 内部执行——工具执行仍由本 ReAct 循环自控。
        List<ToolCallback> toolCallbacks = resolveToolCallbacks(ctx);
        OpenAiChatOptions toolOptions = toolCallbacks.isEmpty() ? null : buildToolOptions(chatModel, toolCallbacks);
        Prompt prompt = toolOptions == null
                ? new Prompt(ctx.buildMessages())
                : new Prompt(ctx.buildMessages(), toolOptions);

        boolean[] textStarted = {false};
        AtomicReference<ChatResponse> aggregateRef = new AtomicReference<>();

        // MessageAggregator：透传原始 chunk，同时在流完成时回调聚合后的完整响应
        Flux<ChatResponse> stream = new MessageAggregator().aggregate(chatModel.stream(prompt), aggregateRef::set);
        try (java.util.stream.Stream<ChatResponse> chunks = stream.toStream()) {
            ctx.getCancellation().registerTransport(chunks::close);
            Iterator<ChatResponse> iterator = chunks.iterator();
            while (iterator.hasNext()) {
                ChatResponse chunk = iterator.next();
                if (ctx.isCancelled()) {
                    break;
                }
                publishModelChunk(ctx, sink, turn, chunk, textStarted);
            }
        } finally {
            ctx.getCancellation().registerTransport(null);
        }
        if (ctx.isCancelled()) {
            throw new java.util.concurrent.CancellationException("Agent execution cancelled");
        }
        // 有正文时收口 TEXT_BLOCK_END
        if (textStarted[0]) {
            AgentEvent textEnd = AgentEvent.of(ctx.getSessionId(), turn, AgentEventType.TEXT_BLOCK_END, null);
            eventPublisher.publish(textEnd);
            sink.tryEmitNext(textEnd);
        }

        return aggregateRef.get();
    }

    private void publishModelChunk(ReactContext ctx, Sinks.Many<AgentEvent> sink, int turn,
                                   ChatResponse chunk, boolean[] textStarted) {
        if (chunk == null || chunk.getResult() == null) {
            return;
        }
        AssistantMessage output = chunk.getResult().getOutput();
        String reasoning = extractReasoningContent(output);
        if (reasoning != null && !reasoning.isEmpty()) {
            AgentEvent thinking = AgentEvent.of(ctx.getSessionId(), turn, AgentEventType.THINKING_BLOCK_DELTA,
                    "{\"text\":\"" + escapeJson(reasoning) + "\"}");
            eventPublisher.publish(thinking);
            sink.tryEmitNext(thinking);
        }
        String text = output.getText();
        if (text != null && !text.isEmpty()) {
            if (!textStarted[0]) {
                AgentEvent start = AgentEvent.of(ctx.getSessionId(), turn, AgentEventType.TEXT_BLOCK_START, null);
                eventPublisher.publish(start);
                sink.tryEmitNext(start);
                textStarted[0] = true;
            }
            AgentEvent delta = AgentEvent.of(ctx.getSessionId(), turn, AgentEventType.TEXT_BLOCK_DELTA,
                    "{\"text\":\"" + escapeJson(text) + "\"}");
            eventPublisher.publish(delta);
            sink.tryEmitNext(delta);
        }
    }

    /**
     * 从模型 metadata 提取思考内容（reasoning）。兼容 reasoningContent / reasoning_content /
     * reasoning 三种键，与 {@code AiClientImpl} 保持一致。
     */
    private String extractReasoningContent(AssistantMessage message) {
        if (message == null || message.getMetadata() == null) {
            return null;
        }
        Map<String, Object> metadata = message.getMetadata();
        for (String key : new String[]{"reasoningContent", "reasoning_content", "reasoning"}) {
            Object v = metadata.get(key);
            if (v instanceof String s) {
                return s;
            }
        }
        return null;
    }

    /**
     * 从聚合响应提取用量 JSON（决策19）。无用量返回 null，不写入 MODEL_CALL_END。
     */
    private String buildUsageJson(ChatResponse resp) {
        try {
            if (resp == null || resp.getMetadata() == null) {
                return null;
            }
            Usage usage = resp.getMetadata().getUsage();
            if (usage == null) {
                return null;
            }
            Long prompt = toLong(usage.getPromptTokens());
            Long completion = toLong(usage.getCompletionTokens());
            Long total = toLong(usage.getTotalTokens());
            if (prompt == null && completion == null && total == null) {
                return null;
            }
            return "{\"promptTokens\":" + prompt + ",\"completionTokens\":" + completion
                    + ",\"totalTokens\":" + total + "}";
        } catch (Exception e) {
            log.debug("[ReactLoop] 用量解析跳过: {}", e.getMessage());
            return null;
        }
    }

    private Long toLong(Number number) {
        return number == null ? null : number.longValue();
    }

    /**
     * 把聚合响应的用量写入埋点累加器（决策19 + task10）。多轮时以最后一轮为准，解析异常静默跳过。
     */
    private void applyUsage(ChatResponse resp, LoopTelemetry tel) {
        try {
            if (resp == null || resp.getMetadata() == null) {
                return;
            }
            Usage usage = resp.getMetadata().getUsage();
            if (usage == null) {
                return;
            }
            tel.promptTokens = toLong(usage.getPromptTokens());
            tel.completionTokens = toLong(usage.getCompletionTokens());
            tel.totalTokens = toLong(usage.getTotalTokens());
        } catch (Exception e) {
            log.debug("[ReactLoop] 用量埋点跳过: {}", e.getMessage());
        }
    }

    /**
     * 最小对话埋点（task10）：在循环所有退出路径统一记录一条调用观测，复用 {@link AiModelInvocationRecorder}。
     * 引擎侧不解析路由/供应商/模型/定价，这些字段置空；至少覆盖发送(dispatched)、完成/错误/中断(outcome)、
     * token 用量与总耗时(latency)。埋点失败绝不影响主流程。
     */
    private void recordTelemetry(ReactContext ctx, String requestId, long startedAtMs, LoopTelemetry tel) {
        try {
            long latency = System.currentTimeMillis() - startedAtMs;
            if (latency < 0) {
                latency = 0;
            }
            Long tenantId = ctx.getTenantId() != null ? ctx.getTenantId() : 1L;
            AiInvocationObservation obs = new AiInvocationObservation(
                    requestId, tenantId, ctx.getUserId(), ctx.getAgentCode(), ctx.getSessionId(),
                    tel.phase, tel.dispatched, tel.outcome,
                    null, null, null,
                    null, null, null, null,
                    null, null, null,
                    latency, tel.promptTokens, tel.completionTokens, tel.totalTokens,
                    null, null);
            invocationRecorder.record(obs);
        } catch (Exception e) {
            log.debug("[ReactLoop] 对话埋点记录跳过: sessionId={}, {}", ctx.getSessionId(), e.getMessage());
        }
    }

    /**
     * 单次 run 的埋点累加器：全程在同一 loop 线程内读写，无需同步。
     * 默认视为成功完成；发生模型错误/超限时置 FAILED，HITL 中断置 CANCELLED。
     */
    private static class LoopTelemetry {
        private boolean dispatched = false;
        private AiInvocationOutcome outcome = AiInvocationOutcome.SUCCESS;
        private AiInvocationPhase phase = AiInvocationPhase.COMPLETED;
        private Long promptTokens;
        private Long completionTokens;
        private Long totalTokens;
    }

    /**
     * 解析当前 Agent 应向模型声明的工具，封装为 Spring AI {@link ToolCallback}（仅携带定义，不承担执行）。
     * 空列表表示本次不声明任何工具（普通对话 Agent）。
     */
    private List<ToolCallback> resolveToolCallbacks(ReactContext ctx) {
        List<AgentTool> tools = resolveAdvertisedTools(ctx);
        if (tools.isEmpty()) {
            return Collections.emptyList();
        }
        List<ToolCallback> callbacks = new ArrayList<>(tools.size());
        for (AgentTool tool : tools) {
            callbacks.add(new AdvertisedToolCallback(tool));
        }
        return callbacks;
    }

    /**
     * 计算当前 Agent 需向模型声明的工具列表。
     * <p>工具来源已由 {@code AgentEngineService.buildContext} 解析注入到 {@link ReactContext#getBoundTools()}：
     * 工具绑定表 {@code ai_agent_tool_config}(enabled=1) + 知识库绑定兜底(builtin:rag_search)。
     * 这里直接取用，不再在循环内重复解析，职责单一。</p>
     * <p>空列表表示本次不声明任何工具（普通对话 Agent），{@code callModel} 走无工具路径，行为与历史一致。</p>
     */
    private List<AgentTool> resolveAdvertisedTools(ReactContext ctx) {
        List<AgentTool> bound = ctx.getBoundTools();
        return bound == null ? Collections.emptyList() : bound;
    }

    /**
     * 按 ChatModel 类型构造携带工具声明的选项。
     * <p>只为 {@link OpenAiChatModel}（含所有 OpenAI 兼容供应商）构造 {@link OpenAiChatOptions}；
     * 必须传具体的 OpenAiChatOptions（而非通用接口），否则 Spring AI 的选项合并会因 toolCallbacks 被
     * {@code @JsonIgnore} 而丢弃工具。其它模型（如 DashScope 原生）返回 null，即本次不带工具选项，
     * 行为与之前一致（该路径暂不支持工具声明，属后续可扩展项）。</p>
     */
    private OpenAiChatOptions buildToolOptions(ChatModel chatModel, List<ToolCallback> toolCallbacks) {
        if (chatModel instanceof OpenAiChatModel) {
            return OpenAiChatOptions.builder()
                    .toolCallbacks(toolCallbacks)
                    .internalToolExecutionEnabled(false)
                    .build();
        }
        log.debug("[ReactLoop] 当前 ChatModel 非 OpenAI 兼容，跳过工具声明: {}",
                chatModel != null ? chatModel.getClass().getSimpleName() : "null");
        return null;
    }

    /**
     * 只用于「向模型声明工具」的 {@link ToolCallback} 包装：仅携带工具定义（name/description/inputSchema），
     * 不承担执行。工具执行由本 {@link ReactLoop} 自控循环负责，调用侧已设置
     * {@code internalToolExecutionEnabled(false)}，Spring AI 不会触发这里的 {@link #call}。
     */
    private static final class AdvertisedToolCallback implements ToolCallback {
        private final ToolDefinition definition;

        AdvertisedToolCallback(AgentTool tool) {
            this.definition = ToolDefinition.builder()
                    .name(tool.getKey())
                    .description(tool.getDescription())
                    .inputSchema(tool.getParametersSchema())
                    .build();
        }

        @Override
        public ToolDefinition getToolDefinition() {
            return definition;
        }

        @Override
        public String call(String toolInput) {
            // 自控循环：工具执行由 ReactLoop 负责，Spring AI 不应内部执行（internalToolExecutionEnabled=false）
            throw new UnsupportedOperationException("Tool execution is handled by ReactLoop, not Spring AI");
        }
    }

    private String escapeJson(String text) {
        if (text == null) return "";
        return text.replace("\\", "\\\\").replace("\"", "\\\"").replace("\n", "\\n").replace("\r", "\\r");
    }
}
