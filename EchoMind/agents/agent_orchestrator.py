"""
亮点：多 Agent 路由与编排

核心问题：多 Agent 情况下如何做 Routing？

路由策略（三层决策）：
  1. 意图路由 —— 根据 IntentCategory 直接映射到专属 Agent
  2. 性能路由 —— 同类 Agent 有多个时，选成功率最高、延迟最低的
  3. 降级路由 —— 专属 Agent 不可用时，自动降级到 GeneralAgent

并行协作：
  - 复杂问题（如"TDoc 摘要 + Gap 分析"）可同时派发给多个 Agent
  - 结果由 Orchestrator 合并后返回

升级机制：
  - Agent 置信度低于阈值 → 自动降级或提示补充标准任务上下文
"""
import asyncio
import logging
import time
import uuid
from dataclasses import dataclass, field
from enum import Enum
from typing import Any, Dict, List, Optional

from anthropic import AsyncAnthropic

from core.intent_recognizer import IntentCategory, IntentRecognizer, UrgencyLevel

logger = logging.getLogger(__name__)


# ── 数据结构 ──────────────────────────────────────────────────────────────────

class AgentType(Enum):
    GENERAL          = "general"           # 通用标准文稿助手
    STANDARD_ANALYST = "standard_analyst"  # 标准问题与 Gap 分析
    TDOC_ANALYST     = "tdoc_analyst"      # TDoc 文稿分析
    PROPOSAL_WRITER  = "proposal_writer"   # 标准提案写作
    REVIEW_DEFENSE   = "review_defense"    # 会议审查与攻防


@dataclass
class AgentStats:
    """Agent 运行时统计，供 Monitor 和路由决策使用。"""
    total:     int   = 0
    success:   int   = 0
    total_ms:  float = 0.0
    monitor_penalty: float = 0.0

    @property
    def success_rate(self) -> float:
        return self.success / self.total if self.total else 1.0

    @property
    def avg_ms(self) -> float:
        return self.total_ms / self.total if self.total else 0.0

    def routing_score(self) -> float:
        """路由评分：成功率高、延迟低的 Agent 得分高。"""
        latency_score = 1.0 / (1.0 + self.avg_ms / 1000)
        base_score = self.success_rate * 0.7 + latency_score * 0.3
        return base_score * max(0.0, 1.0 - self.monitor_penalty)


@dataclass
class AgentResponse:
    agent_type:  AgentType
    content:     str
    success:     bool
    confidence:  float = 1.0
    latency_ms:  float = 0.0
    escalate:    bool  = False   # 是否需要升级


@dataclass
class Request:
    message:     str
    user_id:     str
    conv_id:     str
    context:     str = ""        # 来自 MemoryManager 的格式化上下文
    history:     Optional[List[Dict[str, str]]] = None  # 对话历史，传给意图识别
    intent:      Optional[IntentCategory] = None
    urgency:     Optional[UrgencyLevel]   = None
    request_id:  str = field(default_factory=lambda: str(uuid.uuid4())[:8])


@dataclass
class OrchestratorResult:
    request_id:  str
    response:    str
    agent_type:  AgentType
    intent:      Optional[IntentCategory]
    escalated:   bool  = False
    latency_ms:  float = 0.0


# ── 基础 Agent ────────────────────────────────────────────────────────────────

class BaseAgent:
    """所有 Agent 的基类，封装 LLM 调用和统计。"""

    agent_type: AgentType
    system_prompt: str

    def __init__(self, client: AsyncAnthropic, model: str, skill_manager: Optional[Any] = None):
        self._client = client
        self._model  = model
        self._skill_manager = skill_manager
        self.stats   = AgentStats()

    async def handle(self, req: Request) -> AgentResponse:
        t0 = time.monotonic()
        self.stats.total += 1
        try:
            content = await self._call_llm(req)
            ms = (time.monotonic() - t0) * 1000
            self.stats.success += 1
            self.stats.total_ms += ms
            escalate = self._needs_escalation(content)
            return AgentResponse(
                agent_type=self.agent_type,
                content=content,
                success=True,
                latency_ms=ms,
                escalate=escalate,
            )
        except Exception as ex:
            ms = (time.monotonic() - t0) * 1000
            self.stats.total_ms += ms
            logger.error(f"{self.agent_type.value} 处理失败: {ex}")
            return AgentResponse(
                agent_type=self.agent_type,
                content="抱歉，处理标准文稿任务时出现问题，请稍后重试。",
                success=False,
                latency_ms=ms,
            )

    async def _call_llm(self, req: Request) -> str:
        def _clean(s: str) -> str:
            return s.encode("utf-8", errors="ignore").decode("utf-8")

        messages = []
        if req.context:
            messages.append({"role": "user", "content": f"[背景信息]\n{_clean(req.context)}"})
            messages.append({"role": "assistant", "content": "好的，我已了解背景信息。"})
        messages.append({"role": "user", "content": _clean(req.message)})

        resp = await self._client.messages.create(
            model=self._model,
            max_tokens=1024,
            system=self._build_system_prompt(req),
            messages=messages,
        )
        return resp.content[0].text

    def _build_system_prompt(self, req: Request) -> str:
        """把动态加载的 Skills 拼入 system prompt，让业务规则随请求生效。"""
        if self._skill_manager is None:
            return self.system_prompt
        skill_prompt = self._skill_manager.prompt_for(req.message, self.agent_type.value)
        if not skill_prompt:
            return self.system_prompt
        return f"{self.system_prompt}\n\n[动态 Skills]\n{skill_prompt}"

    def _needs_escalation(self, content: str) -> bool:
        """检测 Agent 是否建议升级（简单关键词检测）。"""
        keywords = ["补充证据", "人工确认", "escalate", "specialist", "无法处理"]
        return any(kw in content for kw in keywords)


class GeneralAgent(BaseAgent):
    agent_type    = AgentType.GENERAL
    system_prompt = (
        "你是 StandardPilot 通信标准文稿处理助手。你可以帮助用户理解 3GPP 标准、"
        "TDoc、会议材料和标准提案流程。如果用户问题不明确，请引导用户补充 "
        "WG、Release、Agenda、TDoc ID、目标公司或目标任务。"
    )


class StandardAnalystAgent(BaseAgent):
    agent_type    = AgentType.STANDARD_ANALYST
    system_prompt = (
        "你是通信标准问题分析专家，擅长围绕一个标准化 topic 综合分析 3GPP TS/TR、"
        "历史 TDoc 摘要和知识库证据，判断现有标准机制是否已经覆盖该问题、是否存在标准化空白，"
        "以及该问题是否值得进入 SA2/RAN/CT 等工作组讨论。你的重点不是总结单篇 TDoc，而是做跨文档、"
        "跨机制的标准化判断。输出应尽量包括：1. 已有标准机制 2. 现有机制覆盖范围 3. 可能存在的标准化 Gap "
        "4. 标准化价值 5. 推进风险与会议 challenge。回答必须区分：已有证据、合理推断、待确认内容。"
        "不要编造标准条款、TDoc ID 或公司立场。"
    )


class TDocAnalystAgent(BaseAgent):
    agent_type    = AgentType.TDOC_ANALYST
    system_prompt = (
        "你是 TDoc 文稿分析专家，擅长对单篇或一组 TDoc 进行内容抽取和结构化摘要。"
        "你的重点是读懂文稿本身，而不是判断整个标准方向是否值得立项。你需要从 TDoc 中提取："
        "1. Background 2. Problem 3. Proposed Solution 4. Impacted Entities / Procedures "
        "5. Company / Source 6. Agenda / Meeting / TDoc ID 7. Open Issues 8. Potential Controversies。"
        "如果文稿中没有明确出现公司、会议、Agenda 或 TDoc ID，必须标记为“未知”或“待确认”，不要编造。"
    )


class ProposalWriterAgent(BaseAgent):
    agent_type    = AgentType.PROPOSAL_WRITER
    system_prompt = (
        "你是通信标准提案写作助手，擅长生成 TDoc 草稿。输出结构应包含 Title、Background、"
        "Discussion、Proposal、Conclusion。不要编造 TDoc ID，不要强行使用 shall，不要把具体算法写进标准。"
        "研究阶段优先使用 may / study whether / it is proposed to study。"
    )


class ReviewDefenseAgent(BaseAgent):
    agent_type    = AgentType.REVIEW_DEFENSE
    system_prompt = (
        "你是标准会议审查和攻防助手，负责检查提案是否缺少证据、是否新增 NF 过重、"
        "是否超出 WG scope、是否把实现问题写成标准问题，并生成可能的会议 challenge 和建议回答。"
    )


# ── 编排器 ────────────────────────────────────────────────────────────────────

class AgentOrchestrator:
    """
    多 Agent 编排器。

    路由逻辑（三层）：
      1. 意图 → Agent 类型映射
      2. 同类多实例时按 routing_score() 选最优
      3. 专属 Agent 失败时降级到 GeneralAgent
    """

    # 意图 → Agent 类型的静态映射（路由表）
    _INTENT_ROUTING: Dict[IntentCategory, AgentType] = {
        IntentCategory.STANDARD_QA:          AgentType.STANDARD_ANALYST,
        IntentCategory.TDOC_SUMMARY:         AgentType.TDOC_ANALYST,
        IntentCategory.GAP_ANALYSIS:         AgentType.STANDARD_ANALYST,
        IntentCategory.PROPOSAL_DRAFT:       AgentType.PROPOSAL_WRITER,
        IntentCategory.REVIEW_DEFENSE:       AgentType.REVIEW_DEFENSE,
        IntentCategory.KNOWLEDGE_MANAGEMENT: AgentType.GENERAL,
    }


    def __init__(
        self,
        api_key:  str,
        base_url: Optional[str] = None,
        model:    str = "claude-3-5-sonnet-20241022",
        skill_manager: Optional[Any] = None,
    ):
        kwargs: Dict[str, Any] = {"api_key": api_key}
        if base_url:
            kwargs["base_url"] = base_url
        client = AsyncAnthropic(**kwargs)

        self._intent_recognizer = IntentRecognizer(api_key=api_key, base_url=base_url, model=model)
        self._skill_manager = skill_manager

        # Agent 池：每种类型可有多个实例（水平扩展）
        self._pool: Dict[AgentType, List[BaseAgent]] = {
            AgentType.GENERAL:          [GeneralAgent(client, model, skill_manager)],
            AgentType.STANDARD_ANALYST: [StandardAnalystAgent(client, model, skill_manager)],
            AgentType.TDOC_ANALYST:     [TDocAnalystAgent(client, model, skill_manager)],
            AgentType.PROPOSAL_WRITER:  [ProposalWriterAgent(client, model, skill_manager)],
            AgentType.REVIEW_DEFENSE:   [ReviewDefenseAgent(client, model, skill_manager)],
        }

    def set_skill_manager(self, skill_manager: Optional[Any]) -> None:
        """更新 SkillManager 引用，供运行时重载或测试替换使用。"""
        self._skill_manager = skill_manager
        for agents in self._pool.values():
            for agent in agents:
                agent._skill_manager = skill_manager

    # ── 主入口 ────────────────────────────────────────────────────────────────

    async def run(self, req: Request) -> OrchestratorResult:
        """
        处理一次请求的完整流程：
          意图识别 → 路由选 Agent → 执行 → 检查升级 → 返回结果
        """
        t0 = time.monotonic()

        # 1. 意图识别（如果调用方已识别则跳过）
        if req.intent is None:
            intent_result = await self._intent_recognizer.recognize(req.message, history=req.history)
            req.intent  = intent_result.intent
            req.urgency = intent_result.urgency

        # 复杂问题自动并行协作，例如同一句同时涉及 TDoc 摘要和 Gap 分析。
        collaboration = self._collaboration_targets(req)
        if len(collaboration) > 1:
            return await self.run_parallel(req, collaboration)

        # 2. 路由：选择 Agent 类型
        agent_type = self._route(req.intent, req.urgency)

        # 3. 执行（含降级）
        response = await self._execute(req, agent_type)

        # 4. 升级检查
        escalated = False
        if response.escalate or req.urgency == UrgencyLevel.CRITICAL :
            escalated = True
            logger.warning(f"请求 {req.request_id} 触发升级: urgency={req.urgency}")
            # 生产环境：此处可记录待确认事项、通知标准专家或补充证据流程

        return OrchestratorResult(
            request_id=req.request_id,
            response=response.content,
            agent_type=response.agent_type,
            intent=req.intent,
            escalated=escalated,
            latency_ms=(time.monotonic() - t0) * 1000,
        )

    async def run_parallel(self, req: Request, agent_types: List[AgentType]) -> OrchestratorResult:
        """
        并行派发给多个 Agent，合并结果。
        适用于复杂问题（如同时涉及 TDoc 摘要和标准化 Gap 分析）。
        """
        t0 = time.monotonic()
        tasks = [self._execute(req, at) for at in agent_types]
        responses = await asyncio.gather(*tasks, return_exceptions=True)

        # 合并：拼接所有成功响应
        parts = []
        for r in responses:
            if isinstance(r, AgentResponse) and r.success:
                parts.append(f"[{r.agent_type.value}]\n{r.content}")

        combined = "\n\n".join(parts) if parts else "抱歉，所有标准文稿处理 Agent 均处理失败。"
        escalated = any(isinstance(r, AgentResponse) and r.escalate for r in responses)

        return OrchestratorResult(
            request_id=req.request_id,
            response=combined,
            agent_type=agent_types[0],
            intent=req.intent,
            escalated=escalated,
            latency_ms=(time.monotonic() - t0) * 1000,
        )

    # ── 路由逻辑 ──────────────────────────────────────────────────────────────

    def _route(self, intent: Optional[IntentCategory], urgency: Optional[UrgencyLevel]) -> AgentType:
        """
        三层路由决策：
          1. 意图映射
          2. 紧急度覆盖（CRITICAL 直接升级）
          3. 默认 GENERAL
        """
        if urgency == UrgencyLevel.CRITICAL:
            return AgentType.REVIEW_DEFENSE

        if intent and intent in self._INTENT_ROUTING:
            target = self._INTENT_ROUTING[intent]
            # 如果目标类型有可用实例则使用，否则降级
            if target in self._pool and self._pool[target]:
                return target

        return AgentType.GENERAL

    def _collaboration_targets(self, req: Request) -> List[AgentType]:
        """判断是否需要多个 Agent 并行协作，例如同一句同时要求 TDoc 摘要和 Gap 分析。"""
        msg = req.message.lower()
        targets: List[AgentType] = []

        tdoc_kws = ["tdoc", "总结", "摘要", "文稿", "background", "proposed solution"]
        gap_kws = ["gap", "标准化价值", "是否覆盖", "标准问题", "实现问题", "challenge"]

        if req.intent == IntentCategory.TDOC_SUMMARY or any(kw in msg for kw in tdoc_kws):
            targets.append(AgentType.TDOC_ANALYST)
        if req.intent in (IntentCategory.GAP_ANALYSIS, IntentCategory.STANDARD_QA, IntentCategory.REVIEW_DEFENSE) or any(kw in msg for kw in gap_kws):
            targets.append(self._route(req.intent, req.urgency))

        deduped = list(dict.fromkeys(targets))
        return [agent_type for agent_type in deduped if self._pool.get(agent_type)]

    def _best_agent(self, agent_type: AgentType) -> Optional[BaseAgent]:
        """
        性能路由：从同类 Agent 中选 routing_score() 最高的。
        这是"基于在线表现动态调整路由"的核心。
        """
        agents = self._pool.get(agent_type, [])
        if not agents:
            return None
        return max(agents, key=lambda a: a.stats.routing_score())

    async def _execute(self, req: Request, agent_type: AgentType) -> AgentResponse:
        """执行 Agent，失败时降级到 GeneralAgent。"""
        agent = self._best_agent(agent_type)
        if agent is None:
            agent = self._best_agent(AgentType.GENERAL)
        if agent is None:
            return AgentResponse(
                agent_type=AgentType.GENERAL,
                content="StandardPilot 服务暂时不可用，请稍后重试。",
                success=False,
            )

        response = await agent.handle(req)

        # 专属 Agent 失败时降级到 GeneralAgent
        if not response.success and agent_type != AgentType.GENERAL:
            logger.warning(f"{agent_type.value} 失败，降级到 GeneralAgent")
            fallback = self._best_agent(AgentType.GENERAL)
            if fallback:
                response = await fallback.handle(req)

        return response

    # ── 统计（供 Monitor 读取）────────────────────────────────────────────────

    def get_stats(self) -> Dict[str, Any]:
        result = {}
        for agent_type, agents in self._pool.items():
            for i, agent in enumerate(agents):
                key = f"{agent_type.value}_{i}"
                result[key] = {
                    "total":        agent.stats.total,
                    "success_rate": round(agent.stats.success_rate, 3),
                    "avg_ms":       round(agent.stats.avg_ms, 1),
                    "monitor_penalty": round(agent.stats.monitor_penalty, 3),
                    "routing_score": round(agent.stats.routing_score(), 3),
                }
        return result

    def update_routing_penalties(self, penalties: Dict[str, float]) -> None:
        """
        接收 Monitor 的在线表现反馈，动态调整路由惩罚项。

        penalties 的 key 使用 get_stats() 中的 agent key，例如 technical_0。
        """
        for agent_type, agents in self._pool.items():
            for i, agent in enumerate(agents):
                key = f"{agent_type.value}_{i}"
                penalty = penalties.get(key, 0.0)
                agent.stats.monitor_penalty = min(max(penalty, 0.0), 0.9)
