{
  "schema_version": "1.0",
  "audit_id": "20260815_sol_canonical",
  "audit_type": "canonical_research_review",
  "as_of_date": "2026-08-15",
  "reviewer": {
    "reviewer_model": "gpt-5.6-sol",
    "reviewer_family": "openai",
    "review_independence": "same-family",
    "acceptance_status": "provisional",
    "role": "fresh zero-context ARIS research-review jury"
  },
  "scope": {
    "venue": "ICASSP 2027",
    "decision_stage": "entry into research-refine, not submission readiness",
    "proposal_reviewed": {
      "primary": "warp-equivariant-private-phase-flow",
      "masked_geometric_tssm_role": "mechanism-matched control only",
      "identity_private_state_role": "causal diagnostic only"
    },
    "evidence_policy": "Only the eight declared raw inputs were used as scientific evidence. No result was inferred from a plan, threshold, code fragment, or historical server artifact.",
    "same_family_provisional": true
  },
  "input_ledger": [
    {
      "path": "RESEARCH_BRIEF.md",
      "sha256": "f5b9d75fc2415a03ba250279edf1e47af978341b7b9d7eef892f2d43a56b7c37"
    },
    {
      "path": "idea-stage/IDEA_REPORT.md",
      "sha256": "6105bcc49d1a4756b7927e87f02d3b38d23ed0d6115f344409d7d8a68c0d2610"
    },
    {
      "path": "idea-stage/IDEA_CANDIDATES.md",
      "sha256": "209d903b86fdb3655f0ca423aab6e7d8788ff5a53cf0c6ddbc514cabbd7c5edd"
    },
    {
      "path": "idea-stage/IDEA_CREATOR_JURY.json",
      "sha256": "c0fdbd622af448b30e31be97cf6c6f05ae20ec88a7bedd31f04c211d92af8d60"
    },
    {
      "path": "idea-stage/NOVELTY_CHECK.json",
      "sha256": "79749893547c834d876801c287bfa2f048b4797c838f7f6d46155318258ed3e5"
    },
    {
      "path": "EXPERIMENT_AUDIT.md",
      "sha256": "2ac7fe4a1a8208287394a2ac4c1771aa0faf30e14319bef8144e509f876f0820"
    },
    {
      "path": "SERVER_METHOD_INVENTORY.md",
      "sha256": "0cda0704f64434296049d18c35e97fd267a0a7168300152e97b142d6ecc363a6"
    },
    {
      "path": "PILOT_DATA_SCHEMA_AUDIT.md",
      "sha256": "7058981e8eb37622c09f5808a4b1329bc7cd133f474101723f15e5e4273eab25"
    }
  ],
  "evidence_status": {
    "eligible_method_results": 0,
    "canonical_implementation_exists": false,
    "frozen_paper_evaluator_exists": false,
    "predicted_track_evidence_exists": false,
    "submission_ready": false,
    "historical_artifacts": {
      "v46": "Ineligible: count-label-supervised ExtraTrees/calibration system on compromised GT-assisted protocols; not the proposed method.",
      "v62": "Ineligible: single-seed development result with incomplete provenance; not the proposed method.",
      "v63": "Ineligible: code-only channel classifier with no bound run or evidence bundle."
    },
    "interpretation": "All performance thresholds are prospective kill gates, not results."
  },
  "scores": {
    "scale": "1-10, where 10 is strongest for entry into a disciplined research-refine phase",
    "problem_significance": {
      "score": 7.7,
      "reason": "Per-person counting under within-track tempo drift is meaningful for MRAC and exposes failures hidden by scene totals, although the presently usable data are narrow and GT-assisted."
    },
    "novelty_residual": {
      "score": 4.5,
      "reason": "MRAC, pose periodic SSL, local phase, temporal equivariance, localized speed perturbation, per-track memory, TSSM, and reconstruction are occupied. Only the exact explicit warp-derivative law for signed local phase increments in identity-indexed MRAC remains plausible, and TWCRAC overlap is unresolved."
    },
    "method_specificity": {
      "score": 6.0,
      "reason": "The modules and interventions are named, but the warp convention, phase identifiability, discrete clock, losses, decoder, capacity controls, and primary estimand are not frozen."
    },
    "scientific_falsifiability": {
      "score": 8.0,
      "reason": "Derivative-law, matched-prior, shortcut, collapse, harmonic, and identity-interference tests can decisively reject the mechanism if preregistered before development-label use."
    },
    "protocol_integrity": {
      "score": 3.7,
      "reason": "The current cache is partial, GT-bbox-assisted, and label-mixed; density reveals count, official instance matching is unavailable, temporal sampling contains duplicates, and the main-result protocol is unfrozen."
    },
    "feasibility": {
      "score": 5.2,
      "reason": "A bounded supplied-track pilot is feasible after repacking, but no server tree implements it, timestamps/FPS are absent, pose coverage is incomplete, and predicted-track evaluation cannot run."
    },
    "icassp_fit": {
      "score": 7.0,
      "reason": "An explicit phase/time-warp transformation law fits signal processing if the paper reports actual phase behavior and avoids a crowded module stack."
    },
    "overall": {
      "score": 5.7,
      "reason": "The question merits one kill-oriented pilot, but the current proposal is not precise or protocol-clean enough for READY."
    }
  },
  "verdict": {
    "code": "REVISE",
    "stage": "entering research-refine",
    "proceed_to_research_refine": true,
    "proceed_mode": "conditional, one bounded kill-oriented primary pilot",
    "freeze_method": false,
    "freeze_novelty_claim": false,
    "authorize_performance_claims": false,
    "rationale": "The role ordering is correct and does not require a wholesale rethink. Research-refine is authorized to close the method, data, comparator, and kill-test specifications below. Training remains blocked until the physical label-vault and protocol gates pass."
  },
  "exact_problem_anchor": {
    "research_question": "On GT-bbox-assisted supplied pose tracks, does enforcing an explicit local time-warp derivative transformation law on signed phase increments in identity-private state improve per-person repetition counting under predeclared within-track tempo drift, relative to matched augmentation-only, PAMS/Track-PAMS, SimPer-style, CycleCL-style, DeepPhase-style, and generic time-equivariant controls, while the counting objective reads no per-person count or period labels?",
    "population": "Checksum-frozen, canonical-source-disjoint MultiRep train/development data available through the partial supplied-pose cache, explicitly treated as pilot-only.",
    "unit_of_analysis": "Video, with per-person outputs aggregated by video-first AvgMAE and AvgOBO equations; source-connected components are the resampling clusters.",
    "primary_estimand": "Paired development-set change in video-level AvgMAE between the derivative-law model and the identical augmentation-only model under the predeclared within-track tempo-drift diagnostic.",
    "secondary_estimands": [
      "Supplied-track Period-mAP, AP50, and AP75 on a frozen explicit scale, labeled as supplied-track diagnostics rather than published end-to-end comparisons.",
      "Clean-to-warp degradation and phase-correspondence error.",
      "Untouched-person response and count change under a one-person tempo intervention."
    ],
    "excluded_questions": [
      "Whether local windows, phase, temporal equivariance, pose SSL, TSSM, private memory, overlap-add, or per-person output are individually novel.",
      "Whether the method is end-to-end, annotation-free, state of the art, or deployment-ready.",
      "Whether a supplied-track partial-cache result establishes predicted-track MRAC."
    ]
  },
  "closest_prior_adjudication": [
    {
      "prior": "PAMS",
      "collision": "Self-supervised skeleton periodic learning, period-adaptive multi-scale consistency, inference expert consensus, and localized 5-7 second internal-tempo perturbation are already covered.",
      "required_boundary": "Treat multi-segment per-identity drift as a stronger stress extension, not a first. Compare PAMS and Track-PAMS on identical tracks; PAMS experts are inference configurations."
    },
    {
      "prior": "SimPer",
      "collision": "Periodicity-varying augmentations and continuous frequency-aware learning are already covered.",
      "required_boundary": "Speed augmentation alone carries no claim; only the signed local derivative law tied to identity-indexed MRAC is testable residual."
    },
    {
      "prior": "CycleCL",
      "collision": "Phase-sensitive self-supervised periodic representation is already covered.",
      "required_boundary": "Show added value beyond matched phase-sensitive learning, not merely that phase can be learned."
    },
    {
      "prior": "DeepPhase",
      "collision": "Unsupervised local motion-phase manifolds and phase-conditioned reconstruction are already covered.",
      "required_boundary": "Do not claim unsupervised phase, local phase, or reconstruction; include a capacity-matched DeepPhase-style control."
    },
    {
      "prior": "Time-Equivariant Contrastive Video Representation Learning",
      "collision": "Temporal transformation equivariance is an established representation-learning principle.",
      "required_boundary": "Ablate explicit derivative scaling against matched generic time-equivariant learning with identical warps and capacity."
    },
    {
      "prior": "TWCRAC",
      "collision": "The accessible record covers time-window-cycle framing, intra-video TCC, pose, local periodic statistics, dynamic thresholds, and non-stationary motion; full-method overlap is unresolved.",
      "required_boundary": "Inspect the complete paper before claim freeze. Equivalent local derivative-law disclosure kills the primary novelty anchor."
    },
    {
      "prior": "MultiCounter and MultiCounter+",
      "collision": "MRAC, identity-indexed outputs, spatial-temporal consistency, and variable-period multi-person counting are established.",
      "required_boundary": "Use them as task/protocol context; never claim first MRAC, per-person counting, or identity consistency."
    },
    {
      "prior": "RepNet, Motion Feature Learning, HTRM-Net, Rethinking TSM, and JTSPS-Net",
      "collision": "TSSM, time-varying period, TSM reconstruction, matrix dropping, local context, skeleton self-similarity, and response decoding are crowded.",
      "required_boundary": "Masked geometric TSSM completion is a control only and cannot replace a failed primary without a new review."
    }
  ],
  "contribution_cap": {
    "maximum_scientific_contributions": 2,
    "method_contribution": "At most one: an empirically supported explicit local warp-derivative objective for signed phase increments in identity-indexed supplied-pose MRAC.",
    "diagnostic_contribution": "At most one: a one-person tempo intervention measuring causal leakage into untouched identities.",
    "control_only": "Masked geometric TSSM ridge completion.",
    "established_operators_not_contributions": [
      "Identity-private buffers or recurrent state allocation",
      "Local windows",
      "Pose or skeleton input",
      "Time-warp augmentation",
      "Phase representation",
      "Normalized overlap-add",
      "Half-open boundary handling",
      "One decode per identity",
      "Supplied-versus-predicted protocol separation",
      "External tracking components"
    ],
    "paper_scope_rule": "For a 4+1 page ICASSP paper, use one phase-flow mechanism, one derivative-law ablation, one compact closest-prior comparison, and one identity-interference diagnostic. Do not add learned tempo experts, a second pretext method, re-entry caches, spectral estimator stacks, or a protocol-as-novelty story."
  },
  "mandatory_revisions": [
    {
      "priority": 1,
      "gate": "before any training",
      "revision": "Build feature-only train/development artifacts and a separately permissioned evaluator label vault. Reject count_gt, density_gt, period/cycle boundaries, raw annotation boxes, object IDs/mappings, and all privileged keys before training-process deserialization; hash every shard and record a forbidden-key receipt."
    },
    {
      "priority": 2,
      "gate": "before any training",
      "revision": "Freeze the canonical-source connected-component split, checksums, source-component bootstrap plan, untouched development evaluator, and forbidden test paths. Mark every artifact partial-cache, GT-bbox-assisted, and supplied-track."
    },
    {
      "priority": 3,
      "gate": "before implementation freeze",
      "revision": "Choose one story: the explicit derivative-law phase-flow. Do not merge the research brief's learned tempo-expert router with it. TSSM remains a control and private state remains a diagnostic."
    },
    {
      "priority": 4,
      "gate": "before implementation freeze",
      "revision": "Write the exact discrete warp convention and derive the signed phase-increment target. Define unit-circle unwrapping, reversal, pause/zero-derivative behavior, aliasing, harmonic ambiguity, missing joints, window seams, and one-decode mass accounting."
    },
    {
      "priority": 5,
      "gate": "before implementation freeze",
      "revision": "Use sampled_frame_indices and source_length as the only clock evidence. Specify masking for repeated indices and zero time steps; do not assume 320 strictly increasing samples or available FPS/timestamps."
    },
    {
      "priority": 6,
      "gate": "before model selection",
      "revision": "Freeze compute- and input-matched comparators: track-global autocorrelation, stationary local windows, identical augmentation-only, PAMS, Track-PAMS, SimPer-style, CycleCL-style, DeepPhase-style, generic time-equivariant contrast, and direct signed-frequency regression."
    },
    {
      "priority": 7,
      "gate": "before model selection",
      "revision": "Preregister one primary endpoint, one minimum effect, one uncertainty rule, and the exact Period-mAP scale. Eliminate the current AvgMAE-or-Period-mAP escape hatch, reconcile 80%-of-performance versus 20%-of-gain shortcut thresholds, and declare the 10-20% clean-to-warp degradation gray zone. Use three independent full runs, sample standard deviation, and paired source-component bootstrap intervals."
    },
    {
      "priority": 8,
      "gate": "before model selection",
      "revision": "Freeze no-pose/timestamp-only, nuisance-metadata, matched-time pose shuffle, unseen resampler, reversal, frame-order shuffle, camera/amplitude, harmonic/half-frequency, collapse-variance, and effective-rank controls."
    },
    {
      "priority": 9,
      "gate": "after the primary backbone exists",
      "revision": "Run private state only as a causal diagnostic against stateless, shared-scene, reset, swap, shuffled-ID, and track-length/confidence-only controls; instrument all state and response buffers for cross-ID contamination."
    },
    {
      "priority": 10,
      "gate": "before claim freeze",
      "revision": "Obtain complete TWCRAC, rerun the novelty boundary, and keep local-window/cycle/dynamic-tempo claims unresolved until then."
    },
    {
      "priority": 11,
      "gate": "throughout research-refine",
      "revision": "Keep v46, v62, and v63 outside efficacy evidence. Bind the clean implementation to commit, configuration, environment, hardware, seed, logs, checkpoints, predictions, and completion receipt."
    }
  ],
  "kill_conditions": [
    {
      "id": "K1",
      "condition": "The derivative-law model misses the single preregistered primary minimum effect over identical augmentation-only, or its paired source-component interval fails the decision rule.",
      "action": "Kill the primary mechanism."
    },
    {
      "id": "K2",
      "condition": "PAMS/Track-PAMS, SimPer-style, CycleCL-style, DeepPhase-style, or matched generic time-equivariant learning matches or exceeds it within uncertainty.",
      "action": "Kill the residual method claim; private state and TSSM cannot rescue it."
    },
    {
      "id": "K3",
      "condition": "Removing derivative scaling, using direct frequency regression, or using global resampling only matches the model within uncertainty.",
      "action": "Conclude that the explicit local transformation law is empirically redundant."
    },
    {
      "id": "K4",
      "condition": "A timestamp/no-pose or nuisance-only model retains more than the final preregistered forbidden fraction of gain, unseen resamplers erase the gain, or pose shuffling preserves phase/count behavior.",
      "action": "Reject the result as augmentation or clock shortcut."
    },
    {
      "id": "K5",
      "condition": "Phase/response collapse, low effective rank, reversal-sign instability, half/double-frequency locking, seam mass error, or non-identifiable phase exceeds preregistered tolerances.",
      "action": "Kill phase-flow instead of adding post hoc modules."
    },
    {
      "id": "K6",
      "condition": "Feature/label separation, source isolation, forbidden-key receipt, untouched evaluator, or test-access controls cannot be demonstrated.",
      "action": "Stop; no count/period-label-restricted claim is licensed."
    },
    {
      "id": "K7",
      "condition": "Missing-pose selection or repeated-frame timing prevents a defensible estimand, or the method requires unavailable FPS/timestamps.",
      "action": "Rebuild the cache or restrict work to engineering diagnostics."
    },
    {
      "id": "K8",
      "condition": "Complete TWCRAC inspection reveals the same explicit local warp-derivative phase mechanism or an equivalent contribution.",
      "action": "Kill or materially re-anchor novelty before drafting."
    },
    {
      "id": "K9",
      "condition": "The primary fails and masked geometric TSSM is proposed as an automatic replacement.",
      "action": "Stop. TSSM remains a control unless a separate preregistered study and fresh novelty review authorize a new anchor."
    }
  ],
  "protocol_integrity_ruling": {
    "permitted_name": "GT-bbox-assisted AlphaPose supplied-track partial-cache development pilot",
    "forbidden_interpretations": [
      "Predicted-track evaluation",
      "End-to-end MRAC",
      "Official MultiRep main result",
      "Direct same-protocol comparison with published MultiCounter or MultiCounter+ end-to-end values",
      "HOTA, IDF1, or ID-switch evidence",
      "Annotation-free training"
    ],
    "critical_facts": [
      "The cache covers 110 of 794 train videos and 51 of 183 validation videos, creating pose-success selection risk.",
      "GT boxes and object mappings form person slots; thirteen train and eight validation slots are ambiguous.",
      "Current pickles colocate inputs with count_gt and density_gt, and density_gt sums to count_gt.",
      "Forty-five training videos are shorter than 320 frames and can contain up to 151 adjacent duplicate sample steps.",
      "AvgMAE and AvgOBO require video-first averaging; the historical MotionBERT scorer pools people.",
      "Supplied-track temporal AP bypasses official instance localization and must be labeled diagnostic."
    ]
  },
  "server_feasibility_ruling": {
    "bounded_pilot_feasible": true,
    "main_paper_evidence_feasible_now": false,
    "basis": [
      "The partial train/development cache is hashable and source-disjoint, so a controlled pilot is possible after physical label separation.",
      "No inventoried PAMS or MotionBERT tree contains the integrated primary method.",
      "Normalized overlap-add exists only as an isolated primitive; no identity-indexed derivative-law phase stack exists.",
      "No predicted-track cache, autonomous identity trajectory, frozen tracker, or tracking metric artifact is available.",
      "Implementation must start on a clean bound branch; historical results are unusable as efficacy evidence."
    ]
  },
  "final_direction": {
    "proceed": true,
    "primary": "Advance exactly one bounded warp-equivariant-private-phase-flow pilot after mandatory gates 1-8 pass.",
    "control": "Use masked-geometric-tssm-ridge-completion only as a mechanism-matched control; never promote it automatically.",
    "diagnostic": "Use identity-private-state-isolation only after the primary backbone exists and only as a causal diagnostic.",
    "stop_rule": "If the explicit derivative-law residual fails, stop method expansion and revisit the research question.",
    "status": "same-family provisional; no novelty clearance; no performance evidence; no submission-readiness implication"
  }
}

