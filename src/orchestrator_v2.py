"""
自我修正协调器：SelfCorrectingOrchestrator

功能：
    整合所有新组件，执行"规划 → 注入 → 生成 → 验证 → 诊断 → 修复"的完整主循环。
    三层修复策略（local_rewrite / partial_rollback / memory_purge）由 MRSD 诊断结果驱动。
    MetaState 提供元认知门控，MetricCollector 收集内部机制指标。

依赖：Generator、SectionPlanner、DiscourseLedger、CommitmentExtractor、DTGStore、
      OnlineValidator、MRSD、EmbeddingModel、NLIModel、MetaState、PlanState、MetricCollector、
      CorrectionLog
被依赖：main.py
"""
from __future__ import annotations

import logging
import re
from pathlib import Path
from typing import Any, Dict, List, Optional, Tuple

from rich.console import Console
from rich.panel import Panel

from .agents.generator import Generator
from .agents.section_planner import SectionPlanner
from .algorithms.mrsd import MRSD
from .core.decision import Decision
from .core.ledger import CommitmentType
from .core.meta_state import MetaState
from .core.plan import PlanState, SectionIntent
from .core.state import GenerationState
from .core.validation import failure_description
from .evaluation.metric_collector import MetricCollector
from .logging.correction_log import CorrectionLog
from .logging.run_logger import RunLogger
from .memory.commitment_extractor import CommitmentExtractor
from .memory.discourse_ledger import DiscourseLedger
from .memory.dtg_store import DTGStore
from .memory.history_corpus import HistoryCorpus, HistoryItem
from .memory.history_retriever import HistoryRetriever
from .references.corpus import CorpusLoader
from .references.retriever import HyDERetriever
from .references.types import GlobalPaperEntry, GlobalPaperIndex
from .metrics.coverage_scorer import TopicCoverageScorer
from .utils.embedding_model import EmbeddingModel
from .utils.nli_model import NLIModel
from .validators.online_validator import OnlineValidator


class SelfCorrectingOrchestrator:
    """
    自我修正协调器

    功能：
        1. 主循环：逐节规划 → DSL 注入 → 生成 → 验证 → MRSD 诊断 → 三层修复
        2. MetaState 元认知门控：gate_action() 控制 trust_validator_major / allow_rollback / strengthen_dsl_injection 三类动作
        3. DiscourseLedger 动态约束管理：salience 显著性驱动的条目注入
        4. MetricCollector 指标收集：不改变系统行为，仅记录

    参数：
        llm_client: LLM 客户端实例
        memory_path: DTG 存储路径（默认 ./sessions）
        session_name: 会话名称，用于文件命名和自动清理

    关键常数：
        MAX_RETRIES_PER_SECTION = 3
        MAX_ROLLBACKS = 5
        TCAS_THRESHOLD = 0.6
    """

    MAX_RETRIES_PER_SECTION = 3
    MAX_ROLLBACKS = 5
    TCAS_THRESHOLD = 0.6
    DSL_RELATION_MAX_PAIRS_PER_SECTION = 8
    DSL_RELATION_BATCH_SIZE = 4
    DSL_RELATION_MIN_CONFIDENCE = 0.5

    def __init__(
        self,
        llm_client,
        memory_path: str = "./sessions",
        session_name: str = "session",
        output_dir: str = "./outputs",
        corpus_dir: str = "./data_sample/med_papers",
        memory_mode: str = "baseline_ref_rrf",
    ):
        """
        初始化自我修正协调器

        功能：
            创建并连接所有子组件，MetaState 初始化为信任状态。
            同时把 output_dir 传给 RunLogger，保证主入口与运行日志落盘目录一致。

        参数：
            llm_client: LLM 客户端实例
            memory_path: DTG 存储路径
            session_name: 会话名称
            output_dir: 输出目录（运行日志和相关工件的统一落盘位置）
            corpus_dir: 论文数据集目录（Markdown paper corpus）
        """
        self.llm_client       = llm_client
        memory_mode_aliases = {
            "history_rrf": "history_dense",
            "history_rrf_quota": "history_dense_quota",
        }
        memory_mode = memory_mode_aliases.get(memory_mode, memory_mode)
        if memory_mode not in ("baseline_ref_rrf", "history_dense", "history_dense_quota"):
            raise ValueError(
                "memory_mode must be one of: baseline_ref_rrf, history_dense, history_dense_quota"
            )
        self.memory_mode      = memory_mode
        self.dtg              = DTGStore(memory_path, session_name=session_name)
        self.meta_state       = MetaState()
        self.console          = Console()
        self.logger           = logging.getLogger(__name__)
        self.run_logger       = RunLogger(output_dir=output_dir, session_name=session_name)
        self.dsl              = DiscourseLedger(llm_client=llm_client, run_logger=self.run_logger)

        llm_client.attach_run_logger(self.run_logger)

        # EmbeddingModel / NLIModel 作为全局单例，所有组件共享同一实例
        self._embed_model = EmbeddingModel()
        self._nli_model   = NLIModel()

        self.generator        = Generator(llm_client, run_logger=self.run_logger)
        self.section_planner  = SectionPlanner(llm_client, self.dtg)
        self.commitment_extractor = CommitmentExtractor(llm_client)
        self.online_validator = OnlineValidator(
            embedding_model=self._embed_model,
            nli_model=self._nli_model,
            dtg_store=self.dtg,
            meta_state=self.meta_state,
            llm_client=llm_client,
            run_logger=self.run_logger,
        )
        self.mrsd = MRSD(dtg_store=self.dtg, embedding_model=self._embed_model)
        self.correction_log   = CorrectionLog()
        self.metric_collector = MetricCollector()
        self._corpus = CorpusLoader(corpus_dir, self._embed_model)
        self.retriever = HyDERetriever(self._corpus)
        self.retriever.attach_run_logger(self.run_logger)
        self.history_corpus_path = Path(memory_path) / f"{session_name}_history_corpus.json"
        self.history_corpus = HistoryCorpus(embed_model=self._embed_model)
        self.history_retriever = HistoryRetriever(self.history_corpus)
        self.last_chunk_map: List[Dict[str, Any]] = []
        self.last_citation_manifest: List[Dict[str, Any]] = []

    # ------------------------------------------------------------------
    # 主入口
    # ------------------------------------------------------------------

    def generate_with_self_correction(
        self,
        task: str,
        constraints: List[str],
        outline: Dict[str, str],
        reference: Optional[Dict[str, Any]] = None,
    ) -> Tuple[str, List[Decision], CorrectionLog]:
        """
        自我修正生成（主方法）

        功能：
            主循环：对每节执行"规划→注入→生成→验证→诊断→修复"。
            失败时调用 MRSD 获取诊断结果，根据 repair_scope 选择修复策略。

        参数：
            task: 生成任务描述
            constraints: 全局约束列表（IMMUTABLE 类型）
            outline: 有序章节大纲 {section_id: section_title}

        返回值：
            Tuple[str, List[Decision], CorrectionLog]：
                (最终文本, 决策列表, 修正日志)
        """
        self._print_header(task, outline)
        self.run_logger.log_run_start(task, constraints, outline)

        try:
            state = self._initialize_state(constraints, outline)
            plan_state = PlanState(global_outline=outline)
            generated_content: Dict[str, str] = {}
            section_queue = list(outline.keys())

            global_index = self.retriever.retrieve_global(task)
            self.logger.info("全局参考索引构建完成：%d 篇论文", global_index.n)
            if self.run_logger is not None:
                self.run_logger.log_global_index(global_index)

            section_word_targets = self._resolve_section_word_targets(
                task=task,
                outline=outline,
                reference=reference,
            )
            self.logger.info("分节目标词数：%s", section_word_targets)

            rollback_count = 0
            current_idx = 0

            # 节级别的诊断跟踪
            consecutive_failures_this_section = 0
            last_purge_succeeded = False
            last_diagnosis_event_id: Optional[str] = None
            last_diagnosis_tier: Optional[str] = None  # 上一次诊断的 error_tier，供 MetaState 更新准确率

            while current_idx < len(section_queue):
                section_id = section_queue[current_idx]
                state.current_section = section_id
                section_title = outline[section_id]

                self._print_section_start(section_id, section_title, current_idx, len(section_queue))
                if self.run_logger is not None:
                    self.run_logger.log_section_start(
                        section_id,
                        section_title,
                        current_idx,
                        len(section_queue),
                        state,
                        len(self.dsl.get_active_entries()),
                    )

                # 第一阶段：规划当前节（SectionPlanner）
                section_word_target = section_word_targets.get(section_id)
                section_intent = self._plan_section(
                    section_id=section_id,
                    section_title=section_title,
                    task=task,
                    plan_state=plan_state,
                    word_target=section_word_target,
                )
                plan_state.add_intent(section_intent)
                if self.run_logger is not None:
                    self.run_logger.log_planning(section_id, section_intent)

                # 提前提取 required_topics：用任务描述 + 节标题提取核心主题词，
                # 生成后注入 Decision，供 OnlineValidator 覆盖率检查使用
                required_topics = self.section_planner.extract_required_topics(
                    section_title=section_title,
                    task_description=task,
                )

                # 准备 DSL 注入
                self._update_dsl_injection(state, section_id, section_queue, current_idx)
                section_papers = self.retriever.rank_for_section(
                    global_index=global_index,
                    section_title=section_title,
                    section_intent=section_intent,
                    task=task,
                )
                self._prepare_history_context(
                    state=state,
                    section_id=section_id,
                    section_title=section_title,
                    section_intent=section_intent,
                    task=task,
                    constraints=constraints,
                )

                rolled_back = False
                report = None
                content: Optional[str] = None
                decision: Optional[Decision] = None
                last_failure_reason: Optional[str] = None
                citation_retry_hint: Optional[str] = None  # 每节重置；引用失败后由验证路径填充
                length_retry_hint: Optional[str] = None    # 每节重置；长度验证失败后由验证路径填充
                _section_tier_failures: Dict[str, int] = {}  # 当前节内各 error_tier 的失败次数

                for attempt in range(self.MAX_RETRIES_PER_SECTION):
                    # 第二阶段：生成
                    temperature = self._get_temperature(consecutive_failures_this_section)
                    if self.run_logger is not None:
                        self.run_logger.log_attempt_start(section_id, attempt + 1, temperature)
                    try:
                        content, decision = self.generator.generate_with_decision(
                            state=state,
                            task=task,
                            recent_content=self._get_recent_content(),
                            section_intent=section_intent,
                            temperature=temperature,
                            section_papers=section_papers,
                            citation_retry_hint=citation_retry_hint,
                            length_retry_hint=length_retry_hint,
                        )
                    except Exception as e:
                        self.logger.error("生成异常（section=%s attempt=%d）: %s", section_id, attempt + 1, e)
                        consecutive_failures_this_section += 1
                        last_failure_reason = "generator_parse_failure"
                        self.correction_log.add_retry(section_id, attempt + 1, "RETRY_SIMPLE", [str(e)])
                        continue

                    # 将 required_topics 注入 Decision，供 OnlineValidator 覆盖率检查消费
                    decision.required_topics = required_topics

                    # 第二点五阶段：引用注入
                    # 在验证前，若 content 中无 [Rx] 标记，执行专项引用注入调用。
                    # 分离"内容写作"和"引用标注"两个任务，使 LLM 聚焦于各自目标。
                    if content and section_papers:
                        content, decision = self._inject_citations_if_needed(
                            content=content,
                            decision=decision,
                            section_papers=section_papers,
                            section_id=section_id,
                        )

                    # 第三阶段：验证
                    try:
                        report = self.online_validator.validate_and_diagnose(
                            decision,
                            content,
                            state,
                            global_index=global_index,
                            word_target=section_word_target,
                        )
                        self.meta_state.update_validator_stability(report.score)
                    except Exception as e:
                        self.logger.error("验证异常（section=%s）: %s", section_id, e)
                        report = None

                    if report is None:
                        last_failure_reason = "validator_exception"
                        consecutive_failures_this_section += 1
                        self.correction_log.add_retry(
                            section_id,
                            attempt + 1,
                            "VALIDATOR_EXCEPTION",
                            ["validator_exception"],
                        )
                        continue

                    # 第四阶段：处理验证结果
                    if report.passed:
                        # 验证通过
                        self._on_section_success(
                            section_id=section_id,
                            content=content,
                            decision=decision,
                            state=state,
                            generated_content=generated_content,
                            section_queue=section_queue,
                            plan_state=plan_state,
                            attempt=attempt,
                            tcas=report.score,
                            section_intent=section_intent,
                        )
                        # 记录诊断结果（若上一次有诊断）
                        if last_diagnosis_event_id:
                            self.metric_collector.record_diagnosis_outcome(
                                last_diagnosis_event_id, succeeded=True
                            )
                            if last_diagnosis_tier:
                                self.meta_state.record_diagnosis_outcome(
                                    last_diagnosis_tier, was_correct=True
                                )
                            last_diagnosis_event_id = None
                            last_diagnosis_tier = None
                        self.metric_collector.record_section_first_pass(
                            section_id, passed_on_first_try=(attempt == 0)
                        )
                        consecutive_failures_this_section = 0
                        last_purge_succeeded = False
                        current_idx += 1
                        break

                    # 验证失败：MRSD 诊断
                    last_failure_reason = "validator_unknown"
                    consecutive_failures_this_section += 1
                    diagnosis = self.mrsd.diagnose(
                        report=report,
                        current_section_id=section_id,
                        section_queue=section_queue,
                        contamination_risk_score=self.meta_state.contamination_risk_score,
                        consecutive_failures_this_section=consecutive_failures_this_section,
                        low_trust_dsl_ref_ratio=self._compute_low_trust_ratio(section_id),
                        last_purge_succeeded=last_purge_succeeded,
                        intent_from_trusted_dsl=(
                            section_intent.dsl_trust_at_generation > 0.6
                        ),
                        recent_section_failure_tiers=[],
                    )

                    # 记录诊断事件
                    diag_event_id = self.metric_collector.record_diagnosis(
                        section_id=section_id,
                        predicted_tier=diagnosis.error_tier.value,
                        predicted_source=diagnosis.error_source.value,
                        confidence=diagnosis.confidence,
                        repair_scope=diagnosis.repair_scope,
                        causal_subgraph_size=len(diagnosis.causal_subgraph),
                        llm_calls_used=0,
                    )
                    if last_diagnosis_event_id:
                        self.metric_collector.record_diagnosis_outcome(
                            last_diagnosis_event_id, succeeded=False
                        )
                        if last_diagnosis_tier:
                            self.meta_state.record_diagnosis_outcome(
                                last_diagnosis_tier, was_correct=False
                            )
                    last_diagnosis_event_id = diag_event_id
                    last_diagnosis_tier = diagnosis.error_tier.value

                    # 更新 MetaState
                    _current_tier = diagnosis.error_tier.value
                    self.meta_state.record_failure(_current_tier, diagnosis.error_source.value)

                    # Fix 3：用当前节内同层级失败次数计算真实 recent_same_tier_failure_rate
                    _section_tier_failures[_current_tier] = (
                        _section_tier_failures.get(_current_tier, 0) + 1
                    )
                    _recent_tier_rate = (
                        _section_tier_failures[_current_tier]
                        / consecutive_failures_this_section
                    )
                    self.meta_state.update_contamination_risk(
                        low_trust_ref_ratio=self._compute_low_trust_ratio(section_id),
                        recent_same_tier_failure_rate=_recent_tier_rate,
                    )

                    # Fix 2：接入 EIV 计算（依赖已更新的 diagnosis_uncertainty_profile）
                    self.meta_state.update_eiv(
                        current_tier=_current_tier,
                        current_tcas=report.score,
                        tcas_threshold=TopicCoverageScorer.THRESHOLD_TCAS_MAJOR,
                        estimated_extra_calls=1,
                        avg_tokens_per_call=2000,
                        token_budget=max(self.meta_state.remaining_retry_budget, 1),
                    )

                    self._print_failure(section_id, attempt + 1, diagnosis, report)
                    self.correction_log.add_retry(
                        section_id, attempt + 1,
                        f"{diagnosis.repair_scope}({diagnosis.error_tier.value})",
                        report.failures,
                    )

                    # 引用失败检测：当 ReferenceValidator 报告合法引用不足时，
                    # 构建明确的重试提示，下一轮生成会将其注入 prompt 顶层。
                    # 目的：把"失败原因"变成"下轮硬约束"，打破三轮同输入循环。
                    ref_rpt = report.reference_report if report else None
                    _citation_only_failure = False
                    if ref_rpt is not None and not ref_rpt.passed:
                        min_cit = self.online_validator.reference_validator._min_citations
                        available_labels = (
                            " ".join(f"[R{e.r_index}]" for e in section_papers)
                            if section_papers else "none"
                        )
                        citation_retry_hint = (
                            f"CRITICAL: The previous attempt produced only {ref_rpt.valid_marker_count} "
                            f"valid [Rx] marker(s), but at least {min_cit} are required. "
                            f"References available for this section: {available_labels}. "
                            f"You MUST cite at least {min_cit} different references by appending "
                            "[Rx] immediately after each supporting sentence. "
                            "Integrate citations naturally throughout the section — "
                            "do not cluster them all in one place. "
                            "[Rx] markers must appear ONLY in the content field — "
                            "never in reasoning, decision, or expected_effect."
                        )
                        self.logger.info(
                            "citation_retry_hint set for next attempt: section=%s valid_markers=%d min_required=%d",
                            section_id, ref_rpt.valid_marker_count, min_cit,
                        )
                        # 引用密度失败不得触发 partial_rollback：
                        # 根因是标记缺失（内容正确但未加 [Rx]），不是上游决策传播错误。
                        # 新版：引用失败以 AbsenceViolation(source_check="citation_density") 进入
                        # report.failures，需按 source_check 识别，而非依赖 failures==[]。
                        from .core.validation import AbsenceViolation as _AV
                        citation_abs = [
                            f for f in report.failures
                            if isinstance(f, _AV) and f.source_check == "citation_density"
                        ]
                        _citation_only_failure = bool(citation_abs) and all(
                            isinstance(f, _AV) and f.source_check == "citation_density"
                            for f in report.failures
                        )
                        if _citation_only_failure:
                            self.logger.info(
                                "citation-only failure detected, overriding diagnosis to local_rewrite: section=%s",
                                section_id,
                            )
                            # ── 免费引用插入矫正（不消耗重试次数）──────────────────
                            # 引用数量不足属于标注问题，内容质量本身没有问题。
                            # 对已生成原文做纯标记插入（不重写内容），保留写作质量。
                            # 若矫正通过，直接接受；若未通过，保留 citation_retry_hint
                            # 供下轮正式重试使用，本轮不额外消耗重试次数。
                            if content and section_papers:
                                self.logger.info(
                                    "免费引用插入矫正启动：section=%s actual=%d min=%d",
                                    section_id, ref_rpt.valid_marker_count, min_cit,
                                )
                                _rc, _rd = self._reinforce_citations(
                                    content=content,
                                    decision=decision,
                                    section_papers=section_papers,
                                    section_id=section_id,
                                    actual_count=ref_rpt.valid_marker_count,
                                    min_required=min_cit,
                                )
                                _reinforce_report = self.online_validator.validate_and_diagnose(
                                    _rd, _rc, state,
                                    global_index=global_index,
                                    word_target=section_word_target,
                                )
                                self.meta_state.update_validator_stability(_reinforce_report.score)

                                if _reinforce_report.passed:
                                    self.logger.info(
                                        "免费引用插入矫正通过：section=%s", section_id
                                    )
                                    self._on_section_success(
                                        section_id=section_id,
                                        content=_rc,
                                        decision=_rd,
                                        state=state,
                                        generated_content=generated_content,
                                        section_queue=section_queue,
                                        plan_state=plan_state,
                                        attempt=attempt,
                                        tcas=_reinforce_report.score,
                                        section_intent=section_intent,
                                    )
                                    if last_diagnosis_event_id:
                                        self.metric_collector.record_diagnosis_outcome(
                                            last_diagnosis_event_id, succeeded=True
                                        )
                                        if last_diagnosis_tier:
                                            self.meta_state.record_diagnosis_outcome(
                                                last_diagnosis_tier, was_correct=True
                                            )
                                        last_diagnosis_event_id = None
                                        last_diagnosis_tier = None
                                    self.metric_collector.record_section_first_pass(
                                        section_id, passed_on_first_try=(attempt == 0)
                                    )
                                    consecutive_failures_this_section = 0
                                    last_purge_succeeded = False
                                    current_idx += 1
                                    break

                                # 矫正未通过：更新 content/decision，
                                # citation_retry_hint 已就位，下轮正式重试会携带
                                self.logger.info(
                                    "免费引用插入矫正未通过，进入下轮正式重试：section=%s",
                                    section_id,
                                )
                                content = _rc
                                decision = _rd

                    # 长度失败检测：从 report.failures 中找 format_length 类型的
                    # AbsenceViolation，从其 obligation 字段提取 actual/target 词数。
                    # 原因：MAJOR 格式问题进入 failures（非 warnings），旧代码查 warnings 永远为空。
                    from .core.validation import AbsenceViolation as _AV2
                    _length_failures = [
                        f for f in (report.failures if report else [])
                        if isinstance(f, _AV2) and getattr(f, "source_check", "") == "format_length"
                    ]
                    if _length_failures:
                        _obligation_text = _length_failures[0].obligation
                        _m_actual = re.search(r'actual=(\d+)', _obligation_text)
                        _m_target = re.search(r'target=(\d+)', _obligation_text)
                        if _m_actual and _m_target:
                            _actual = int(_m_actual.group(1))
                            _target = int(_m_target.group(1))
                            if _actual < _target:
                                if _actual < int(_target * 0.35):
                                    length_retry_hint = (
                                        f"Previous attempt was severely under-generated: "
                                        f"only {_actual} words against a target of {_target} words. "
                                        f"You MUST write approximately {_target} words. "
                                        "Every paragraph must be fully developed with citations, "
                                        "evidence, and in-depth analysis. Do not truncate early."
                                    )
                                else:
                                    length_retry_hint = (
                                        f"Previous attempt was too short: {_actual} words "
                                        f"against a target of {_target} words. "
                                        f"Write approximately {_target} words. "
                                        "Expand every key point with concrete evidence, "
                                        "analysis, and examples. Do not truncate early."
                                    )
                            else:
                                length_retry_hint = (
                                    f"Previous attempt was too long: {_actual} words "
                                    f"against a target of {_target} words. "
                                    f"Condense to approximately {_target} words. "
                                    "Cut redundant phrasing and repetition while "
                                    "preserving all key arguments and evidence."
                                )
                            self.logger.info(
                                "length_retry_hint set for next attempt: section=%s actual=%d target=%d",
                                section_id, _actual, _target,
                            )
                        else:
                            length_retry_hint = None
                    else:
                        length_retry_hint = None

                    # 执行修复
                    if not _citation_only_failure and diagnosis.repair_scope == "partial_rollback":
                        # 回退策略：需要 MetaState 门控
                        if (
                            not self.meta_state.gate_action("allow_rollback")
                            or rollback_count >= self.MAX_ROLLBACKS
                            or not diagnosis.should_rollback()
                        ):
                            self.logger.info("回退被门控或超限，降级为 local_rewrite")
                            self._update_dsl_injection_strengthen(state)
                            continue

                        target = diagnosis.target_section
                        if target and self._execute_rollback(
                            target_section=target,
                            current_section=section_id,
                            reason="; ".join(failure_description(f) for f in report.failures),
                            state=state,
                            generated_content=generated_content,
                            section_queue=section_queue,
                            plan_state=plan_state,
                        ):
                            rollback_count += 1
                            self.meta_state.remaining_rollback_budget = max(
                                0, self.meta_state.remaining_rollback_budget - 1
                            )
                            self.correction_log.add_rollback(
                                from_section=section_id,
                                to_section=target,
                                reason=f"MRSD:{diagnosis.error_tier.value}",
                            )
                            self.metric_collector.record_repair(
                                section_id=section_id,
                                repair_scope="partial_rollback",
                                triggered_by_tier=diagnosis.error_tier.value,
                                triggered_by_confidence=diagnosis.confidence,
                                succeeded=True,
                                extra_llm_calls=0,
                                rollback_distance=abs(
                                    section_queue.index(section_id)
                                    - (section_queue.index(target) if target in section_queue else 0)
                                ),
                            )
                            consecutive_failures_this_section = 0
                            current_idx = section_queue.index(target)
                            rolled_back = True
                            break
                        else:
                            self.logger.warning("回退执行失败，降级为 local_rewrite")
                            continue

                    elif not _citation_only_failure and diagnosis.repair_scope == "memory_purge":
                        # 精确记忆清除
                        purged = self.dsl.purge_contaminated_entries(
                            contaminated_section=section_id,
                            conflict_description="; ".join(
                                failure_description(f) for f in report.failures[:2]
                            ),
                        )
                        last_purge_succeeded = len(purged) > 0
                        self.logger.info("memory_purge：清除 %d 条条目", len(purged))
                        # 更新 DSL 注入
                        self._update_dsl_injection(state, section_id, section_queue, current_idx)
                        self.metric_collector.record_repair(
                            section_id=section_id,
                            repair_scope="memory_purge",
                            triggered_by_tier=diagnosis.error_tier.value,
                            triggered_by_confidence=diagnosis.confidence,
                            succeeded=last_purge_succeeded,
                            extra_llm_calls=0,
                        )
                        continue

                    else:
                        # local_rewrite：更新 DSL 注入（若需要强化）
                        if diagnosis.decoding_config.strengthen_dsl_injection:
                            self._update_dsl_injection_strengthen(state)
                        # plan_level：重规划 SectionIntent
                        if diagnosis.decoding_config.trigger_section_intent_revision:
                            section_intent = self._plan_section(
                                section_id=section_id,
                                section_title=section_title,
                                task=task,
                                plan_state=plan_state,
                                is_revision=True,
                                revision_reason="; ".join(failure_description(f) for f in report.failures),
                                word_target=section_word_target,
                            )
                            plan_state.revise_intent(
                                section_id=section_id,
                                new_intent=section_intent,
                                reason="plan_level repair",
                            )
                        self.metric_collector.record_repair(
                            section_id=section_id,
                            repair_scope="local_rewrite",
                            triggered_by_tier=diagnosis.error_tier.value,
                            triggered_by_confidence=diagnosis.confidence,
                            succeeded=False,  # 后续验证后更新
                            extra_llm_calls=1,
                        )
                        continue

                else:
                    # 超过最大重试次数：降级接受最后一次的版本
                    if not rolled_back:
                        reason_code = last_failure_reason or "validator_unknown"
                        self.logger.warning(
                            "degraded_acceptance: section=%s attempts=%d reason=%s",
                            section_id,
                            self.MAX_RETRIES_PER_SECTION,
                            reason_code,
                        )
                        if self.run_logger is not None:
                            self.run_logger.log_section_degraded(
                                section_id,
                                self.MAX_RETRIES_PER_SECTION,
                                reason_code,
                            )
                        fallback_content = self._coerce_degraded_section_content(content)
                        fallback_decision = decision

                        generated_content[section_id] = fallback_content
                        state.generated_sections.append(section_id)
                        state.section_snippets[section_id] = fallback_content[:300]
                        state.section_summaries[section_id] = fallback_content[:500]
                        state.update_progress()
                        if fallback_decision:
                            self.dtg.add_decision(fallback_decision)

                        last_issues = report.failures if report else []
                        self.correction_log.add_failure(section_id, last_issues)
                        state.flagged_issues.append(
                            f"{section_id}: degraded content accepted after validation failure"
                        )
                        self.metric_collector.record_section_first_pass(section_id, False)
                        consecutive_failures_this_section = 0
                        current_idx += 1

            # 组装最终文本（含引用重编号和参考文献列表）
            self.last_chunk_map = self._build_chunk_map(outline, generated_content)
            self.last_citation_manifest = self._build_citation_manifest(
                generated_content=generated_content,
                global_index=global_index,
            )
            final_text = self._post_process_references_v2(
                outline, generated_content, global_index
            )
            self._print_summary()
            self.run_logger.log_run_summary(
                self.correction_log.get_statistics(),
                self.meta_state,
            )

            return final_text, self.dtg.decision_log, self.correction_log
        finally:
            self.run_logger.close()

    # ------------------------------------------------------------------
    # 第一阶段：规划
    # ------------------------------------------------------------------

    def _plan_section(
        self,
        section_id: str,
        section_title: str,
        task: str,
        plan_state: PlanState,
        is_revision: bool = False,
        revision_reason: str = "",
        word_target: Optional[int] = None,
    ) -> SectionIntent:
        """
        调用 SectionPlanner 生成当前节的 SectionIntent

        功能：
            获取 DSL 上下文、已完成章节摘要，调用 SectionPlanner.plan_section()。

        参数：
            section_id: 当前节 ID
            section_title: 当前节标题
            task: 全局任务描述
            plan_state: 当前规划状态
            is_revision: 是否为修订（plan_level repair 时为 True）
            revision_reason: 修订原因（plan_level repair 时提供）

        返回值：
            SectionIntent：生成的局部计划
        """
        memory_trust = self.dsl.compute_memory_trust_level()
        low_trust_ids = self.dsl.get_low_trust_entry_ids(threshold=0.5)
        dsl_entry_ids = [e.entry_id for e in self.dsl.get_active_entries()]

        injectable = self.dsl.get_injectable_entries(
            target_section_idx=list(plan_state.global_outline.keys()).index(section_id)
            if section_id in plan_state.global_outline else 0,
            total_sections=len(plan_state.global_outline),
            recent_decision_ids=[],
            historical_failure_entry_ids=[],
            outline=plan_state.global_outline,
            target_section_id=section_id,
        )
        dsl_context = "\n".join(f"- [{e.commitment_type.value}] {e.content}" for e in injectable)

        section_summaries_str = "\n".join(
            f"[{sid}] {intent.local_goal}"
            for sid, intent in list(plan_state.section_intents.items())[:5]
        )

        if is_revision and revision_reason:
            task_with_reason = f"{task}\n\n(Revision reason: {revision_reason})"
        else:
            task_with_reason = task

        try:
            return self.section_planner.plan_section(
                section_id=section_id,
                section_title=section_title,
                task_description=task_with_reason,
                dsl_context=dsl_context,
                section_summaries=section_summaries_str,
                source_dsl_entry_ids=dsl_entry_ids,
                dsl_trust_at_generation=memory_trust,
                word_target=word_target,
            )
        except Exception as e:
            self.logger.warning("SectionPlanner 异常，使用默认 intent：%s", e)
            return SectionIntent.create(
                section_id=section_id,
                local_goal=f"Complete the content for {section_title}",
                scope_boundary=f"This section must stay within {section_title} and must not cover later sections",
                coverage_requirements=[],
                commitments_to_maintain=[],
                risks_to_avoid=[],
                success_criteria=["The content matches the section goal and does not violate major constraints."],
                source_dsl_entry_ids=dsl_entry_ids,
                dsl_trust_at_generation=memory_trust,
                word_target=word_target,
            )

    # ------------------------------------------------------------------
    # 第二阶段：DSL 注入
    # ------------------------------------------------------------------

    def _update_dsl_injection(
        self,
        state: GenerationState,
        section_id: str,
        section_queue: List[str],
        current_idx: int,
    ) -> None:
        """
        更新 GenerationState 的 DSL 注入文本

        功能：
            计算当前节的 injectable entries，格式化为注入字符串，
            写入 state.dsl_injection。

        参数：
            state: 当前生成状态
            section_id: 当前节 ID
            section_queue: 全局节列表
            current_idx: 当前节序号（0-based）
        """
        injectable = self.dsl.get_injectable_entries(
            target_section_idx=current_idx,
            total_sections=len(section_queue),
            recent_decision_ids=[
                d.decision_id for d in self.dtg.decision_log[-2:]
            ],
            historical_failure_entry_ids=[],
            outline={sid: sid for sid in section_queue},
            target_section_id=section_id,
        )
        if injectable:
            state.dsl_injection = "\n".join(
                f"- {{{e.commitment_type.value}|{e.constraint_type.value}}} {e.content}"
                for e in injectable
            )
        else:
            state.dsl_injection = ""

        if getattr(self, "run_logger", None) is not None:
            self.run_logger.log_dsl_injection(section_id, injectable)

    def _update_dsl_injection_strengthen(self, state: GenerationState) -> None:
        """
        强化 DSL 注入（strengthen_dsl_injection=True 时调用）

        功能：
            在当前 dsl_injection 基础上追加强调说明。
        """
        if state.dsl_injection:
            state.dsl_injection = (
                "[Important] Treat the active discourse commitments below as continuity constraints. "
                "The current Section Intent remains authoritative.\n"
                + state.dsl_injection
            )

    # ------------------------------------------------------------------
    # 成功处理
    # ------------------------------------------------------------------

    # ------------------------------------------------------------------
    # History Corpus
    # ------------------------------------------------------------------

    def _prepare_history_context(
        self,
        state: GenerationState,
        section_id: str,
        section_title: str,
        section_intent: SectionIntent,
        task: str,
        constraints: List[str],
    ) -> None:
        """按 memory_mode 决定是否检索历史语料并写入 state.history_context。"""
        if self.memory_mode == "baseline_ref_rrf":
            state.history_context = ""
            self.logger.info(
                "history_context_empty: mode=baseline_ref_rrf section=%s",
                section_id,
            )
            return

        query = self._build_history_query(
            section_id=section_id,
            section_title=section_title,
            section_intent=section_intent,
            task=task,
            constraints=constraints,
        )

        if self.memory_mode == "history_dense_quota":
            results = self.history_retriever.retrieve(query, top_k=40)
            state.history_context = self._format_history_context(
                results,
                allowed_types={"section_summary", "decision"},
                type_quota={
                    "section_summary": 3,
                    "decision": 1,
                    "dsl": 0,
                },
                include_role_instruction=False,
            )
            self.logger.info(
                "history_context_retrieved: mode=history_dense_quota section=%s candidates=%d",
                section_id,
                len(results),
            )
            return

        results = self.history_retriever.retrieve(query, top_k=8)
        state.history_context = self._format_history_context(
            results,
            allowed_types={"section_summary", "decision"},
            type_quota={
                "section_summary": 3,
                "decision": 1,
                "dsl": 0,
            },
            include_role_instruction=False,
        )
        self.logger.info(
            "history_context_retrieved: mode=history_dense section=%s hits=%d",
            section_id,
            len(results),
        )

    def _summarize_for_history(self, content: str, section_id: str) -> str:
        """用 LLM 为历史语料生成 2-4 句摘要；失败时退回 content[:500]。"""
        fallback = (content or "")[:500]
        if not hasattr(self, "llm_client"):
            return fallback
        prompt = (
            "Summarize the completed section for a long-form writing memory system.\n"
            "Write 2-4 sentences. Do not merely copy the opening sentences.\n"
            "Preserve the section's core argument, key facts, important promises, "
            "and clues useful for later sections.\n\n"
            f"Section id: {section_id}\n"
            f"Section content:\n{content or ''}\n\n"
            "History summary:"
        )
        for attempt in range(5):
            try:
                summary = self.llm_client.generate(
                    prompt=prompt,
                    temperature=0.2,
                    max_tokens=500,
                    allow_think_only_fallback=True,
                    log_meta={
                        "caller": "SelfCorrectingOrchestrator._summarize_for_history",
                        "section_id": section_id,
                        "attempt": attempt + 1,
                    },
                ).strip()
                if summary:
                    return summary
            except Exception as exc:
                self.logger.warning(
                    "history_summary_failed: section=%s attempt=%d error=%s",
                    section_id,
                    attempt + 1,
                    exc,
                )
        return fallback

    def _update_history_corpus_from_section(
        self,
        section_id: str,
        section_intent: Optional[SectionIntent],
        content: str,
        decision: Decision,
        new_entries: List[Any],
    ) -> None:
        """每节成功后写入 5 类历史 item，并重建索引后落盘。"""
        if not hasattr(self, "history_corpus"):
            return
        try:
            section_summary = self._summarize_for_history(content, section_id)
            items = [
                HistoryItem(
                    item_id=f"{section_id}:section_summary",
                    item_type="section_summary",
                    section_id=section_id,
                    text=section_summary,
                ),
                HistoryItem(
                    item_id=f"{section_id}:intent_node",
                    item_type="intent_node",
                    section_id=section_id,
                    text=section_intent.to_prompt_text() if section_intent else "",
                ),
                HistoryItem(
                    item_id=f"{section_id}:decision",
                    item_type="decision",
                    section_id=section_id,
                    text=f"{decision.decision}\n\n{decision.reasoning}",
                ),
                HistoryItem(
                    item_id=f"{section_id}:expected_effect",
                    item_type="expected_effect",
                    section_id=section_id,
                    text=decision.expected_effect,
                ),
            ]
            for item in items:
                self.history_corpus.add_item(item)

            for entry in new_entries:
                if getattr(entry, "commitment_type", None) == CommitmentType.HYPOTHESIS:
                    continue
                entry_id = getattr(entry, "entry_id", "")
                self.history_corpus.add_item(HistoryItem(
                    item_id=f"{section_id}:dsl:{entry_id}",
                    item_type="dsl",
                    section_id=section_id,
                    text=getattr(entry, "content", ""),
                ))

            self.history_corpus.build_index()
            self.history_corpus.save_to_disk(self.history_corpus_path)
            self.logger.info(
                "history_corpus_updated: section=%s total_items=%d path=%s",
                section_id,
                self.history_corpus.item_count(),
                self.history_corpus_path,
            )
        except Exception as exc:
            self.logger.warning(
                "history_corpus_update_failed: section=%s error=%s",
                section_id,
                exc,
            )

    @staticmethod
    def _build_history_query(
        section_id: str,
        section_title: str,
        section_intent: SectionIntent,
        task: str,
        constraints: List[str],
    ) -> str:
        """构造 history corpus 专用 full query，不与论文检索 query 混用。"""
        lines = [
            f"section_id: {section_id}",
            f"section_title: {section_title}",
            f"goal / local_goal: {section_intent.local_goal}",
            f"scope_boundary: {section_intent.scope_boundary}",
            "open_loops_to_advance:",
            *[f"- {item}" for item in section_intent.open_loops_to_advance],
            "commitments_to_maintain:",
            *[f"- {item}" for item in section_intent.commitments_to_maintain],
            "risks_to_avoid:",
            *[f"- {item}" for item in section_intent.risks_to_avoid],
            "success_criteria:",
            *[f"- {item}" for item in section_intent.success_criteria],
            f"task: {task}",
            "global_constraints:",
            *[f"- {item}" for item in constraints],
        ]
        return "\n".join(lines)

    @staticmethod
    def _filter_history_results_by_quota(
        results: List[dict],
        allowed_types: set,
        type_quota: Dict[str, int],
    ) -> List[dict]:
        """按检索顺序执行类型白名单和配额筛选，不用其他类型补位。"""
        counts: Dict[str, int] = {}
        selected: List[dict] = []
        max_items = sum(type_quota.values())

        for result in results:
            item_type = str(result.get("item_type", ""))
            if item_type not in allowed_types:
                continue
            if counts.get(item_type, 0) >= type_quota.get(item_type, 0):
                continue
            selected.append(result)
            counts[item_type] = counts.get(item_type, 0) + 1
            if len(selected) >= max_items:
                break

        return selected

    @staticmethod
    def _format_history_context(
        results: List[dict],
        allowed_types: Optional[set] = None,
        type_quota: Optional[Dict[str, int]] = None,
        include_role_instruction: bool = False,
    ) -> str:
        """格式化历史检索结果；只做空白清理和宽松安全截断。"""
        if allowed_types is not None or type_quota is not None:
            results = SelfCorrectingOrchestrator._filter_history_results_by_quota(
                results=results,
                allowed_types=allowed_types or set(),
                type_quota=type_quota or {},
            )
        if not results:
            return ""

        lines: List[str] = []
        if include_role_instruction:
            lines.extend([
                "These are retrieved records from already completed sections.",
                "Use them only to maintain continuity and avoid contradictions.",
                "Do not treat past decisions, expected effects, or section intents as instructions for the current section.",
                "The current Section Intent below is authoritative.",
                "Historical items are not checklist items; do not try to address every item explicitly.",
                "Do not repeat historical content.",
                "Do not expand the current section beyond its intended scope or word target because of historical context.",
                "Do not treat historical context as a substitute for cited references; every substantive medical claim still needs support from the provided references [Rx].",
                "",
            ])
        for result in results:
            text = re.sub(r"\s+", " ", (result.get("text") or "").strip())
            if not text:
                continue
            score = float(result.get("score", 0.0))
            lines.append(
                f"- [{result.get('item_type', '')}|{result.get('section_id', '')}|score={score:.4f}] {text}"
            )
        return "\n".join(lines)

    def _on_section_success(
        self,
        section_id: str,
        content: str,
        decision: Decision,
        state: GenerationState,
        generated_content: Dict[str, str],
        section_queue: List[str],
        plan_state: PlanState,
        attempt: int,
        tcas: float,
        section_intent: Optional[SectionIntent] = None,
    ) -> None:
        """
        验证通过后的统一处理逻辑

        功能：
            1. 保存内容和决策
            2. 更新 state 和 plan_state
            3. 从生成内容中提取承诺并写入 DSL
            4. 更新 DSL 条目稳定性
            5. 更新 MetaState.memory_trust_level
            6. 记录 DSL 快照（MetricCollector）
            7. 打印成功信息

        参数：
            section_id: 节 ID
            content: 生成内容
            decision: 决策对象
            state: 生成状态
            generated_content: 已生成内容字典
            section_queue: 全局节列表
            plan_state: 规划状态
            attempt: 本次为第几次尝试（0-based）
            tcas: TCAS 评分
        """
        generated_content[section_id] = content
        state.generated_sections.append(section_id)
        state.section_snippets[section_id] = content[:300]
        state.section_summaries[section_id] = content[:500]
        state.update_progress()
        self.dtg.add_decision(decision)
        self.correction_log.add_success(section_id, attempt + 1)

        # 提取承诺并写入 DSL
        new_entries: List[Any] = []
        try:
            new_entries = self.commitment_extractor.extract(
                section_content=content,
                section_id=section_id,
                decision_id=decision.decision_id,
                existing_summary="; ".join(state.section_summaries.get(sid, "")[:100] for sid in state.generated_sections[-3:-1]),
            )
            for entry in new_entries:
                # Phase 3 DSL 溯源：记录产生此条目的 DTG 决策节点
                entry.source_node = decision.decision_id
                self.dsl.add_entry(entry)
        except Exception as e:
            self.logger.warning("承诺提取失败（跳过）：%s", e)

        self._update_history_corpus_from_section(
            section_id=section_id,
            section_intent=section_intent,
            content=content,
            decision=decision,
            new_entries=new_entries,
        )

        relation_stats = self.dsl.process_pending_relations(
            section_id=section_id,
            max_pairs=self.DSL_RELATION_MAX_PAIRS_PER_SECTION,
            batch_size=self.DSL_RELATION_BATCH_SIZE,
            confidence_threshold=self.DSL_RELATION_MIN_CONFIDENCE,
        )
        self._log_dsl_relation_stats(section_id, len(new_entries), relation_stats)

        # 更新 DSL 稳定性
        self.dsl.update_entry_stability(section_id, state.generated_sections)

        # 更新 MetaState
        self.meta_state.memory_trust_level = self.dsl.compute_memory_trust_level()
        self.meta_state.update_contamination_risk(
            low_trust_ref_ratio=self._compute_low_trust_ratio(section_id),
            recent_same_tier_failure_rate=0.0,
        )

        # 记录 DSL 快照
        active = self.dsl.get_active_entries()
        self.metric_collector.record_dsl_snapshot(
            section_id=section_id,
            total_entries=len(active),
            high_stability_count=sum(1 for e in active if e.stability_score > 0.7),
            revoked_count=0,
            open_loop_count=len(self.dsl.get_open_loops()),
            closed_loop_count=0,
            memory_trust_level=self.meta_state.memory_trust_level,
        )

        if self.run_logger is not None:
            self.run_logger.log_section_success(
                section_id=section_id,
                total_attempts=attempt + 1,
                tcas=tcas,
                new_entries=new_entries,
                total_active_entries=len(active),
                memory_trust=self.meta_state.memory_trust_level,
            )

        self._log_postprocess_skipped(section_id)
        self._print_success(section_id, attempt + 1, tcas)

    def _log_dsl_relation_stats(
        self,
        section_id: str,
        new_entries: int,
        stats: Dict[str, Any],
    ) -> None:
        """输出 section 级 DSL 关系统计。"""
        time_cost_ms = int(stats.get("time_cost_ms", 0))
        self.logger.info(
            "[DSL RELATION]\n"
            "  section=%s\n"
            "  new_entries=%s\n"
            "  raw_pairs_checked=%s\n"
            "  pairs_dedup_skipped=%s\n"
            "  pairs_prefilter_none=%s\n"
            "  pairs_cache_hit=%s\n"
            "  pairs_enqueued=%s\n"
            "  pairs_sent_to_llm=%s\n"
            "  pairs_none_llm=%s\n"
            "  pairs_supports=%s\n"
            "  pairs_conflicts=%s\n"
            "  pairs_resolves=%s\n"
            "  remaining_queue=%s\n"
            "  time_cost=%.2fs",
            section_id,
            new_entries,
            stats.get("raw_pairs_checked", 0),
            stats.get("pairs_dedup_skipped", 0),
            stats.get("pairs_prefilter_none", 0),
            stats.get("pairs_cache_hit", 0),
            stats.get("pairs_enqueued", 0),
            stats.get("pairs_sent_to_llm", 0),
            stats.get("pairs_none_llm", 0),
            stats.get("pairs_supports", 0),
            stats.get("pairs_conflicts", 0),
            stats.get("pairs_resolves", 0),
            stats.get("remaining_queue", 0),
            time_cost_ms / 1000.0,
        )
        if self.run_logger is not None:
            self.run_logger.log_dsl_relation_stats(section_id, new_entries, stats)

    # ------------------------------------------------------------------
    # 回退
    # ------------------------------------------------------------------

    def _log_postprocess_skipped(self, section_id: str) -> None:
        """记录 postprocess 默认关闭的原因。"""
        reason = "feature_disabled_by_default"
        self.logger.info("postprocess_skipped: section=%s reason=%s", section_id, reason)
        if getattr(self, "run_logger", None) is not None:
            self.run_logger.log_postprocess_skipped(section_id, reason)


    def _execute_rollback(
        self,
        target_section: str,
        current_section: str,
        reason: str,
        state: GenerationState,
        generated_content: Dict[str, str],
        section_queue: List[str],
        plan_state: PlanState,
    ) -> bool:
        """
        执行回退操作

        功能：
            1. 验证目标节存在
            2. 清除 generated_content、state 和 DTGStore 中的被回退节数据
            3. 回退 DiscourseLedger（清除被回退节引入的 DSL 条目）
            4. 回退 PlanState（清除 intent）
            5. 清除 flagged_issues 中的相关标记

        参数：
            target_section: 回退目标节 ID（从此节重新生成）
            current_section: 当前失败节 ID
            reason: 回退原因
            state: 生成状态
            generated_content: 已生成内容字典
            section_queue: 全局节列表
            plan_state: 规划状态

        返回值：
            bool：回退是否成功
        """
        if target_section not in section_queue:
            self.logger.warning("回退目标 '%s' 不在 section_queue 中，跳过", target_section)
            return False

        target_idx = section_queue.index(target_section)
        current_idx = (
            section_queue.index(current_section)
            if current_section in section_queue
            else len(section_queue)
        )
        sections_to_remove = section_queue[target_idx: current_idx + 1]

        # 清除内容和状态
        for sec in sections_to_remove:
            generated_content.pop(sec, None)
        state.generated_sections = [
            s for s in state.generated_sections if s not in sections_to_remove
        ]
        state.update_progress()

        # 回退 DTGStore
        prev_section = section_queue[target_idx - 1] if target_idx > 0 else None
        self.dtg.rollback_to_section(prev_section)

        # 回退 DiscourseLedger（清除目标节及之后引入的条目）
        cutoff = section_queue[target_idx - 1] if target_idx > 0 else section_queue[0]
        self.dsl.rollback_to_section(cutoff, section_queue)

        # 回退 PlanState（清除 intent）
        plan_state.rollback_intents_from(target_section, section_queue)

        # History corpus 跟随回滚，避免 history_dense 读到已撤回章节
        if hasattr(self, "history_corpus"):
            for sec in sections_to_remove:
                self.history_corpus.remove_section(sec)
            self.history_corpus.save_to_disk(self.history_corpus_path)

        # 清除 flagged_issues
        state.flagged_issues = [
            issue for issue in state.flagged_issues
            if not any(sec in issue for sec in sections_to_remove)
        ]

        self.logger.info(
            "回退完成：%s → %s，清除 %d 节，原因：%s",
            current_section, target_section, len(sections_to_remove), reason
        )
        return True

    # ------------------------------------------------------------------
    # 辅助方法
    # ------------------------------------------------------------------

    def _initialize_state(
        self,
        constraints: List[str],
        outline: Dict[str, str],
    ) -> GenerationState:
        """
        初始化 GenerationState

        参数：
            constraints: 全局约束列表
            outline: 章节大纲

        返回值：
            GenerationState：初始化后的生成状态
        """
        first_section = next(iter(outline))
        state = GenerationState(
            current_section=first_section,
            progress=0.0,
            global_constraints=constraints,
            outline=outline,
            generated_sections=[],
        )

        # Phase 3：将任务规范级约束写入 DSL 作为 IMMUTABLE DISCOURSE_POLICY 条目，
        # 使 MRCA 的 D_j(r) 计算能追踪这些约束的传播影响
        from .core.ledger import CommitmentType, ConstraintType, LedgerEntry
        for constraint in constraints:
            if not constraint.strip():
                continue
            entry = LedgerEntry.create(
                commitment_type=CommitmentType.DISCOURSE_POLICY,
                content=constraint,
                constraint_type=ConstraintType.IMMUTABLE,
                source_section="__task_spec__",
                source_decision_id="__task_spec__",
                trust_level=1.0,
            )
            entry.source_node = "__task_spec__"
            self.dsl.add_entry(entry)

        return state

    def _get_recent_content(self) -> str:
        """
        获取最近 2 个决策的 expected_effect 作为上下文摘要

        返回值：
            str：最近内容摘要字符串
        """
        recent = self.dtg.decision_log[-2:]
        if not recent:
            return ""
        return "\n".join(f"[{d.target_section}] {d.expected_effect}" for d in recent)

    def _get_temperature(self, consecutive_failures: int) -> float:
        """
        根据连续失败次数决定生成温度

        关键实现细节：
            0 次失败 → 0.7（正常生成）
            1 次失败 → 0.5（中等保守）
            2+ 次失败 → 0.3（低温保守重写）

        参数：
            consecutive_failures: 当前节连续失败次数

        返回值：
            float：生成温度
        """
        if consecutive_failures == 0:
            return 0.7
        elif consecutive_failures == 1:
            return 0.5
        else:
            return 0.3

    @staticmethod
    def _parse_section_word_target(task: str, outline: Dict[str, str]) -> Optional[int]:
        """
        从任务描述中提取全局词数目标，除以节数得到每节目标词数。

        匹配形式：
            "approximately 9600-word", "9600 words", "9,600-word" 等

        返回值：
            int：每节目标词数；无法解析时返回 None
        """
        num_sections = max(len(outline), 1)
        m = re.search(r'(\d[\d,]*)\s*[-–]?\s*word', task, re.IGNORECASE)
        if m:
            total = int(m.group(1).replace(',', ''))
            return max(100, total // num_sections)
        return None

    @staticmethod
    def _resolve_section_word_targets(
        task: str,
        outline: Dict[str, str],
        reference: Optional[Dict[str, Any]] = None,
    ) -> Dict[str, Optional[int]]:
        """Resolve per-section word targets, preferring explicit task reference data."""

        if isinstance(reference, dict):
            constraints = reference.get("constraints")
            if isinstance(constraints, dict):
                raw_targets = constraints.get("section_word_targets")
                if isinstance(raw_targets, dict):
                    resolved_targets: Dict[str, Optional[int]] = {}
                    for section_id in outline:
                        raw_value = raw_targets.get(section_id)
                        if isinstance(raw_value, (int, float, str)):
                            try:
                                parsed = int(raw_value)
                            except (TypeError, ValueError):
                                parsed = None
                            resolved_targets[section_id] = parsed if parsed and parsed > 0 else None
                        else:
                            resolved_targets[section_id] = None
                    if any(value is not None for value in resolved_targets.values()):
                        return resolved_targets

        uniform_target = SelfCorrectingOrchestrator._parse_section_word_target(task, outline)
        return {
            section_id: uniform_target
            for section_id in outline
        }

    def _compute_low_trust_ratio(self, section_id: str) -> float:
        """
        计算当前节引用的低信任 DSL 条目比例

        参数：
            section_id: 当前节 ID

        返回值：
            float：低信任条目比例 [0.0, 1.0]
        """
        active = self.dsl.get_active_entries()
        if not active:
            return 0.0
        low_trust = self.dsl.get_low_trust_entry_ids(threshold=0.5)
        return len(low_trust) / len(active)

    # ── 引用注入 ─────────────────────────────────────────────────────────────

    _CITATION_INJECTION_PROMPT = """\
You are an academic editor. Your only task is to insert [Rx] citation markers into \
the provided text. Do NOT add, remove, or rephrase any words.

Available references:
{paper_list}

Rules:
1. For each reference that supports a specific claim or statement in the text, \
insert [Rx] immediately after the period ending that sentence (before the space).
   Example: "The enzyme regulates metabolism [R2]."
2. Each reference should be cited at least once if it supports any claim.
3. [Rx] markers go ONLY in the text — never in headings.
4. Output ONLY the annotated text, nothing else.

Text to annotate:
{content}

Annotated text:"""

    # 引用强化插入 prompt：用于已有标记但数量不足时的专项矫正。
    # 与 _CITATION_INJECTION_PROMPT 的区别：明确告知上次实际数量和最低要求，
    # 同时重复完整论文列表和原文，引导 LLM 做补充插入而非重写。
    _CITATION_REINFORCE_PROMPT = """\
You are an academic editor performing citation reinforcement. Do NOT rewrite, add, or remove any prose.

The previous version of this section contained only {actual_count} citation marker(s) — \
below the minimum requirement of {min_required}.

Your task: insert additional [Rx] markers into the text wherever the supporting reference applies.

Available references for this section:
{paper_list}

Requirements:
1. Insert [Rx] immediately after the sentence or clause it supports.
   Example: "Dropout reduces overfitting [R3]."
2. You MUST achieve at least {min_required} distinct [Rx] markers in the output.
3. Each reference may appear multiple times if multiple sentences support it.
4. Do NOT add, remove, or rephrase any words — only insert [Rx] markers.
5. [Rx] markers go ONLY in the body text — never in headings.
6. Output ONLY the annotated text, nothing else.

Original text (from previous attempt):
{content}

Annotated text:"""

    def _inject_citations_if_needed(
        self,
        content: str,
        decision: "Decision",
        section_papers: List[GlobalPaperEntry],
        section_id: str,
    ) -> Tuple[str, "Decision"]:
        """
        两阶段引用注入：若 content 中无 [Rx] 标记，发起专项注入 LLM 调用。

        设计原理：
            内容生成任务（写作质量、长度、学术风格）和引用标注任务（找到哪句话
            对应哪篇论文）存在注意力竞争。分离为两个独立调用，各自聚焦，
            比强化 prompt 提示更稳定。

        流程：
            1. 检测 content 中的 [Rx] 标记数量
            2. 若 >= 1，直接返回（不浪费 token）
            3. 若 == 0，构建精简注入 prompt，调用 LLM 插入标记
            4. 注入后若仍为 0（corpus 无相关论文），记录 corpus_gap 并返回原始内容

        参数：
            content:       当前节已生成文本
            decision:      对应的 Decision 对象（注入后同步更新 decision.content）
            section_papers: 该节可用论文列表
            section_id:    节 ID（用于日志）

        返回：
            Tuple[str, Decision]：(可能已注入的内容, 已更新的 decision)
        """
        existing = re.findall(r"\[R\d+\]", content)
        if existing:
            self.logger.debug(
                "引用注入：section=%s 已有 %d 个标记，跳过注入",
                section_id, len(existing),
            )
            return content, decision

        if not section_papers:
            self.logger.info(
                "引用注入：section=%s 无可用论文，跳过注入（corpus_gap）",
                section_id,
            )
            return content, decision

        # 构建论文列表（摘要截取前 150 字符，控制 prompt 长度）
        paper_lines = []
        for entry in section_papers:
            abstract_snippet = (entry.abstract or entry.top_chunk_text or "")[:150].replace("\n", " ")
            paper_lines.append(
                f"[R{entry.r_index}] {entry.title[:80]} | {abstract_snippet}"
            )
        paper_list_str = "\n".join(paper_lines)

        prompt = self._CITATION_INJECTION_PROMPT.format(
            paper_list=paper_list_str,
            content=content,
        )

        try:
            injected = self.llm_client.generate(
                prompt=prompt,
                temperature=0.1,
                max_tokens=min(4096, max(512, len(content.split()) * 3)),
                log_meta={"caller": f"CitationInjector.{section_id}"},
            )
            injected = injected.strip()

            injected_markers = re.findall(r"\[R\d+\]", injected)
            if not injected_markers:
                self.logger.warning(
                    "引用注入：section=%s 注入后仍无标记 → corpus_gap（可引论文与内容语义不匹配）",
                    section_id,
                )
                return content, decision

            # 校验：注入后文本长度不应大幅缩减（防止 LLM 截断内容）
            original_words = len(content.split())
            injected_words = len(injected.split())
            if injected_words < original_words * 0.8:
                self.logger.warning(
                    "引用注入：section=%s 注入后词数骤降（%d→%d），使用原始内容",
                    section_id, original_words, injected_words,
                )
                return content, decision

            self.logger.info(
                "引用注入：section=%s 成功插入 %d 个标记 %s",
                section_id,
                len(injected_markers),
                injected_markers[:5],
            )
            decision.content = injected
            return injected, decision

        except Exception as exc:
            self.logger.warning(
                "引用注入：section=%s LLM 调用失败 %s，使用原始内容",
                section_id, exc,
            )
            return content, decision

    def _reinforce_citations(
        self,
        content: str,
        decision: "Decision",
        section_papers: List[GlobalPaperEntry],
        section_id: str,
        actual_count: int,
        min_required: int,
    ) -> Tuple[str, "Decision"]:
        """
        引用强化插入：对已生成内容做纯标记插入，不重写任何正文。

        设计原理：
            引用数量不足通常是写作注意力分配问题（写作质量与引用标注竞争），
            而非内容本身存在缺陷。纯插入策略保留已有写作质量，
            仅在恰当位置补充缺失的 [Rx] 标记。

        与 _inject_citations_if_needed 的区别：
            - 触发条件：已有标记但数量低于 min_required（而非零标记）
            - prompt 中明确传递 actual_count 和 min_required，
              以及上次生成的完整原文，要求 LLM 补充插入而非从零开始

        参数：
            content:        当前节已生成文本（含现有 [Rx] 标记）
            decision:       对应 Decision（插入成功后同步 decision.content）
            section_papers: 该节可用论文列表
            section_id:     节 ID（日志用）
            actual_count:   上一次验证的实际引用标记数
            min_required:   最低要求引用标记数

        返回：
            Tuple[str, Decision]：(插入后内容, 更新后 decision)；
            插入失败时返回原始 (content, decision)。
        """
        if not section_papers:
            self.logger.info(
                "引用强化插入：section=%s 无可用论文，跳过",
                section_id,
            )
            return content, decision

        # 第一阶段：构建论文列表（含摘要片段，控制 prompt 长度）
        paper_lines = []
        for entry in section_papers:
            abstract_snippet = (entry.abstract or entry.top_chunk_text or "")[:150].replace("\n", " ")
            paper_lines.append(
                f"[R{entry.r_index}] {entry.title[:80]} | {abstract_snippet}"
            )
        paper_list_str = "\n".join(paper_lines)

        prompt = self._CITATION_REINFORCE_PROMPT.format(
            actual_count=actual_count,
            min_required=min_required,
            paper_list=paper_list_str,
            content=content,
        )

        # 第二阶段：调用 LLM 做纯插入（低温度保证确定性，token 上限按原文词数放宽）
        try:
            reinforced = self.llm_client.generate(
                prompt=prompt,
                temperature=0.1,
                max_tokens=min(4096, max(512, len(content.split()) * 3)),
                log_meta={"caller": f"CitationReinforcer.{section_id}"},
            )
            reinforced = reinforced.strip()

            reinforced_markers = re.findall(r"\[R\d+\]", reinforced)
            marker_count = len(reinforced_markers)

            # 第三阶段：校验插入结果
            if marker_count < min_required:
                self.logger.warning(
                    "引用强化插入：section=%s 插入后仅 %d 个标记（需 %d），返回原始内容",
                    section_id, marker_count, min_required,
                )
                return content, decision

            # 防止 LLM 在插入时截断正文
            original_words = len(content.split())
            reinforced_words = len(reinforced.split())
            if reinforced_words < original_words * 0.8:
                self.logger.warning(
                    "引用强化插入：section=%s 词数骤降（%d→%d），使用原始内容",
                    section_id, original_words, reinforced_words,
                )
                return content, decision

            self.logger.info(
                "引用强化插入：section=%s 成功，标记数 %d→%d %s",
                section_id, actual_count, marker_count, reinforced_markers[:6],
            )
            decision.content = reinforced
            return reinforced, decision

        except Exception as exc:
            self.logger.warning(
                "引用强化插入：section=%s LLM 调用失败 %s，使用原始内容",
                section_id, exc,
            )
            return content, decision

    def _post_process_references_v2(
        self,
        outline: Dict[str, str],
        generated_content: Dict[str, str],
        global_index: GlobalPaperIndex,
    ) -> str:
        """
        组装最终文本，清理越界 [Rx] 标记，按首次出现重编号，末尾追加 References 列表。

        流程：
            1. 按大纲顺序扫描全文，提取所有 [Rx] 标记
            2. 越界标记（x ∉ valid_r_set）直接删除
            3. 按首次出现顺序为合法 r_index 分配连续编号 1, 2, 3…
            4. 将 [Rx] 替换为 [编号]
            5. 按编号顺序从 GlobalPaperEntry 构建 References 节

        参数：
            outline:           有序章节大纲 {section_id: title}
            generated_content: 各节已生成文本
            global_index:      全局参考索引（R1…RN）

        返回值：
            str：含内联引用编号和 References 列表的完整文本
        """
        import re
        from collections import OrderedDict

        valid_r_set = global_index.valid_r_set

        # 第一轮：扫描确定首次出现顺序，构建 r_index → 全局编号 映射
        r_to_num: "OrderedDict[int, int]" = OrderedDict()
        counter = 0

        def _scan(match: "re.Match") -> str:
            nonlocal counter
            idx = int(match.group(1))
            if idx not in valid_r_set:
                return ""
            if idx not in r_to_num:
                counter += 1
                r_to_num[idx] = counter
            return f"[{r_to_num[idx]}]"

        parts = []
        for section_id, title in outline.items():
            raw = generated_content.get(section_id, "")
            processed = re.sub(r"\[R(\d+)\]", _scan, raw)
            # 将节内部的段落分隔（\n\n）折叠为单个换行符，确保每节在
            # split_blocks(drop_markdown_wrappers=True) 后恰好产生 1 个内容块。
            # 这保证 benchmark range_keyword 的绝对块位置约束能够满足。
            processed = re.sub(r"\n\s*\n", "\n", processed).strip()
            parts.append(f"## {title}\n\n{processed}")

        assembled = "\n\n---\n\n".join(parts)

        if r_to_num:
            ref_lines = ["\n\n---\n\n## References\n"]
            # 按全局编号排序输出
            for r_idx, num in sorted(r_to_num.items(), key=lambda kv: kv[1]):
                entry_obj = global_index.get_by_r(r_idx)
                if entry_obj is None:
                    continue
                authors = entry_obj.authors
                author_str = ", ".join(str(a) for a in authors[:3])
                if len(authors) > 3:
                    author_str += " et al."
                entry = f"[{num}]"
                if author_str:
                    entry += f" {author_str}."
                entry += f" {entry_obj.title}."
                if entry_obj.doi:
                    entry += f" DOI: {entry_obj.doi}"
                ref_lines.append(entry)
            assembled += "\n".join(ref_lines)

        self.logger.info(
            "后处理完成：共引用 %d 篇论文（valid_r=%s → 编号1…%d）",
            len(r_to_num),
            sorted(r_to_num.keys()),
            counter,
        )
        return assembled

    def _build_chunk_map(
        self,
        outline: Dict[str, str],
        generated_content: Dict[str, str],
    ) -> List[Dict[str, Any]]:
        chunk_map: List[Dict[str, Any]] = []
        total_sections = len(outline)
        for section_index, (section_id, title) in enumerate(outline.items(), start=1):
            text = generated_content.get(section_id, "").strip()
            if section_index == 1:
                section_key = "introduction"
            elif section_index == total_sections:
                section_key = "conclusion"
            else:
                section_key = "main_body"
            chunk_map.append(
                {
                    "chunk_id": section_id,
                    "section_id": section_id,
                    "title": title,
                    "text": text,
                    "word_count": len(text.split()),
                    "section_index": section_index,
                    "section_key": section_key,
                }
            )
        return chunk_map

    def _build_citation_manifest(
        self,
        *,
        generated_content: Dict[str, str],
        global_index: GlobalPaperIndex,
    ) -> List[Dict[str, Any]]:
        if global_index.is_empty():
            return []

        manifest: List[Dict[str, Any]] = []
        citation_id = 1
        for section_id, content in generated_content.items():
            for sentence_text, r_index in self._extract_citation_events(content):
                entry = global_index.get_by_r(r_index)
                if entry is None:
                    continue
                manifest.append(
                    {
                        "citation_id": f"C{citation_id:04d}",
                        "chunk_id": section_id,
                        "section_id": section_id,
                        "source_id": entry.paper_id,
                        "source_type": self._infer_source_type(entry),
                        "claim_role": self._infer_claim_role(section_id, sentence_text),
                        "claim_span": sentence_text,
                        "source_excerpt": (entry.abstract or entry.top_chunk_text or "")[:1200],
                        "r_index": entry.r_index,
                        "title": entry.title,
                        "doi": entry.doi,
                    }
                )
                citation_id += 1
        return manifest

    @staticmethod
    def _extract_citation_events(content: str) -> List[Tuple[str, int]]:
        events: List[Tuple[str, int]] = []
        if not content.strip():
            return events

        sentence_pattern = re.compile(
            r"[^.!?]+[.!?]+(?:\s*\[R\d+\])+|[^.!?]+(?:\s*\[R\d+\])+"
        )
        for match in sentence_pattern.finditer(content):
            sentence = match.group(0).strip()
            markers = re.findall(r"\[R(\d+)\]", sentence)
            if not markers:
                continue
            clean_sentence = re.sub(r"\s*\[R\d+\]", "", sentence).strip()
            if not clean_sentence:
                continue
            for marker in markers:
                events.append((clean_sentence, int(marker)))
        return events

    @staticmethod
    def _infer_claim_role(section_id: str, sentence_text: str) -> str:
        section_key = section_id.casefold()
        text = sentence_text.casefold()
        if section_key == "sec1":
            if any(term in text for term in ("define", "defined", "refers to", "characterized")):
                return "definition"
            return "background"
        if section_key == "sec2":
            return "comparison"
        if section_key == "sec3":
            return "mechanism"
        if section_key == "sec4":
            return "evidence_synthesis"
        if section_key == "sec5":
            if any(term in text for term in ("should", "recommend", "must", "clinical practice")):
                return "practice"
            return "interpretation"
        if section_key in {"sec6", "sec7"}:
            return "gap"
        if any(term in text for term in ("should", "recommend", "must")):
            return "recommendation"
        if any(term in text for term in ("compare", "compared", "higher", "lower", "versus")):
            return "comparison"
        if any(term in text for term in ("mechanism", "pathophysiology", "plaque", "thrombus")):
            return "mechanism"
        return "background"

    @staticmethod
    def _infer_source_type(entry: GlobalPaperEntry) -> str:
        text = f"{entry.title}\n{entry.abstract}\n{entry.top_chunk_text}".casefold()
        source_type_terms = (
            ("meta_analysis", ("meta-analysis", "meta analysis")),
            ("systematic_review", ("systematic review",)),
            ("guideline", ("guideline", "guidelines", "consensus statement")),
            ("rct", ("randomized", "randomised", "placebo-controlled")),
            ("trial", ("trial", "trials")),
            ("prospective", ("prospective",)),
            ("cohort", ("cohort",)),
            ("retrospective", ("retrospective",)),
            ("case_control", ("case-control", "case control")),
            ("observational", ("observational", "registry")),
            ("mechanistic", ("mechanistic", "molecular", "pathway")),
            ("animal", ("animal model", "murine", "mouse", "rat model")),
            ("in_vitro", ("in vitro", "cell line")),
            ("narrative", ("narrative review",)),
        )
        for source_type, terms in source_type_terms:
            if any(term in text for term in terms):
                return source_type
        return "observational"

    def _assemble_text(
        self,
        outline: Dict[str, str],
        generated_content: Dict[str, str],
    ) -> str:
        """
        按大纲顺序组装最终文本。

        与 _post_process_references_v2 一致：将节内部的段落分隔折叠为单个换行符，
        确保每节在 split_blocks(drop_markdown_wrappers=True) 后恰好产生 1 个内容块。

        参数：
            outline: 章节大纲
            generated_content: 已生成内容字典

        返回值：
            str：完整文本
        """
        parts = []
        for section_id, title in outline.items():
            content = generated_content.get(section_id, "")
            content = re.sub(r"\n\s*\n", "\n", content).strip()
            parts.append(f"## {title}\n\n{content}")
        return "\n\n---\n\n".join(parts)

    def _coerce_degraded_section_content(self, content: Optional[str]) -> str:
        """Normalize degraded section content so final text never includes failure placeholders."""
        return content.strip() if content is not None else ""

    # ------------------------------------------------------------------
    # Rich 打印
    # ------------------------------------------------------------------

    def _print_header(self, task: str, outline: Dict[str, str]) -> None:
        self.console.print(Panel(
            f"[bold cyan]MetaWriter v4.0[/bold cyan]\n"
            f"Task: {task}\n"
            f"Sections: {len(outline)}",
            title="Generation Start",
            border_style="cyan",
        ))

    def _print_section_start(
        self, section_id: str, title: str, idx: int, total: int
    ) -> None:
        # 目的：
        #   Windows 上常见的 gbk 控制台无法稳定输出 ▶ / — 等字符。
        #   这里统一改用 ASCII，避免真实 benchmark 运行因为打印阶段报编码错而中断。
        self.console.print(
            f"\n[bold blue][{idx+1}/{total}] {section_id}[/bold blue] - {title}"
        )

    def _print_success(self, section_id: str, attempt: int, tcas: float) -> None:
        attempt_str = f"(attempt {attempt})" if attempt > 1 else "(first pass)"
        self.console.print(
            f"  [green][OK] {section_id} passed {attempt_str} TCAS={tcas:.3f}[/green]"
        )

    def _print_failure(self, section_id: str, attempt: int, diagnosis, report) -> None:
        issues_str = " | ".join(failure_description(f)[:40] for f in (report.failures or [])[:3])
        self.console.print(
            f"  [yellow][FAIL] {section_id} failed on attempt {attempt} -> "
            f"{diagnosis.repair_scope}({diagnosis.error_tier.value}/"
            f"{diagnosis.error_source.value})[/yellow]\n"
            f"    [dim]{issues_str}[/dim]"
        )

    def _print_summary(self) -> None:
        stats = self.correction_log.get_statistics()
        metric_summary = self.metric_collector.compute_repair_efficiency()
        self.console.print(Panel(
            f"Sections: {stats['total_sections']}   "
            f"First-pass rate: {stats['success_rate_first_try']:.0%}   "
            f"Retries: {stats['total_retries']}   "
            f"Rollbacks: {stats['total_rollbacks']}   "
            f"Failed sections: {stats['total_failures']}\n"
            f"False Rollback Rate: {metric_summary.get('false_rollback_rate', 'N/A')}   "
            f"DSL Trust Level: {self.meta_state.memory_trust_level:.3f}",
            title="[bold green]Generation Complete[/bold green]",
            border_style="green",
        ))
