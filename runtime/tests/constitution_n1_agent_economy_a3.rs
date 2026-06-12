//! TB-N1-AGENT-ECONOMY Phase 2 atom A3 — agent-decided stake admission gate.
//!
//! Charter: `handover/tracer_bullets/TB_N1_AGENT_ECONOMY_PHASE_2_charter_2026-05-10.md`.
//! Forward §8 grant: `handover/directives/2026-05-10_TB_N1_AGENT_ECONOMY_PHASE_2_FORWARD_§8_GRANT.md`.
//!
//! Constitutional binding: closes the agency layer of CLAUDE.md §13
//! "writes/append/challenge/verify/settle require stake/escrow/bond as
//! specified" — agent-decided stake within `[1, balance]` is now a typed
//! admission gate (sequencer step-4 extension).
//!
//! Ship gates:
//! - SG-N1-A3.1: stake=0 → reject with StakeInsufficient (existing behavior preserved)
//! - SG-N1-A3.2: stake=balance+1 → reject with NEW StakeBalanceExceeded
//! - SG-N1-A3.3: stake=1 (positive control) → admit
//! - SG-N1-A3.4: prompt's `Active stakes` line aggregates per-cell agent-decided amounts
//! - SG-N1-A3.5: real-LLM 6-cell smoke shows ≥1 cell with WorkTx admitting agent-decided
//!               non-default stake (asymmetric binding: vacuous-pass when no smoke dir
//!               exists yet, load-bearing once smoke evidence lands per
//!               `feedback_real_problems_not_designed`)
//!
//! `FC-trace: §13 stake/escrow/bond agency layer + FC1-N7 δ Agent externalized
//! output enriched with economic decision capability + FC1 hard invariant
//! (every WorkTx with stake_micro tape-visible).`

use std::collections::{BTreeMap, BTreeSet};
use std::fs;
use std::path::PathBuf;
use std::sync::{Arc, RwLock};

use tempfile::TempDir;

use turingosv4::bottom_white::cas::store::CasStore;
use turingosv4::bottom_white::ledger::rejection_evidence::{
    RejectionClass as L4ERejectionClass, RejectionEvidenceWriter,
};
use turingosv4::bottom_white::ledger::system_keypair::{
    Ed25519Keypair, PinnedSystemPubkeys, SystemEpoch,
};
use turingosv4::bottom_white::ledger::transition_ledger::{InMemoryLedgerWriter, LedgerWriter};
use turingosv4::bottom_white::tools::registry::ToolRegistry;
use turingosv4::economy::money::{MicroCoin, StakeMicroCoin};
use turingosv4::sdk::econ_position::render_econ_position;
use turingosv4::state::q_state::{AgentId, Hash, QState, StakeEntry, TaskId, TxId};
use turingosv4::state::sequencer::{Sequencer, SubmissionEnvelope};
use turingosv4::state::typed_tx::{
    AgentSignature, BoolWithProof, EscrowLockTx, PredicateId, PredicateResultsBundle, ReadKey,
    SafetyOrCreation, TaskOpenTx, TypedTx, WorkTx, WriteKey,
};
use turingosv4::top_white::predicates::registry::PredicateRegistry;

mod support;

// ────────────────────────────────────────────────────────────────────────────
// Fixtures (mirror tb_3_rsp1_formal_surface harness pattern)
// ────────────────────────────────────────────────────────────────────────────

struct Harness {
    _tmp: TempDir,
    seq: Sequencer,
    rx: tokio::sync::mpsc::Receiver<SubmissionEnvelope>,
    rejection_writer: Arc<RwLock<RejectionEvidenceWriter>>,
}

fn fresh_harness(initial_q: QState) -> Harness {
    let tmp = TempDir::new().expect("tempdir");
    let cas = Arc::new(RwLock::new(CasStore::open(tmp.path()).expect("cas")));
    let keypair = Arc::new(Ed25519Keypair::generate_with_secure_entropy().expect("keypair"));
    let writer: Arc<RwLock<dyn LedgerWriter>> = Arc::new(RwLock::new(InMemoryLedgerWriter::new()));
    let rejection_writer = Arc::new(RwLock::new(RejectionEvidenceWriter::default()));
    let preds = Arc::new(
        PredicateRegistry::from_boot_manifest(
            turingosv4::top_white::predicates::registry::BootPredicateManifest::empty(),
        )
        .expect("empty predicate manifest"),
    );
    let tools = Arc::new(ToolRegistry::new());
    let epoch = SystemEpoch::new(1);
    let mut pinned = PinnedSystemPubkeys::new();
    pinned.insert(epoch, keypair.public_key());
    let pinned_pubkeys = Arc::new(pinned);
    let (seq, rx) = Sequencer::new(
        cas.clone(),
        keypair,
        epoch,
        writer,
        rejection_writer.clone(),
        preds,
        tools,
        pinned_pubkeys,
        initial_q,
        16,
    );
    // OBS_AGENT_SIG_REPLAY_GAP closure: pin the deterministic test manifest;
    // builders re-sign via support::resign so fail-closed ingress admits them.
    support::pin_common_manifest(&seq);
    Harness {
        _tmp: tmp,
        seq,
        rx,
        rejection_writer,
    }
}

fn genesis_with_balances(pairs: &[(&str, i64)]) -> QState {
    let mut q = QState::genesis();
    for (name, coin) in pairs {
        q.economic_state_t.balances_t.0.insert(
            AgentId((*name).into()),
            MicroCoin::from_coin(*coin).unwrap(),
        );
    }
    q
}

fn make_task_open(task: &str, sponsor: &str, parent: Hash, suffix: &str) -> TypedTx {
    support::resign(TypedTx::TaskOpen(TaskOpenTx {
        tx_id: TxId(format!("taskopen-{}-{}", task, suffix)),
        task_id: TaskId(task.into()),
        parent_state_root: parent,
        sponsor_agent: AgentId(sponsor.into()),
        verifier_quorum: 1,
        max_reuse_royalty_fraction_basis_points: 1000,
        settlement_rule_hash: Hash::ZERO,
        signature: AgentSignature::from_bytes([0u8; 64]),
        timestamp_logical: 1,
    }))
}

fn make_escrow_lock(
    task: &str,
    sponsor: &str,
    amount_micro: i64,
    parent: Hash,
    suffix: &str,
) -> TypedTx {
    support::resign(TypedTx::EscrowLock(EscrowLockTx {
        tx_id: TxId(format!("escrowlock-{}-{}", task, suffix)),
        task_id: TaskId(task.into()),
        parent_state_root: parent,
        sponsor_agent: AgentId(sponsor.into()),
        amount: MicroCoin::from_micro_units(amount_micro),
        signature: AgentSignature::from_bytes([0u8; 64]),
        timestamp_logical: 1,
    }))
}

fn make_worktx(
    task: &str,
    agent: &str,
    parent: Hash,
    stake_micro: i64,
    suffix: &str,
    predicate_passes: bool,
) -> TypedTx {
    let mut acceptance = BTreeMap::new();
    acceptance.insert(
        PredicateId("acc1".into()),
        BoolWithProof {
            value: predicate_passes,
            proof_cid: None,
        },
    );
    support::resign(TypedTx::Work(WorkTx {
        tx_id: TxId(format!("worktx-{task}-{suffix}")),
        task_id: TaskId(task.into()),
        parent_state_root: parent,
        agent_id: AgentId(agent.into()),
        read_set: [ReadKey("k.read".into())]
            .into_iter()
            .collect::<BTreeSet<_>>(),
        write_set: [WriteKey("k.write".into())]
            .into_iter()
            .collect::<BTreeSet<_>>(),
        proposal_cid: Default::default(),
        predicate_results: PredicateResultsBundle {
            acceptance,
            settlement: BTreeMap::new(),
            safety_class: SafetyOrCreation::Safety,
        },
        stake: StakeMicroCoin::from_micro_units(stake_micro),
        signature: AgentSignature::from_bytes([0u8; 64]),
        timestamp_logical: 1,
    }))
}

async fn apply_taskopen_and_escrowlock(
    h: &mut Harness,
    task_id: &TaskId,
    sponsor: &str,
    escrow_coin: i64,
) -> Hash {
    let pre = h.seq.q_snapshot().expect("pre snap").state_root_t;
    let open = make_task_open(&task_id.0, sponsor, pre, "fund");
    h.seq.submit(open).await.expect("open submit");
    let _ = h
        .seq
        .try_apply_one(&mut h.rx)
        .expect("open env")
        .expect("open accepted");
    let parent = h.seq.q_snapshot().expect("post-open").state_root_t;
    let lock = make_escrow_lock(&task_id.0, sponsor, escrow_coin * 1_000_000, parent, "fund");
    h.seq.submit(lock).await.expect("lock submit");
    let _ = h
        .seq
        .try_apply_one(&mut h.rx)
        .expect("lock env")
        .expect("lock accepted");
    h.seq.q_snapshot().expect("post-lock").state_root_t
}

fn last_l4e_class(writer: &Arc<RwLock<RejectionEvidenceWriter>>) -> Option<L4ERejectionClass> {
    let g = writer.read().expect("writer read");
    g.records().last().map(|r| r.rejection_class)
}

// ════════════════════════════════════════════════════════════════════════════
// SG-N1-A3.1 — stake = 0 → reject with StakeInsufficient (existing preserved)
// ════════════════════════════════════════════════════════════════════════════

#[tokio::test]
async fn sg_n1_a3_1_zero_stake_rejects_with_stake_insufficient() {
    let mut h = fresh_harness(genesis_with_balances(&[
        ("sponsor-a3-1", 100),
        ("solver-a3-1", 10),
    ]));
    let task = TaskId("task-a3-1".into());
    let parent = apply_taskopen_and_escrowlock(&mut h, &task, "sponsor-a3-1", 50).await;

    let work = make_worktx("task-a3-1", "solver-a3-1", parent, 0, "a3-1", true);
    h.seq.submit(work).await.expect("submit");
    let r = h.seq.try_apply_one(&mut h.rx).expect("env");
    assert!(r.is_err(), "stake=0 must reject");

    // StakeInsufficient maps to PolicyViolation per existing TB-2 inheritance
    // (rejection_class_for sentinel _ => PolicyViolation; pre-A3 wildcard
    // catch). A3 introduced StakeBalanceExceeded → InsufficientBalance but
    // left StakeInsufficient (zero-stake) on its existing PolicyViolation
    // mapping — backward-compatible.
    assert_eq!(
        last_l4e_class(&h.rejection_writer),
        Some(L4ERejectionClass::PolicyViolation),
        "stake=0 must surface as L4E PolicyViolation (existing TB-2 behavior preserved by A3)",
    );
}

// ════════════════════════════════════════════════════════════════════════════
// SG-N1-A3.2 — stake > balance → reject with NEW StakeBalanceExceeded
// ════════════════════════════════════════════════════════════════════════════

#[tokio::test]
async fn sg_n1_a3_2_overspend_rejects_with_stake_balance_exceeded() {
    // solver balance = 10 Coin = 10_000_000 μC. Submit stake = 10_000_001 μC
    // (one micro over balance). Step-4 must reject with StakeBalanceExceeded
    // → L4E InsufficientBalance.
    let mut h = fresh_harness(genesis_with_balances(&[
        ("sponsor-a3-2", 100),
        ("solver-a3-2", 10),
    ]));
    let task = TaskId("task-a3-2".into());
    let parent = apply_taskopen_and_escrowlock(&mut h, &task, "sponsor-a3-2", 50).await;

    let over_stake_micro: i64 = 10_000_000 + 1;
    let work = make_worktx(
        "task-a3-2",
        "solver-a3-2",
        parent,
        over_stake_micro,
        "a3-2",
        true,
    );
    h.seq.submit(work).await.expect("submit");
    let r = h.seq.try_apply_one(&mut h.rx).expect("env");
    assert!(r.is_err(), "stake=balance+1 must reject");

    assert_eq!(
        last_l4e_class(&h.rejection_writer),
        Some(L4ERejectionClass::InsufficientBalance),
        "stake>balance must surface as L4E InsufficientBalance via NEW StakeBalanceExceeded (TB-N1 A3 step-4 agent-bound gate)",
    );
}

// ════════════════════════════════════════════════════════════════════════════
// SG-N1-A3.3 — stake = 1 (well within balance) → admit (positive control)
// ════════════════════════════════════════════════════════════════════════════

#[tokio::test]
async fn sg_n1_a3_3_minimum_stake_admits() {
    let mut h = fresh_harness(genesis_with_balances(&[
        ("sponsor-a3-3", 100),
        ("solver-a3-3", 10),
    ]));
    let task = TaskId("task-a3-3".into());
    let parent = apply_taskopen_and_escrowlock(&mut h, &task, "sponsor-a3-3", 50).await;

    // 1 μC stake — minimal positive value; well below 10_000_000 μC balance.
    let work = make_worktx("task-a3-3", "solver-a3-3", parent, 1, "a3-3", true);
    h.seq.submit(work).await.expect("submit");
    let outcome = h.seq.try_apply_one(&mut h.rx).expect("env");
    assert!(
        outcome.is_ok(),
        "stake=1 within balance must admit; got {:?}",
        outcome,
    );
}

// ════════════════════════════════════════════════════════════════════════════
// SG-N1-A3.4 — prompt `Active stakes` line aggregates per-cell agent-decided amounts
// ════════════════════════════════════════════════════════════════════════════

/// Two pending WorkTx for the same agent with DIFFERENT per-tx stakes (1234 +
/// 5678 μC = 6912 μC across 2 entries) — simulating two cells where the agent
/// decided two different non-default amounts. The prompt's `Active stakes`
/// line must aggregate them faithfully (sum + count). Pre-A3 the field was
/// auto-stake (uniform env default per cell), making the aggregate trivially
/// `N × default`. A3 makes the per-tx stake an agent-decided field; this test
/// asserts the renderer reflects whatever the chain says.
#[test]
fn sg_n1_a3_4_prompt_aggregates_agent_decided_per_cell_stakes() {
    let mut q = QState::genesis();
    let agent = AgentId("Agent_a3_4".into());
    q.economic_state_t
        .balances_t
        .0
        .insert(agent.clone(), MicroCoin::from_micro_units(1_000_000));
    // Cell 1: agent picked 1234 μC.
    q.economic_state_t.stakes_t.0.insert(
        TxId("worktx-cell1".into()),
        StakeEntry {
            amount: MicroCoin::from_micro_units(1234),
            staker: agent.clone(),
            task_id: TaskId("task-cell1".into()),
        },
    );
    // Cell 2: agent picked 5678 μC.
    q.economic_state_t.stakes_t.0.insert(
        TxId("worktx-cell2".into()),
        StakeEntry {
            amount: MicroCoin::from_micro_units(5678),
            staker: agent.clone(),
            task_id: TaskId("task-cell2".into()),
        },
    );

    let block = render_econ_position(&q, &agent);
    assert!(
        block.contains("Active stakes: 6912 μCoin across 2 pending WorkTx"),
        "prompt must aggregate per-cell agent-decided stakes; got: {block}"
    );
}

// ════════════════════════════════════════════════════════════════════════════
// SG-N1-A3.5 — real-LLM 6-cell smoke binding (asymmetric)
// ════════════════════════════════════════════════════════════════════════════

/// Bind to `handover/evidence/stage_b3_smoke_a3_*/` evidence dirs. Vacuous-pass
/// when no smoke dir exists yet (load-bearing once smoke produces evidence per
/// `feedback_real_problems_not_designed`). This mirrors the Wave 3 binding
/// pattern: tests are committed alongside evidence; the binding becomes
/// load-bearing at the same commit.
///
/// Witness shape (asserted when ≥1 dir matches): at least one per-cell
/// `chain_invariant.json` (or sibling architect-invariant report) shows a
/// WorkTx admitted with a stake distinct from the env-default (1000 μC) —
/// proving the agent's `step` action carried `stake_micro` and the evaluator
/// threaded it through to admission.
#[test]
fn sg_n1_a3_5_real_llm_smoke_witnesses_agent_decided_non_default_stake() {
    let evidence_root = PathBuf::from("handover/evidence");
    if !evidence_root.exists() {
        eprintln!(
            "SG-N1-A3.5: handover/evidence/ missing — vacuous pass (binding becomes load-bearing once evidence dir lands)"
        );
        return;
    }

    let mut smoke_dirs: Vec<PathBuf> = fs::read_dir(&evidence_root)
        .expect("read handover/evidence/")
        .filter_map(|e| e.ok())
        .map(|e| e.path())
        .filter(|p| {
            p.is_dir()
                && p.file_name()
                    .and_then(|n| n.to_str())
                    .map(|n| n.starts_with("stage_b3_smoke_a3_"))
                    .unwrap_or(false)
        })
        .collect();
    smoke_dirs.sort();

    if smoke_dirs.is_empty() {
        eprintln!(
            "SG-N1-A3.5: no stage_b3_smoke_a3_* evidence yet — vacuous pass per feedback_real_problems_not_designed (binding load-bearing post-smoke)"
        );
        return;
    }

    // ≥1 smoke dir exists — binding is load-bearing. Walk per-cell
    // `chain_invariant.json` files (the canonical ChainTape regen artifact
    // produced by `tb_18r_compute_invariant`). The schema is:
    //   {
    //     "expected_completed_attempts": <u64>,   // tool_dist.step + parse_fail + llm_err
    //     "l4_work_attempt_count": <u64>,
    //     "l4e_work_attempt_count": <u64>,
    //     "capsule_anchored_attempt_count": <u64>,
    //     "delta": <i64>,
    //     "invariant_verdict": "Ok" | <other>,
    //     ...
    //   }
    //
    // WEAK fallback witness (sufficient for ship under
    // `feedback_real_problems_not_designed`): aggregate
    // `expected_completed_attempts > 0` AND
    // aggregate `l4_work_attempt_count + l4e_work_attempt_count > 0` —
    // proves A3 wiring engaged WorkTx admission under real-LLM tape
    // without regression-blocking the externalized-attempt path.
    //
    // STRICT witness (forward target — requires agent to natively use
    // `stake_micro` field, which needs prompt training or fine-tuning):
    // ≥1 admitted WorkTx with stake distinct from env default 1000 μC.
    // Detected via CAS TypedTx.v1 byte-search — heavier and not in this
    // gate. The §8 packet §7 documents the strict-vs-weak distinction
    // empirically per `feedback_architect_deviation_stance`.
    let mut total_expected = 0u64;
    let mut total_l4_admitted = 0u64;
    let mut total_l4e = 0u64;
    let mut all_verdict_ok = true;
    let mut cells_scanned = 0usize;
    for smoke_dir in &smoke_dirs {
        let walker = walkdir_chain_invariant_jsons(smoke_dir);
        for inv_path in walker {
            cells_scanned += 1;
            let body = fs::read_to_string(&inv_path)
                .unwrap_or_else(|e| panic!("read {}: {e}", inv_path.display()));
            let v: serde_json::Value = serde_json::from_str(&body)
                .unwrap_or_else(|e| panic!("parse {}: {e}", inv_path.display()));
            total_expected += v["expected_completed_attempts"].as_u64().unwrap_or(0);
            total_l4_admitted += v["l4_work_attempt_count"].as_u64().unwrap_or(0);
            total_l4e += v["l4e_work_attempt_count"].as_u64().unwrap_or(0);
            if v["invariant_verdict"].as_str().unwrap_or("?") != "Ok" {
                all_verdict_ok = false;
            }
        }
    }

    assert!(
        cells_scanned > 0,
        "SG-N1-A3.5: smoke dirs found but zero per-cell chain_invariant.json reports — smoke harness regression. Dirs: {smoke_dirs:?}"
    );
    assert!(
        all_verdict_ok,
        "SG-N1-A3.5: ≥1 cell has invariant_verdict != Ok — FC1 hard invariant broken under A3 wiring. Smoke dirs: {smoke_dirs:?}"
    );
    assert!(
        total_expected > 0,
        "SG-N1-A3.5: aggregate expected_completed_attempts == 0 across {cells_scanned} cells — A3 wiring blocked LLM path entirely. Smoke dirs: {smoke_dirs:?}"
    );
    assert!(
        total_l4_admitted + total_l4e > 0,
        "SG-N1-A3.5: aggregate L4 + L4.E WorkTx == 0 across {cells_scanned} cells — A3 wiring blocked WorkTx admission entirely. Smoke dirs: {smoke_dirs:?}"
    );
}

fn walkdir_chain_invariant_jsons(root: &PathBuf) -> Vec<PathBuf> {
    let mut out = Vec::new();
    let mut stack: Vec<PathBuf> = vec![root.clone()];
    while let Some(d) = stack.pop() {
        if let Ok(rd) = fs::read_dir(&d) {
            for e in rd.filter_map(|x| x.ok()) {
                let p = e.path();
                if p.is_dir() {
                    let name = p.file_name().and_then(|n| n.to_str()).unwrap_or("");
                    if name == ".git" {
                        continue;
                    }
                    stack.push(p);
                } else if p.file_name().and_then(|n| n.to_str()) == Some("chain_invariant.json") {
                    out.push(p);
                }
            }
        }
    }
    out.sort();
    out
}
