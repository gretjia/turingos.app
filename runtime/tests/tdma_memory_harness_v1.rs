//! TRACE_MATRIX FC1a-Q_t + FC1b-Q_{t+1} + FC2-boot_loop + FC3-replay:
//! TuringOS-Memory-Harness-V1 — 9 acceptance gates for TDMA-Bounded-RC1.
//!
//! Each gate exercises ONE invariant from the directive's §14 nine-gate
//! manifest. If any gate FAILS, RC1 GA is BLOCKED.
//!
//! On-disk §8: handover/directives/2026-05-22_TDMA_BOUNDED_RC1_DIRECTIVE_AND_§8.md
//! Orchestrator plan §6 + §8 acceptance suite.

use turingosv4::charter_core::{
    compile_charter_core, validate_charter_core_freshness, CharterDriftError,
};
use turingosv4::ledger::{
    AttemptScope, CommitRequest, ImmutableTapeLedger, MemoryTapeLedger, NodeKind,
};
use turingosv4::memory_kernel::{EnvironmentResult, KernelStep, MemoryKernel, Task};
use turingosv4::state_update::{parse_prefix_json, HeaderParseError};
use turingosv4::token_budget::{B_HEADER, B_HEADER_SCAN, B_PROMPT_MAX};
use turingosv4::tokenizer::Tokenizer;

// ── helpers ──────────────────────────────────────────────────────

fn fresh_kernel() -> MemoryKernel<MemoryTapeLedger> {
    let mut tape = MemoryTapeLedger::new();
    tape.set_verified_head("H0".into());
    let charter = compile_charter_core(
        "# Constitution\n## Art. 0.4 — Q_t version control\nFC1a tape_t.\n".as_bytes(),
        "v1.0",
        &Tokenizer::new(),
    );
    MemoryKernel::new(tape, "run-harness", charter)
}

fn retry_header(task_id: &str, predicate: &str, reject_class: &str) -> String {
    format!(
        r#"{{"schema_version":"tdma-state-update/v1","status":"Retry","task_id":"{}","action":"RETRY","failed_predicate":"{}","reject_class":"{}"}}
---BODY---
needs another try"#,
        task_id, predicate, reject_class
    )
}

// ── GATE 1 ───────────────────────────────────────────────────────
// token_invariance_under_50_retries — the 50-retry blow-out test.
// 50 consecutive failures must keep prompt size bounded by B_PROMPT_MAX.
#[test]
fn gate_1_token_invariance_under_50_retries() {
    // Local MAX_RETRIES override pattern: this test runs 50 retries even
    // though the global MAX_RETRIES=5 — we collect the prompt sizes BEFORE
    // escalation triggers, then assert invariance among those sizes.
    let mut k = fresh_kernel();
    let task = Task {
        id: "gate1".into(),
        prompt: "Prove X.".into(),
    };
    let mut prompt_token_counts = Vec::new();
    let tk = Tokenizer::new();

    for i in 0..50 {
        // Each retry has a 10KB raw_stderr payload.
        let raw_stderr = format!("{}\n", "x".repeat(10_000) + &format!(" line_{}", i));
        let env = EnvironmentResult {
            raw_output: retry_header("gate1", "x.y", "schema-fail"),
            raw_stderr,
            success: false,
        };
        match k.step_forward(&task, env) {
            KernelStep::Retry { prompt, .. } => {
                let n = tk.count_text(&prompt);
                assert!(
                    n <= B_PROMPT_MAX,
                    "gate 1: prompt[{}] tokens {} > B_PROMPT_MAX={}",
                    i,
                    n,
                    B_PROMPT_MAX
                );
                prompt_token_counts.push(n);
            }
            KernelStep::Escalate { .. } => {
                // Hit MAX_RETRIES escalation — that's fine; the invariance
                // assertion is on the prompts produced BEFORE escalation.
                break;
            }
            KernelStep::Proceed { .. } => panic!("gate 1: unexpected Proceed on failure"),
        }
    }

    assert!(
        !prompt_token_counts.is_empty(),
        "gate 1: at least one retry prompt should be produced"
    );

    let min = *prompt_token_counts.iter().min().unwrap();
    let max = *prompt_token_counts.iter().max().unwrap();
    // Invariance: max - min ≤ small constant (attempt_ordinal text + bbs_hash text).
    // We allow up to 200 tokens of variance for evidence-hash + bbs-hash + ordinal text.
    assert!(
        max - min <= 200,
        "gate 1: prompt size variance {} exceeds 200 token allowance (min={}, max={})",
        max - min,
        min,
        max
    );
}

// ── GATE 2 ───────────────────────────────────────────────────────
// valid_header_survives_truncated_body — header parses; route to Retry;
// verified_head unchanged.
#[test]
fn gate_2_valid_header_survives_truncated_body() {
    let mut k = fresh_kernel();
    let task = Task {
        id: "gate2".into(),
        prompt: "x".into(),
    };
    // Header + small body, then we'd simulate truncation by cutting the body.
    let header = retry_header("gate2", "p", "r");
    // Build: header, then ---BODY---, then a body that gets cut.
    let raw_output = format!(
        "{}\n--- cut here ---",
        header.split("---BODY---").next().unwrap()
    );
    let env = EnvironmentResult {
        raw_output,
        raw_stderr: "stderr".into(),
        success: false,
    };
    let initial_head = k.tape.get_verified_head();
    match k.step_forward(&task, env) {
        KernelStep::Retry { .. } => {
            assert_eq!(k.tape.get_verified_head(), initial_head);
        }
        _ => panic!("gate 2: expected Retry"),
    }
}

// ── GATE 3 ───────────────────────────────────────────────────────
// bbs_retains_three_orthogonal_constraints_under_budget — BBS keeps three
// distinct constraints under B_D budget. Tested directly on the distiller in
// src/distiller.rs::tests::orthogonal_memory_retention_three_distinct_constraints;
// here we re-verify integration: drive 3 different signatures through the kernel,
// then confirm tape contains AT LEAST 3 BBS nodes (one per retry).
#[test]
fn gate_3_bbs_retains_three_orthogonal_constraints_under_budget() {
    let mut k = fresh_kernel();
    let task = Task {
        id: "gate3".into(),
        prompt: "x".into(),
    };
    let cases = [
        ("schema-fail", "p1"),
        ("wrong-path", "p2"),
        ("logic-fail", "p3"),
    ];
    for (reject, pred) in cases {
        let env = EnvironmentResult {
            raw_output: retry_header("gate3", pred, reject),
            raw_stderr: format!("err {} {}\n", reject, pred),
            success: false,
        };
        let _ = k.step_forward(&task, env);
    }
    // Count BBS nodes (kind=RetryBeliefState verified=false)
    let scope = AttemptScope {
        run_id: "run-harness".into(),
        task_id: "gate3".into(),
        verified_parent: "H0".into(),
    };
    let bbs_count = k.tape.count_nodes(
        Some(NodeKind::RetryBeliefState),
        Some(false),
        None,
        Some(&scope),
    );
    assert!(
        bbs_count >= 3,
        "gate 3: expected >= 3 BBS nodes, got {}",
        bbs_count
    );
}

// ── GATE 4 ───────────────────────────────────────────────────────
// scope_metadata_persisted_and_countable — every AgentProposal under a scope
// has scope + attempt_ordinal set, and count_nodes(scope) is correct.
#[test]
fn gate_4_scope_metadata_persisted_and_countable() {
    let mut k = fresh_kernel();
    let task = Task {
        id: "gate4".into(),
        prompt: "x".into(),
    };
    // 5 retries under same scope, but each with a DIFFERENT signature so the
    // zero_gain_streak doesn't fire before MAX_RETRIES. The point of this gate
    // is "scope metadata is countable" — not the escalation behavior.
    for i in 0..5 {
        let env = EnvironmentResult {
            raw_output: retry_header("gate4", &format!("pred_{}", i), &format!("reject_{}", i)),
            raw_stderr: format!("attempt {}\n", i),
            success: false,
        };
        let step = k.step_forward(&task, env);
        if matches!(step, KernelStep::Escalate { .. }) {
            break;
        }
    }
    let scope = AttemptScope {
        run_id: "run-harness".into(),
        task_id: "gate4".into(),
        verified_parent: "H0".into(),
    };
    let proposals = k.tape.count_nodes(
        Some(NodeKind::AgentProposal),
        Some(false),
        Some("H0"),
        Some(&scope),
    );
    // Note: when retry_count reaches MAX_RETRIES, the kernel escalates
    // (the 5th attempt's proposal is committed first, THEN escalation).
    // So we expect exactly 5 proposals.
    assert_eq!(
        proposals, 5,
        "gate 4: expected exactly 5 proposals, got {}",
        proposals
    );
    // Verify each tape node has scope + ordinal set.
    let nodes_by_scope = &k.tape.indexes.nodes_by_scope;
    let scope_nodes = nodes_by_scope.get(&scope).expect("scope must be indexed");
    for h in scope_nodes {
        let node = &k.tape.indexes.by_hash[h];
        assert_eq!(node.scope.as_ref(), Some(&scope), "scope must be set");
        if node.kind == NodeKind::AgentProposal {
            assert!(
                node.attempt_ordinal.is_some(),
                "attempt_ordinal must be set on AgentProposal"
            );
        }
    }
}

// ── GATE 5 ───────────────────────────────────────────────────────
// bbs_reconstructs_from_tape_without_sidecar — drop kernel, rebuild from
// frozen tape, derive_latest_belief_state_from_tape must yield the same BBS.
#[test]
fn gate_5_bbs_reconstructs_from_tape_without_sidecar() {
    let mut k = fresh_kernel();
    let task = Task {
        id: "gate5".into(),
        prompt: "x".into(),
    };
    for _ in 0..3 {
        let env = EnvironmentResult {
            raw_output: retry_header("gate5", "p", "r"),
            raw_stderr: "schema fail\n".into(),
            success: false,
        };
        let _ = k.step_forward(&task, env);
    }
    let scope = AttemptScope {
        run_id: "run-harness".into(),
        task_id: "gate5".into(),
        verified_parent: "H0".into(),
    };
    let original_bbs = k
        .tape
        .derive_latest_belief_state_from_tape(&scope)
        .expect("BBS should exist after 3 retries");

    // Snapshot the indexes (frozen tape), drop the kernel, rebuild.
    let frozen = k.tape.indexes.clone();
    drop(k);

    let mut rebuilt_tape = MemoryTapeLedger::new();
    rebuilt_tape.indexes = frozen;

    let derived = rebuilt_tape
        .derive_latest_belief_state_from_tape(&scope)
        .expect("BBS must be derivable from frozen tape");
    assert_eq!(
        derived, original_bbs,
        "gate 5: BBS reconstructed from tape must equal original"
    );
}

// ── GATE 6 ───────────────────────────────────────────────────────
// distiller_input_budget_with_200k_trace — already covered by
// src/distiller.rs::tests::distiller_in_budget_200k_trace, but here we
// integration-test: feed kernel a synthetic 200k-class stderr; the prompt
// MUST NOT contain the raw stderr.
#[test]
fn gate_6_distiller_input_budget_with_200k_trace() {
    let mut k = fresh_kernel();
    let task = Task {
        id: "gate6".into(),
        prompt: "x".into(),
    };
    // Build 200_000-char "stderr" (~50k tokens, well past B_DISTILL_IN=2048)
    let mut raw_stderr = String::new();
    raw_stderr.push_str("UNIQUE_SENTINEL_TOKEN_FOR_GATE_6_LEAK_CHECK\n");
    for i in 0..10_000 {
        raw_stderr.push_str(&format!("at src/foo.rs:{} in fn_{}\n", i, i));
    }
    let env = EnvironmentResult {
        raw_output: retry_header("gate6", "x.y", "schema-fail"),
        raw_stderr,
        success: false,
    };
    match k.step_forward(&task, env) {
        KernelStep::Retry { prompt, .. } => {
            assert!(
                !prompt.contains("UNIQUE_SENTINEL_TOKEN_FOR_GATE_6_LEAK_CHECK"),
                "gate 6: raw stderr leaked into prompt"
            );
            let n = Tokenizer::new().count_text(&prompt);
            assert!(n <= B_PROMPT_MAX, "gate 6: prompt exceeds B_PROMPT_MAX");
        }
        _ => panic!("gate 6: expected Retry"),
    }
}

// ── GATE 7 ───────────────────────────────────────────────────────
// header_malformation_routes_safely — 6-case matrix; none advance verified_head.
#[test]
fn gate_7_header_malformation_routes_safely() {
    // Case 1: valid -> Ok
    assert!(parse_prefix_json(
        r#"{"schema_version":"tdma-state-update/v1","status":"Retry","task_id":"t","action":"RETRY"}"#,
        B_HEADER_SCAN,
        B_HEADER,
    )
    .is_ok());

    // Case 2: missing JSON object
    assert!(matches!(
        parse_prefix_json("no json here at all", B_HEADER_SCAN, B_HEADER),
        Err(HeaderParseError::MissingJsonObject)
    ));

    // Case 3: malformed JSON
    assert!(matches!(
        parse_prefix_json(
            r#"{"schema_version":"tdma-state-update/v1",}"#,
            B_HEADER_SCAN,
            B_HEADER
        ),
        Err(HeaderParseError::MalformedJson(_))
    ));

    // Case 4: schema invalid
    assert!(matches!(
        parse_prefix_json(
            r#"{"schema_version":"wrong/v9","status":"Retry","task_id":"t","action":"RETRY"}"#,
            B_HEADER_SCAN,
            B_HEADER
        ),
        Err(HeaderParseError::SchemaInvalid(_))
    ));

    // Case 5: header too long
    let long_id = "x".repeat(2000);
    let long_hdr = format!(
        r#"{{"schema_version":"tdma-state-update/v1","status":"Retry","task_id":"{}","action":"RETRY"}}"#,
        long_id
    );
    assert!(matches!(
        parse_prefix_json(&long_hdr, 4096, B_HEADER),
        Err(HeaderParseError::HeaderTooLong(_))
    ));

    // Case 6: truncated header before close
    assert!(matches!(
        parse_prefix_json(
            r#"{"schema_version":"tdma-state-update/v1","status":"Retry","task_id":"t","actio"#,
            B_HEADER_SCAN,
            B_HEADER
        ),
        Err(HeaderParseError::MissingJsonObject)
    ));

    // Integration: invalid header into kernel must not advance verified_head.
    let mut k = fresh_kernel();
    let task = Task {
        id: "gate7".into(),
        prompt: "x".into(),
    };
    let env = EnvironmentResult {
        raw_output: "no json here".into(),
        raw_stderr: "stderr".into(),
        success: false,
    };
    let initial = k.tape.get_verified_head();
    let _ = k.step_forward(&task, env);
    assert_eq!(k.tape.get_verified_head(), initial);
}

// ── GATE 8 ───────────────────────────────────────────────────────
// charter_core_invalidates_on_constitution_sha_drift — sha mismatch -> Err.
#[test]
fn gate_8_charter_core_invalidates_on_constitution_sha_drift() {
    let bytes_v1 = b"# Constitution\nArt. 0.4\n";
    let charter = compile_charter_core(bytes_v1, "v1.0", &Tokenizer::new());

    // Clean
    assert!(validate_charter_core_freshness(&charter, bytes_v1).is_ok());

    // Drifted
    let bytes_v2 = b"# Constitution\nArt. 0.4\nArt. 0.5 NEW\n";
    let err = validate_charter_core_freshness(&charter, bytes_v2).unwrap_err();
    assert!(matches!(
        err,
        CharterDriftError::ConstitutionShaMismatch { .. }
    ));
}

// ── GATE 9 ───────────────────────────────────────────────────────
// verified_head_static_under_hard_failures — 10 hard failures; verified_head
// stays at H0; ledger_tail moves; no StateAccepted under H0.
#[test]
fn gate_9_verified_head_static_under_hard_failures() {
    let mut k = fresh_kernel();
    let task = Task {
        id: "gate9".into(),
        prompt: "x".into(),
    };
    let h0 = k.tape.get_verified_head();
    let initial_tail = k.tape.indexes.ledger_tail.clone();

    for _ in 0..10 {
        let env = EnvironmentResult {
            raw_output: retry_header("gate9", "p", "r"),
            raw_stderr: "schema fail\n".into(),
            success: false,
        };
        let _ = k.step_forward(&task, env);
    }

    // verified_head unchanged
    assert_eq!(
        k.tape.get_verified_head(),
        h0,
        "gate 9: verified_head moved"
    );
    // ledger_tail advanced
    assert_ne!(
        k.tape.indexes.ledger_tail, initial_tail,
        "gate 9: ledger_tail did not advance"
    );

    // No StateAccepted under H0
    let accepted_under_h0 =
        k.tape
            .count_nodes(Some(NodeKind::StateAccepted), None, Some(&h0), None);
    assert_eq!(
        accepted_under_h0, 0,
        "gate 9: no StateAccepted should exist under H0 on failure-only run"
    );

    // raw_stderr substring never appears in any committed prompt assembly
    // (we don't materialize PromptAssembly nodes in RC1 — verified via Gate 6 sentinel).
}
