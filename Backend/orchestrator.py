
class RetrievalList(list):
    """List of retrieved evidence records that also supports dict-like ['count'] access."""
    def __getitem__(self, k):
        if k == "count":
            return len(self)
        return super().__getitem__(k)

    def get(self, k, default=None):
        if k == "count":
            return len(self)
        return default

import uuid
import json
import time

from Backend.query_analysis.domain_classifier import classify

from rag.retrieval import retrieve

from Backend.evidence_reranking.pipeline import (
    EvidenceRankingPipeline,
)

from Backend.evidence_reranking.evidence_analyzer import (
    analyze_evidence,
)

from Backend.governance import evaluate_governance

from Backend.evidence_engine.rag_adapter import (
    adapt_retrieval_results,
)

from Backend.evidence_engine.llm_classifier import (
    classify_evidence,
)

from Backend.evidence_engine.validator import (
    validate_evidence_consistency,
)

from Backend.evidence_engine.claim_builder import (
    build_claim_assessment,
)

from Backend.evidence_engine.engine import (
    EvidenceEngine,
)

from Backend.evidence_engine.absence_protocol import (
    build_absence_verification,
    absence_verification_to_dict,
)

from Backend.evidence_engine.gap_adapter import (
    build_gap_input,
)

from Backend.final_synthesis import (
    synthesize_final_assessment,
)

from Backend.risk_integration_v2 import (
    assess_with_evidence_engine,
    risk_assessment_to_dict,
)

from Backend.risk_engine.models import (
    DecisionContext,
    DecisionImpact,
    AuthorityRequirement,
    AIAnalysis,
)

from Backend.audit.recorder import (
    create_audit_record,
    append_audit_record,
)

from Backend.policy_standard_mapping.mapping_engine import (
    PolicyStandardMappingEngine,
)

from Backend.policy_standard_mapping.retrieval_planner import (
    plan_and_retrieve_evidence,
)

from Backend.policy_standard_mapping.claim_validation_gate import (
    validate_synthesis_claims,
)

from Backend.regional_comparative_gap import (
    RegionalComparativeGapEngine,
    validate_regional_claims,
)


# ============================================================
# DEFAULT QUESTION
# ============================================================

QUESTION = (
    "What security requirements apply to 5G network slicing in India?"
)


# ============================================================
# SUPPORTED JURISDICTIONS
# ============================================================

SUPPORTED_JURISDICTIONS = {
    "India",
    "European Union",
}


# ============================================================
# EXECUTION CONFIGURATION
# ============================================================

FULL_CONFIG = {
    "retrieval_k": 20,
    "rerank_candidate_limit": None,
    "rerank_top_k": 8,
    "counter_retrieval_k": 20,
    "counter_rerank_candidate_limit": None,
    "counter_rerank_top_k": 8,
    "final_evidence_k": 8,
}


DEMO_CONFIG = {
    # Compact execution for live frontend scenarios (<40s target).
    "retrieval_k": 6,
    "rerank_candidate_limit": 3,
    "rerank_top_k": 3,
    "counter_retrieval_k": 3,
    "counter_rerank_candidate_limit": 2,
    "counter_rerank_top_k": 2,
    "final_evidence_k": 3,
}


def _get_execution_config(demo_mode=False):
    """
    Return a copy of the execution configuration.

    DEMO mode is intended for interactive scenario execution.
    FULL mode is intended for complete backend analysis.
    """

    return dict(
        DEMO_CONFIG if demo_mode else FULL_CONFIG
    )


# ============================================================
# EVIDENCE ASSESSMENT SERIALIZATION
# ============================================================

def _assessment_to_dict(assessment):

    return {
        "overall_status": (
            assessment.overall_status.value
        ),
        "overall_strength": (
            assessment.overall_strength.value
        ),
        "supporting_count": (
            assessment.supporting_count
        ),
        "contradicting_count": (
            assessment.contradicting_count
        ),
        "primary_source_count": (
            assessment.primary_source_count
        ),
        "official_source_count": (
            assessment.official_source_count
        ),
        "source_diversity": (
            assessment.source_diversity
        ),
        "overall_confidence": (
            assessment.overall_confidence
        ),
        "missing_evidence": list(
            assessment.missing_evidence
        ),
    }


# ============================================================
# EVIDENCE DEDUPLICATION
# ============================================================

def _evidence_key(item):

    metadata = item.get(
        "metadata",
        {},
    )

    return (
        metadata.get("chunk_id")
        or metadata.get("id")
        or metadata.get("document")
        or metadata.get("source_file")
        or item.get("evidence_id")
        or item.get("original_rank")
    )


def _merge_evidence(
    primary,
    counter,
):

    combined = []
    seen = set()

    for item in primary + counter:

        key = _evidence_key(item)

        if key in seen:
            continue

        seen.add(key)
        combined.append(item)

    return combined


# ============================================================
# CACHED EVIDENCE RANKING PIPELINE
# ============================================================

_cached_ranking_pipeline = None


def get_ranking_pipeline() -> EvidenceRankingPipeline:
    global _cached_ranking_pipeline

    if _cached_ranking_pipeline is None:
        _cached_ranking_pipeline = EvidenceRankingPipeline()

    return _cached_ranking_pipeline


# ============================================================
# FULL HACKGRID PIPELINE
# ============================================================

def run_pipeline(
    question,
    jurisdiction="India",
    demo_mode=False,
    notes=None,
    regional_mode="OFF",
    execution_id=None,
    event_type="QUESTION_ANALYSIS",
    scenario_id=None,
    scenario_title=None,
    step_id=None,
    step_title=None,
    time_budget_seconds=38.0,
):

    t_start = time.perf_counter()

    performance = {}

    question = question.strip()

    if not question:
        raise ValueError(
            "Question cannot be empty."
        )

    exec_id = execution_id or f"RUN-{uuid.uuid4().hex[:12]}"
    workflow_stages = []

    # ========================================================
    # EXECUTION CONFIGURATION
    # ========================================================

    execution_config = _get_execution_config(
        demo_mode
    )

    primary_k = execution_config[
        "retrieval_k"
    ]

    primary_rerank_candidate_limit = execution_config[
        "rerank_candidate_limit"
    ]

    primary_rerank_top_k = execution_config[
        "rerank_top_k"
    ]

    counter_k = execution_config[
        "counter_retrieval_k"
    ]

    counter_rerank_candidate_limit = execution_config[
        "counter_rerank_candidate_limit"
    ]

    counter_rerank_top_k = execution_config[
        "counter_rerank_top_k"
    ]

    final_evidence_limit = execution_config[
        "final_evidence_k"
    ]

    # ========================================================
    # JURISDICTION VALIDATION
    # ========================================================

    if jurisdiction not in SUPPORTED_JURISDICTIONS:

        supported = ", ".join(
            sorted(SUPPORTED_JURISDICTIONS)
        )

        raise ValueError(
            f"Unsupported jurisdiction '{jurisdiction}'. "
            f"Supported jurisdictions: {supported}"
        )

    # ========================================================
    # 0. DOMAIN + INTENT CLASSIFICATION
    # ========================================================

    t_stage = time.perf_counter()

    print(
        "\n[0/9] Domain + Intent classification..."
    )
    workflow_stages.append("Query Understanding")

    classification = classify(
        question
    )

    performance[
        "classification_ms"
    ] = round(
        (
            time.perf_counter()
            - t_stage
        ) * 1000,
        2,
    )

    print(
        "Domain:",
        classification.get("domain"),
    )

    print(
        "Intent:",
        classification.get("intent"),
    )

    print(
        "Confidence:",
        classification.get("confidence"),
    )

    print(
        "Jurisdiction:",
        jurisdiction,
    )

    print(
        "Execution Mode:",
        "DEMO" if demo_mode else "FULL",
    )

    print("=" * 80)

    print(
        "HACKGRID -- "
        + (
            "COMPACT DEMO"
            if demo_mode
            else "FULL"
        )
        + " EVIDENCE-AWARE PIPELINE"
    )

    print("=" * 80)

    primary_domain = (
        classification.get("domain")
        or classification.get(
            "primary_domain"
        )
    )

    secondary = classification.get(
        "secondary_domains",
        [],
    )

    detected_domains = (
        [primary_domain]
        if primary_domain
        else []
    ) + (
        secondary
        if isinstance(
            secondary,
            list,
        )
        else []
    )

    # ========================================================
    # 1. JURISDICTION-AWARE MULTI-KB RETRIEVAL
    # ========================================================

    t_stage = time.perf_counter()

    print(
        "\n[1/9] Jurisdiction-aware multi-KB retrieval..."
    )
    workflow_stages.append("Retrieval")

    results = plan_and_retrieve_evidence(
        question,
        k=primary_k,
        jurisdiction=jurisdiction,
        domains=detected_domains,
    )

    performance[
        "retrieval_ms"
    ] = round(
        (
            time.perf_counter()
            - t_stage
        ) * 1000,
        2,
    )

    if not results:
        raise RuntimeError(
            "RAG returned no evidence for the "
            f"{jurisdiction} jurisdiction."
        )

    kb_distribution = {}

    for r in results:

        k_name = (
            r.get("kb")
            or r.get(
                "metadata",
                {},
            ).get(
                "kb",
                "MAIN",
            )
        )

        kb_distribution[k_name] = (
            kb_distribution.get(
                k_name,
                0,
            )
            + 1
        )

    print(
        f"Retrieved {len(results)} candidate "
        f"evidence records for {jurisdiction}. "
        f"KBs: {kb_distribution}"
    )

    # ========================================================
    # 1B. PRIMARY EVIDENCE RERANKING
    # ========================================================

    t_stage = time.perf_counter()

    print(
        "\n[1B/9] Top-K reranking + evidence analysis..."
    )
    workflow_stages.append("Semantic Reranking")

    deadline = t_start + time_budget_seconds
    rem_before_rerank = deadline - time.perf_counter()

    if demo_mode and rem_before_rerank < 20.0:
        print("[1B/9] Remaining time budget tight; using vector similarity ranking for primary evidence...")
        reranked_results = []
        for rank, c in enumerate(results[:primary_rerank_top_k], start=1):
            item = dict(c)
            item["rerank_rank"] = rank
            item["reranker_score"] = float(item.get("similarity", 0.85))
            reranked_results.append(item)
        counter_evidence_query = f"not {question}" if not question.startswith("not ") else question
    else:
        evidence_ranking_pipeline = (
            get_ranking_pipeline()
        )

        ranking_result = (
            evidence_ranking_pipeline.run(
                query=question,

                candidates=results,

                final_top_k=(
                    primary_rerank_top_k
                ),

                candidate_limit=(
                    primary_rerank_candidate_limit
                ),
            )
        )

        reranked_results = (
            ranking_result[
                "reranked_evidence"
            ]
        )

        if not reranked_results:
            raise RuntimeError(
                "Reranking returned no evidence."
            )

        counter_evidence_query = (
            ranking_result[
                "counter_evidence_query"
            ]
        )

    performance[
        "reranking_ms"
    ] = round(
        (
            time.perf_counter()
            - t_stage
        ) * 1000,
        2,
    )

    print(
        f"Reranked to {len(reranked_results)} "
        "primary evidence records."
    )

    # ========================================================
    # 1C. JURISDICTION-AWARE COUNTER EVIDENCE
    # ========================================================

    t_stage = time.perf_counter()

    print(
        "\n[1C/9] Counter-evidence retrieval..."
    )
    workflow_stages.append("Counter-Evidence Retrieval")

    counter_results = retrieve(
        counter_evidence_query,
        k=counter_k,
        jurisdiction=jurisdiction,
        domains=detected_domains,
    )

    print(
        f"Retrieved {len(counter_results)} "
        "counter-evidence candidates."
    )

    if demo_mode:
        counter_reranked_results = []
        for rank, c in enumerate(counter_results[:counter_rerank_top_k], start=1):
            item = dict(c)
            item["rerank_rank"] = rank
            item["reranker_score"] = float(item.get("similarity", 0.5))
            counter_reranked_results.append(item)
    else:
        counter_ranking_result = (
            evidence_ranking_pipeline.run(
                query=counter_evidence_query,

                candidates=counter_results,

                final_top_k=(
                    counter_rerank_top_k
                ),

                candidate_limit=(
                    counter_rerank_candidate_limit
                ),
            )
        )

        counter_reranked_results = (
            counter_ranking_result[
                "reranked_evidence"
            ]
        )

    performance[
        "counter_evidence_ms"
    ] = round(
        (
            time.perf_counter()
            - t_stage
        ) * 1000,
        2,
    )

    print(
        f"Reranked to {len(counter_reranked_results)} "
        "counter-evidence records."
    )

    # ========================================================
    # 1D. MERGE + DEDUPLICATE
    # ========================================================

    print(
        "\n[1D/9] Merging evidence..."
    )

    combined_candidates = _merge_evidence(
        reranked_results,
        counter_reranked_results,
    )

    print(
        f"Combined unique evidence: "
        f"{len(combined_candidates)}"
    )

    if not combined_candidates:
        raise RuntimeError(
            "No combined evidence available."
        )

    # ========================================================
    # 1E. SUPPORTING / CONTRADICTING / CONTEXTUAL
    # ========================================================

    print(
        "\n[1E/9] Evidence role analysis..."
    )

    combined_analysis = analyze_evidence(
        candidates=combined_candidates,
        query=question,
        final_top_k=final_evidence_limit,
    )

    ranking_evidence_analysis = (
        combined_analysis.to_dict()
    )

    print(
        "Supporting:",
        len(
            ranking_evidence_analysis[
                "supporting_evidence"
            ]
        ),
    )

    print(
        "Contradicting:",
        len(
            ranking_evidence_analysis[
                "contradicting_evidence"
            ]
        ),
    )

    print(
        "Contextual:",
        len(
            ranking_evidence_analysis[
                "contextual_evidence"
            ]
        ),
    )

    print(
        "Evidence gaps:",
        len(
            ranking_evidence_analysis[
                "evidence_gaps"
            ]
        ),
    )

    # ========================================================
    # 1F. FINAL TOP-K
    # ========================================================

    combined_candidates.sort(
        key=lambda item: item.get(
            "reranker_score",
            0.0,
        ),
        reverse=True,
    )

    final_evidence = (
        combined_candidates[
            :final_evidence_limit
        ]
    )

    if not final_evidence:
        raise RuntimeError(
            "Final evidence selection returned no evidence."
        )

    if demo_mode:

        for ev in final_evidence:

            ev_text = str(
                ev.get(
                    "text",
                    "",
                )
            ).strip()

            if len(ev_text) > 1000:

                ev["text"] = (
                    ev_text[:1000]
                    + "\n"
                    "[Truncated for compact demo analysis]"
                )

    print(
        f"Final evidence selected: "
        f"{len(final_evidence)}"
    )

    # Preserve existing RAG adapter contract.

    evidence_records = (
        adapt_retrieval_results(
            final_evidence
        )
    )

    print(
        f"Adapted evidence records: "
        f"{len(evidence_records)}"
    )

    # ========================================================
    # 2. GPT-OSS EVIDENCE CLASSIFICATION
    # ========================================================

    t_stage = time.perf_counter()

    print(
        "\n[2/9] GPT-OSS evidence classification..."
    )
    workflow_stages.append("GPT-OSS Classification")

    deadline = t_start + time_budget_seconds
    rem_stage2 = max(2.0, deadline - time.perf_counter())
    stage2_timeout = min(10.0, max(2.0, rem_stage2 * 0.35)) if demo_mode else None

    evidence_classification = (
        classify_evidence(
            claim=question,
            evidence_records=evidence_records,
            demo_mode=demo_mode,
            timeout=stage2_timeout,
        )
    )

    if (
        evidence_classification.get(
            "status"
        )
        != "SUCCESS"
    ):

        err_msg = (
            evidence_classification.get(
                "error"
            )
            or evidence_classification.get(
                "status"
            )
        )

        print(
            f"Evidence classification failed: "
            f"{err_msg}"
        )

        raise RuntimeError(
            f"Evidence classification failed: "
            f"{err_msg}"
        )

    validation = (
        validate_evidence_consistency(
            classifications=(
                evidence_classification
            ),
            evidence_records=(
                evidence_records
            ),
        )
    )

    if not validation["valid"]:

        raise RuntimeError(
            "Evidence consistency validation failed: "
            + str(
                validation["errors"]
            )
        )

    performance[
        "evidence_classification_ms"
    ] = round(
        (
            time.perf_counter()
            - t_stage
        ) * 1000,
        2,
    )

    print(
        "Evidence classification: PASS"
    )

    # ========================================================
    # 3. EVIDENCE ENGINE
    # ========================================================

    t_stage = time.perf_counter()

    print(
        "\n[3/9] Evidence Engine..."
    )
    workflow_stages.append("Evidence Sufficiency Engine")

    claim = build_claim_assessment(
        evidence_classification,
        evidence_records,
    )

    evidence_engine = EvidenceEngine()

    evidence_assessment = (
        evidence_engine.assess(
            claims=[
                claim
            ]
        )
    )

    evidence_dict = (
        _assessment_to_dict(
            evidence_assessment
        )
    )

    performance[
        "evidence_engine_ms"
    ] = round(
        (
            time.perf_counter()
            - t_stage
        ) * 1000,
        2,
    )

    print(
        "Evidence status:",
        evidence_dict[
            "overall_status"
        ],
    )

    # ========================================================
    # 4. ABSENCE VERIFICATION
    # ========================================================

    t_stage = time.perf_counter()

    print(
        "\n[4/9] Absence Verification..."
    )
    workflow_stages.append("Absence Verification")

    absence = build_absence_verification(
        claim=question,

        evidence_records=evidence_records,

        search_scope=(
            "HackGrid RAG knowledge base; "
            f"jurisdiction={jurisdiction}; "
            f"{len(results)}-candidate "
            "jurisdiction-filtered retrieval "
            "with reranking and counter-evidence search"
        ),

        authoritative_jurisdictions=[
            jurisdiction
        ],
    )

    absence_dict = (
        absence_verification_to_dict(
            absence
        )
    )

    performance[
        "absence_ms"
    ] = round(
        (
            time.perf_counter()
            - t_stage
        ) * 1000,
        2,
    )

    # ========================================================
    # 5. GAP ANALYSIS
    # ========================================================

    t_stage = time.perf_counter()

    print(
        "\n[5/9] Gap Analysis..."
    )
    workflow_stages.append("Gap Analysis")

    gap_input = build_gap_input(
        evidence_assessment=(
            evidence_assessment
        ),

        absence_verifications=[
            absence_dict
        ],

        question=question,
    )

    performance[
        "gap_ms"
    ] = round(
        (
            time.perf_counter()
            - t_stage
        ) * 1000,
        2,
    )

    # ========================================================
    # 6. EXISTING RISK + AUTHORITY ENGINE
    # ========================================================

    t_stage = time.perf_counter()

    print(
        "\n[6/9] Risk Engine..."
    )
    workflow_stages.append("Risk & Governance Engine")

    risk_context = DecisionContext(
        domain=(
            classification.get(
                "domain",
                "General Evidence",
            )
        ),

        decision_impact=(
            DecisionImpact.REGULATORY
        ),

        consequence_score=85,

        authority_requirement=(
            AuthorityRequirement.SENIOR_AUTHORITY
        ),

        sensitive_information=True,

        external_action=True,

        production_change=False,

        legal_or_regulatory_interpretation=True,

        affects_public_safety=True,

        affects_critical_infrastructure=True,
    )

    ai_analysis = AIAnalysis(
        confidence=max(
            0.0,
            min(
                1.0,
                evidence_assessment.overall_confidence,
            ),
        ),

        factual_claims=len(
            evidence_classification.get(
                "classifications",
                [],
            )
        ),

        supported_claims=(
            evidence_assessment.supporting_count
        ),

        unsupported_claims=len(
            evidence_assessment.missing_evidence
        ),

        hallucination_risk=max(
            0.0,
            min(
                1.0,
                1.0
                - evidence_assessment.overall_confidence,
            ),
        ),

        novel_situation=False,
    )

    risk_assessment = (
        assess_with_evidence_engine(
            decision_context=risk_context,
            evidence_assessment=(
                evidence_assessment
            ),
            ai_analysis=ai_analysis,
        )
    )

    risk_dict = (
        risk_assessment_to_dict(
            risk_assessment
        )
    )

    performance[
        "risk_ms"
    ] = round(
        (
            time.perf_counter()
            - t_stage
        ) * 1000,
        2,
    )

    print(
        "Risk:",
        risk_dict["risk_level"],
        risk_dict["risk_score"],
        risk_dict["escalation_level"],
    )

    # ========================================================
    # 6B. POLICY <-> STANDARD MAPPING ENGINE
    # ========================================================

    t_stage = time.perf_counter()

    print(
        "\n[6B/9] Policy <-> Standard Mapping Engine..."
    )

    mapping_engine = PolicyStandardMappingEngine(
        target_jurisdiction=jurisdiction
    )

    policy_standard_mapping = mapping_engine.map_evidence(
        evidence_records=final_evidence,
        question=question,
    )

    performance[
        "policy_mapping_ms"
    ] = round(
        (
            time.perf_counter()
            - t_stage
        ) * 1000,
        2,
    )

    print(
        f"Mappings: {len(policy_standard_mapping['mappings'])} | "
        f"Gaps: {len(policy_standard_mapping['gaps'])} | "
        f"Sufficiency: {policy_standard_mapping['sufficiency']['requirement_mapping']}"
    )

    # ========================================================
    # 7. FINAL GPT-OSS SYNTHESIS
    # ========================================================

    t_stage = time.perf_counter()

    print(
        "\n[7/9] Final GPT-OSS synthesis..."
    )
    workflow_stages.append("GPT-OSS Final Synthesis")

    # ========================================================
    # 6C. REGIONAL COMPARATIVE GAP ANALYSIS
    # ========================================================

    regional_analysis = None
    q_lower = question.lower()
    auto_regional = any(
        kw in q_lower
        for kw in [
            "regional", "neighbouring", "neighboring", "comparative",
            "bangladesh", "sri lanka", "pakistan", "nepal", "bhutan",
            "cross-jurisdiction", "neighbour", "neighbor"
        ]
    )
    effective_regional_mode = regional_mode
    if effective_regional_mode == "OFF" and auto_regional:
        effective_regional_mode = "COMPARATIVE"

    if effective_regional_mode != "OFF":
        t_stage = time.perf_counter()
        print("\n[6C/9] Regional Comparative Gap Analysis Engine...")
        domain_name = classification.get("domain") or "telecom"
        regional_engine = RegionalComparativeGapEngine(
            host_jurisdiction=jurisdiction,
            regional_mode=effective_regional_mode,
        )
        regional_result_obj = regional_engine.compare(
            evidence_records=final_evidence,
            question=question,
            domain=domain_name,
        )
        regional_analysis = regional_result_obj.to_dict()
        performance["regional_gap_ms"] = round(
            (time.perf_counter() - t_stage) * 1000, 2
        )
        print(
            f"Regional Mode: {effective_regional_mode} | "
            f"Gap Status: {regional_analysis['gap_status']} | "
            f"Action: {regional_analysis['action']} | "
            f"Human Review: {regional_analysis['human_review_required']}"
        )

    # ========================================================
    # 7. FINAL GPT-OSS SYNTHESIS
    # ========================================================

    t_stage = time.perf_counter()

    print(
        "\n[7/9] Final GPT-OSS synthesis..."
    )

    rem_stage7 = deadline - time.perf_counter()
    if demo_mode and rem_stage7 < 6.0:
        print("[7/9] Live demo budget deadline approaching (<6s); generating evidence-grounded fallback synthesis.")
        from Backend.final_synthesis import _generate_fallback_synthesis
        final = _generate_fallback_synthesis(
            question=question,
            evidence_records=evidence_records,
            classification=evidence_classification,
            evidence_assessment=evidence_dict,
            absence_verifications=[
                absence_dict
            ],
            gap_input=gap_input,
            risk_assessment=risk_dict,
            counter_evidence_analysis=ranking_evidence_analysis,
            policy_standard_mapping=policy_standard_mapping,
            regional_comparative_analysis=regional_analysis,
        )
    else:
        stage7_timeout = min(15.0, max(3.0, rem_stage7 - 2.0)) if demo_mode else None
        final = (
            synthesize_final_assessment(
                question=question,
                evidence_records=evidence_records,
                classification=evidence_classification,
                evidence_assessment=evidence_dict,
                absence_verifications=[
                    absence_dict
                ],
                gap_input=gap_input,
                risk_assessment=risk_dict,
                demo_mode=demo_mode,
                counter_evidence_analysis=ranking_evidence_analysis,
                policy_standard_mapping=policy_standard_mapping,
                regional_comparative_analysis=regional_analysis,
                timeout=stage7_timeout,
            )
        )

    # ========================================================
    # 7B. PRE-OUTPUT CLAIM VALIDATION GATE
    # ========================================================

    final = validate_synthesis_claims(
        synthesis_result=final,
        evidence_records=evidence_records,
    )

    if regional_analysis:
        final = validate_regional_claims(
            synthesis_result=final,
            regional_analysis=regional_analysis,
        )

    performance[
        "synthesis_ms"
    ] = round(
        (
            time.perf_counter()
            - t_stage
        ) * 1000,
        2,
    )

    # ========================================================
    # GOVERNANCE
    # ========================================================

    governance = evaluate_governance(
        question=question,
        evidence_assessment=evidence_dict,
        gap_analysis=gap_input,
        risk_assessment=risk_dict,
        final_synthesis=final,
        classification=evidence_classification,
    )

    # ========================================================
    # 8. CLAIM -> EVIDENCE MAPPINGS
    # ========================================================

    print(
        "\n[8/9] Building claim -> evidence mappings..."
    )
    workflow_stages.append("Claim-Evidence Mapping")

    mappings = []

    for claim_item in final.get(
        "claims",
        [],
    ):

        mappings.append(
            {
                "claim_id": claim_item.get(
                    "claim_id"
                ),

                "claim": claim_item.get(
                    "claim"
                ),

                "status": claim_item.get(
                    "status"
                ),

                "evidence_ids": claim_item.get(
                    "evidence_ids",
                    [],
                ),

                "confidence": claim_item.get(
                    "confidence",
                    0.0,
                ),
            }
        )

    # ========================================================
    # 9. AUDIT
    # ========================================================

    t_stage = time.perf_counter()

    print(
        "\n[9/9] Writing audit trail..."
    )
    workflow_stages.append("Audit Trail Ledger")

    audit_record = create_audit_record(
        question=question,

        model="openai/gpt-oss-120b",

        execution_id=exec_id,

        event_type=event_type,

        execution_status="COMPLETED",

        scenario_id=scenario_id,

        scenario_title=scenario_title,

        step_id=step_id,

        step_title=step_title,

        workflow_stages=workflow_stages,

        provenance="RUNTIME_EXECUTION",

        domain=classification.get("domain") if "classification" in locals() and isinstance(classification, dict) else None,

        jurisdiction=jurisdiction,

        retrieved_evidence=evidence_records,

        evidence_classification=(
            evidence_classification
        ),

        evidence_assessment=evidence_dict,

        absence_verification=[
            absence_dict
        ],

        gap_analysis=gap_input,

        risk_assessment=risk_dict,

        final_synthesis=final,

        claim_evidence_mappings=mappings,

        human_review_required=(
            risk_dict[
                "human_review_required"
            ]
        ),

        final_decision=(
            "PENDING_HUMAN_REVIEW"
            if risk_dict[
                "human_review_required"
            ]
            else "SYSTEM_RECOMMENDATION"
        ),
        notes=notes or [],
    )

    if regional_analysis:
        audit_record["regional_comparative_analysis"] = {
            "host_jurisdiction": regional_analysis.get("host_jurisdiction"),
            "regional_jurisdictions": regional_analysis.get("regional_jurisdictions"),
            "regional_evidence_ids": regional_analysis.get("evidence_ids"),
            "gap_status": regional_analysis.get("gap_status"),
            "human_review_required": regional_analysis.get("human_review_required"),
            "coverage_status": regional_analysis.get("coverage_status"),
        }

    audit_id = append_audit_record(
        audit_record
    )

    performance[
        "audit_ms"
    ] = round(
        (
            time.perf_counter()
            - t_stage
        ) * 1000,
        2,
    )

    performance[
        "total_ms"
    ] = round(
        (
            time.perf_counter()
            - t_start
        ) * 1000,
        2,
    )

    # ========================================================
    # RETURN STRUCTURED RESULT
    # ========================================================

    return {
        "question": question,

        "execution_mode": (
            "DEMO"
            if demo_mode
            else "FULL"
        ),

        "execution_config": (
            execution_config
        ),

        "performance": performance,

        # Selected jurisdiction
        "jurisdiction": jurisdiction,

        "jurisdiction_sources": {
            "selected_jurisdiction": (
                jurisdiction
            ),

            "included_jurisdictions": [
                jurisdiction,
                "International",
            ],
        },

        # Domain + intent
        "query_analysis": classification,

        # Original retrieval count
        "retrieval_candidates": len(
            results
        ),

        # Primary reranking
        "reranked_evidence": (
            reranked_results[:3]
            if demo_mode
            else reranked_results
        ),

        # Counter evidence
        "counter_evidence_query": (
            counter_evidence_query
        ),

        "counter_evidence_candidates": (
            len(counter_results)
        ),

        "counter_evidence": (
            counter_reranked_results[:2]
            if demo_mode
            else counter_reranked_results
        ),

        "counter_evidence_analysis": (
            final.get("counter_evidence", [])
        ),

        # Evidence analysis
        "evidence_analysis": (
            ranking_evidence_analysis
        ),

        # Final evidence passed downstream
        "retrieval": RetrievalList(
            evidence_records[:4]
            if demo_mode
            else evidence_records
        ),

        # Existing pipeline
        "classification": (
            evidence_classification
        ),

        "validation": validation,

        "evidence_assessment": (
            evidence_dict
        ),

        "absence_verification": (
            absence_dict
        ),

        "gap_analysis": gap_input,

        "risk_assessment": risk_dict,

        "final_synthesis": final,

        "claim_evidence_mappings": (
            mappings
        ),

        "governance": governance,

        # Policy <-> Standard Mapping Engine Results
        "policy_standard_mappings": policy_standard_mapping.get("mappings", []),
        "extracted_requirements": policy_standard_mapping.get("extracted_requirements", []),
        "genuine_gaps": policy_standard_mapping.get("gaps", []),
        "decision_sufficiency": policy_standard_mapping.get("sufficiency", {}),

        # Regional Comparative Gap Analysis
        "regional_comparative_analysis": regional_analysis,

        "notes": notes or [],

        "audit_id": audit_id,
        "execution_id": exec_id,
        "event_type": event_type,
        "workflow_stages": workflow_stages,
    }


# ============================================================
# MANUAL EXECUTION
# ============================================================

def main():

    result = run_pipeline(
        QUESTION,
        jurisdiction="India",
        demo_mode=False,
    )

    # ========================================================
    # FINAL OUTPUT
    # ========================================================

    print(
        "\n" + "=" * 80
    )

    print(
        "HACKGRID FINAL ASSESSMENT"
    )

    print(
        "=" * 80
    )

    print(
        json.dumps(
            result["final_synthesis"],
            indent=2,
            ensure_ascii=False,
        )
    )

    print(
        "\n" + "=" * 80
    )

    print(
        "GOVERNANCE"
    )

    print(
        "=" * 80
    )

    print(
        json.dumps(
            result["risk_assessment"],
            indent=2,
            ensure_ascii=False,
        )
    )

    print(
        "\n" + "=" * 80
    )

    print(
        "AUDIT"
    )

    print(
        "=" * 80
    )

    print(
        "Audit ID:",
        result["audit_id"],
    )

    print(
        "\nFULL ORCHESTRATOR: PASS"
    )


if __name__ == "__main__":
    main()