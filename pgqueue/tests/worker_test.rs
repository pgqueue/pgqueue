//! End-to-end worker tests: processing, retries, timeouts, panics, aborts,
//! burst mode, and graceful shutdown against real Postgres.

use sqlx::PgPool;
use std::sync::atomic::{AtomicU32, Ordering};
use std::sync::{Arc, Mutex};
use std::time::Duration;

use crate::{
    DEQUEUE_CLAIM, DEQUEUE_PROBE, FINISH_STATEMENT, Stats, expire_worker, hold_gate,
    install_statement_gate, leased_consumer, new_job, wait_for_lock_waiter,
};
use crate::{
    EnqueueResultTestExt, QueueProtocolTestExt, TestDb, backdate_job_liveness, pool_with_max,
    wait_for_some, wait_for_worker_intake_closed, wait_until,
};
use pgqueue::{
    Error, JobContext, JobError, JobErrorKind, JobRequest, JobRetention, JobState, JobStatus,
    Queue, Worker, WorkerComponent, WorkerHealthStatus, WorkerTimers,
};
use pgqueue::{SweepOperations, Sweeper};
use serde::{Deserialize, Serialize};
use serde_json::json;
use sqlx::{Connection, PgConnection, Row};
use std::sync::atomic::AtomicUsize;
use tokio_util::sync::CancellationToken;
use uuid::Uuid;

/// Shared, clonable log of what handlers saw.
type Log = Arc<Mutex<Vec<String>>>;

#[derive(Debug, Clone, Serialize, Deserialize)]
struct Payload {
    tag: String,
}

#[pgqueue::job(max_attempts = 1)]
async fn record(args: Payload, log: JobState<Log>, ctx: JobContext) -> anyhow::Result<String> {
    // Exercise the full JobContext surface.
    anyhow::ensure!(ctx.attempt() >= 1);
    anyhow::ensure!(ctx.worker_id() != Uuid::nil());
    anyhow::ensure!(ctx.queue().name() == "default");
    anyhow::ensure!(!ctx.cancellation().is_cancelled());
    anyhow::ensure!(ctx.job().name == "record");
    anyhow::ensure!(format!("{ctx:?}").contains("record"));
    log.0
        .lock()
        .map_err(|_| anyhow::anyhow!("record log lock poisoned"))?
        .push(args.tag.clone());
    Ok(format!("done:{}", args.tag))
}

#[pgqueue::job(max_attempts = 2)]
async fn always_fails(_: ()) -> anyhow::Result<()> {
    anyhow::bail!("boom")
}

#[pgqueue::job(name = "registration_collision")]
async fn registration_collision_a(_: ()) {}

#[pgqueue::job(name = "registration_collision")]
async fn registration_collision_b(_: ()) {}

#[pgqueue::job(max_attempts = 1, timeout_ms = 200)]
async fn sleeps_forever(_: ()) -> anyhow::Result<()> {
    std::future::pending().await
}

#[pgqueue::job(max_attempts = 1, timeout_ms = 30_000)]
async fn slow_but_abortable(_: ()) -> anyhow::Result<()> {
    std::future::pending().await
}

#[derive(Clone)]
struct ShutdownLeaseProbe {
    started: Arc<tokio::sync::Notify>,
}

#[pgqueue::job(max_attempts = 1, timeout_ms = 30_000)]
async fn holds_during_shutdown(_: (), probe: JobState<ShutdownLeaseProbe>) -> anyhow::Result<()> {
    probe.0.started.notify_one();
    std::future::pending().await
}

#[derive(Clone)]
struct SlotFillProbe {
    barrier: Arc<tokio::sync::Barrier>,
}

#[pgqueue::job]
async fn fills_worker_slot(_: (), probe: JobState<SlotFillProbe>) -> anyhow::Result<()> {
    probe.0.barrier.wait().await;
    Ok(())
}

#[pgqueue::job(max_attempts = 1)]
async fn cancels_observer_token(_: (), ctx: JobContext) -> anyhow::Result<()> {
    let cancellation = ctx.cancellation();
    cancellation.cancel();
    anyhow::ensure!(cancellation.is_cancelled());
    Ok(())
}

#[derive(Clone)]
struct CancellationObservedProbe {
    started: Arc<tokio::sync::Notify>,
    observed: Arc<tokio::sync::Notify>,
}

#[pgqueue::job(max_attempts = 1, timeout_ms = 30_000)]
async fn observes_shutdown_cancellation(
    _: (),
    probe: JobState<CancellationObservedProbe>,
    ctx: JobContext,
) -> anyhow::Result<()> {
    probe.0.started.notify_one();
    let cancellation = ctx.cancellation();
    cancellation.cancelled().await;
    probe.0.observed.notify_one();
    Ok(())
}

/// Reacts to shutdown the way [`JobContext::cancellation`] documents, reporting
/// the unfinished attempt as an error.
#[pgqueue::job(max_attempts = 1, timeout_ms = 30_000)]
async fn errs_on_shutdown_cancellation(
    _: (),
    probe: JobState<CancellationObservedProbe>,
    ctx: JobContext,
) -> anyhow::Result<()> {
    probe.0.started.notify_one();
    ctx.cancellation().cancelled().await;
    probe.0.observed.notify_one();
    anyhow::bail!("stopped for shutdown")
}

#[derive(Clone)]
struct HandlerTickProbe {
    started: Arc<tokio::sync::Notify>,
    ticks: Arc<AtomicU32>,
}

/// Never looks at its cancellation token: only a forced stop ends it. Each tick
/// stands in for an externally visible side effect.
#[pgqueue::job(max_attempts = 1, timeout_ms = 60_000)]
async fn ticks_until_forced_to_stop(
    _: (),
    probe: JobState<HandlerTickProbe>,
) -> anyhow::Result<()> {
    probe.0.started.notify_one();
    loop {
        tokio::time::sleep(Duration::from_millis(20)).await;
        probe.0.ticks.fetch_add(1, Ordering::SeqCst);
    }
}

#[derive(Clone)]
struct CooperativeTickProbe {
    started: Arc<tokio::sync::Notify>,
    cancelled: Arc<tokio::sync::Notify>,
    ticks: Arc<AtomicU32>,
}

/// Reports the cooperative cancellation a user abort raises and then keeps
/// working through it, so only a forced stop ends it. Each tick stands in for
/// an externally visible side effect.
#[pgqueue::job(max_attempts = 1, timeout_ms = 60_000)]
async fn ticks_through_a_cooperative_abort(
    _: (),
    probe: JobState<CooperativeTickProbe>,
    ctx: JobContext,
) -> anyhow::Result<()> {
    probe.0.started.notify_one();
    let cancellation = ctx.cancellation();
    let mut reported = false;
    loop {
        tokio::time::sleep(Duration::from_millis(20)).await;
        if !reported && cancellation.is_cancelled() {
            reported = true;
            probe.0.cancelled.notify_one();
        }
        probe.0.ticks.fetch_add(1, Ordering::SeqCst);
    }
}

#[derive(Clone)]
struct AbortCleanupProbe {
    started: Arc<tokio::sync::Notify>,
    observed: Arc<tokio::sync::Notify>,
    cleaned: Arc<tokio::sync::Notify>,
}

#[pgqueue::job(max_attempts = 1, timeout_ms = 30_000)]
async fn cleans_up_after_user_abort(
    _: (),
    probe: JobState<AbortCleanupProbe>,
    ctx: JobContext,
) -> anyhow::Result<()> {
    probe.0.started.notify_one();
    let cancellation = ctx.cancellation();
    cancellation.cancelled().await;
    probe.0.observed.notify_one();
    tokio::time::sleep(Duration::from_millis(25)).await;
    probe.0.cleaned.notify_one();
    Ok(())
}

#[derive(Clone)]
struct ForcedAbortProbe {
    started: Arc<tokio::sync::Notify>,
    observed: Arc<tokio::sync::Notify>,
    dropped: Arc<tokio::sync::Notify>,
}

struct ForcedAbortDrop(Arc<tokio::sync::Notify>);

impl Drop for ForcedAbortDrop {
    fn drop(&mut self) {
        self.0.notify_one();
    }
}

#[pgqueue::job(max_attempts = 1, timeout_ms = 30_000)]
async fn exceeds_abort_grace(
    _: (),
    probe: JobState<ForcedAbortProbe>,
    ctx: JobContext,
) -> anyhow::Result<()> {
    let _drop = ForcedAbortDrop(probe.0.dropped.clone());
    probe.0.started.notify_one();
    let cancellation = ctx.cancellation();
    cancellation.cancelled().await;
    probe.0.observed.notify_one();
    std::future::pending().await
}

#[pgqueue::job(max_attempts = 1)]
async fn panics(_: ()) -> anyhow::Result<()> {
    panic!("kaboom {}", 42); // String panic payload
}

#[pgqueue::job(max_attempts = 1)]
async fn panics_static(_: ()) -> anyhow::Result<()> {
    panic!("static kaboom"); // &'static str panic payload
}

#[pgqueue::job(max_attempts = 1)]
async fn panics_weird(_: ()) -> anyhow::Result<()> {
    std::panic::panic_any(42u32); // non-string panic payload
}

#[pgqueue::job(max_attempts = 5)]
async fn needs_missing_state(_: (), missing: JobState<Uuid>) -> anyhow::Result<()> {
    let _ = missing;
    Ok(())
}

#[pgqueue::job(max_attempts = 5)]
async fn decodes_payload(args: Payload) -> anyhow::Result<()> {
    let _ = args;
    Ok(())
}

#[pgqueue::job(max_attempts = 5)]
async fn returns_decode_error(_: ()) -> Result<(), JobError> {
    Err(JobError::new(
        JobErrorKind::Decode,
        "handler decode failure",
    ))
}

#[pgqueue::job]
async fn counts(_: (), counter: JobState<Arc<AtomicU32>>) -> anyhow::Result<u32> {
    Ok(counter.0.fetch_add(1, Ordering::SeqCst) + 1)
}

#[pgqueue::job(max_attempts = 2, timeout_ms = 30_000)]
async fn swept_once(_: (), attempts: JobState<Arc<AtomicU32>>) -> anyhow::Result<()> {
    if attempts.0.fetch_add(1, Ordering::SeqCst) == 0 {
        std::future::pending::<()>().await;
    }
    Ok(())
}

#[derive(Clone)]
struct MissingRowProbe {
    started: tokio::sync::mpsc::UnboundedSender<u8>,
    dropped: tokio::sync::mpsc::UnboundedSender<u8>,
}

struct MissingRowDrop {
    tag: u8,
    dropped: tokio::sync::mpsc::UnboundedSender<u8>,
}

impl Drop for MissingRowDrop {
    fn drop(&mut self) {
        let _ = self.dropped.send(self.tag);
    }
}

#[pgqueue::job(max_attempts = 1, timeout_ms = 10)]
async fn waits_after_row_deletion(tag: u8, probe: JobState<MissingRowProbe>) -> anyhow::Result<()> {
    let _drop = MissingRowDrop {
        tag,
        dropped: probe.0.dropped.clone(),
    };
    let _ = probe.0.started.send(tag);
    std::future::pending().await
}

#[derive(Clone)]
struct AbortFailureRace {
    started: Arc<tokio::sync::Notify>,
    release: Arc<tokio::sync::Notify>,
}

#[derive(Clone)]
struct AbortSuccessRace {
    started: Arc<tokio::sync::Notify>,
    release: Arc<tokio::sync::Notify>,
}

#[pgqueue::job(max_attempts = 1, timeout_ms = 30_000)]
async fn succeeds_during_abort(_: (), state: JobState<AbortSuccessRace>) -> anyhow::Result<String> {
    state.0.started.notify_one();
    state.0.release.notified().await;
    Ok("handler finished".to_string())
}

#[pgqueue::job(max_attempts = 1, timeout_ms = 30_000)]
async fn succeeds_as_sweeper_marks(_: (), state: JobState<AbortSuccessRace>) -> anyhow::Result<()> {
    state.0.started.notify_one();
    state.0.release.notified().await;
    Ok(())
}

#[pgqueue::job(max_attempts = 1, timeout_ms = 30_000)]
async fn fails_during_abort(_: (), state: JobState<AbortFailureRace>) -> anyhow::Result<()> {
    state.0.started.notify_one();
    state.0.release.notified().await;
    anyhow::bail!("handler failed while abort was pending")
}

#[derive(Clone)]
struct SweepFailureRace {
    started: Arc<tokio::sync::Notify>,
    release: Arc<tokio::sync::Notify>,
}

#[pgqueue::job(max_attempts = 2, timeout_ms = 30_000)]
async fn fails_as_sweeper_marks(
    _: (),
    state: JobState<SweepFailureRace>,
    ctx: JobContext,
) -> anyhow::Result<()> {
    if ctx.attempt() == 1 {
        state.0.started.notify_one();
        state.0.release.notified().await;
        anyhow::bail!("handler failed as sweep abort landed");
    }
    Ok(())
}

#[derive(Clone)]
struct SweepFailureReasonRace {
    started: Arc<tokio::sync::Notify>,
    release: Arc<tokio::sync::Notify>,
    retried: Arc<tokio::sync::Notify>,
    hold: Arc<tokio::sync::Notify>,
}

/// Fails the first attempt on cue, then parks the second so the row the retry
/// produced can be read while it still carries the reason the first one ended.
#[pgqueue::job(max_attempts = 3, timeout_ms = 30_000)]
async fn fails_then_parks_as_sweeper_marks(
    _: (),
    state: JobState<SweepFailureReasonRace>,
    ctx: JobContext,
) -> anyhow::Result<()> {
    if ctx.attempt() == 1 {
        state.0.started.notify_one();
        state.0.release.notified().await;
        anyhow::bail!("the real handler failure");
    }
    state.0.retried.notify_one();
    state.0.hold.notified().await;
    Ok(())
}

use crate::test_timers;

fn test_worker(queue: Queue) -> pgqueue::WorkerBuilder {
    Worker::builder(queue)
        .timers(test_timers())
        .poll_interval(Duration::from_millis(50))
        .abort_grace(Duration::from_millis(100))
        .shutdown_grace(Duration::from_secs(5))
}

/// Polls until the job reaches a terminal status (or the deadline passes).
async fn wait_terminal(queue: &Queue, id: Uuid, secs: u64) -> pgqueue::JobRow {
    wait_for_some(
        Duration::from_secs(secs),
        Duration::from_millis(25),
        &format!("job {id} never finished"),
        || async {
            queue
                .fetch_job(id)
                .await
                .unwrap()
                .filter(|row| row.status.is_terminal())
        },
    )
    .await
}

async fn wait_status(queue: &Queue, id: Uuid, status: JobStatus, secs: u64) -> pgqueue::JobRow {
    wait_for_some(
        Duration::from_secs(secs),
        Duration::from_millis(25),
        &format!("job {id} never reached {status}"),
        || async {
            queue
                .fetch_job(id)
                .await
                .unwrap()
                .filter(|row| row.status == status)
        },
    )
    .await
}

#[sqlx::test(migrations = "./migrations")]
async fn test_worker_health_tracks_start_ready_and_stopped(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let worker = test_worker(db.queue.clone())
        .register_job(counts)
        .state(Arc::new(AtomicU32::new(0)))
        .build()
        .unwrap();
    let health = worker.health();
    assert_eq!(health.snapshot().status, WorkerHealthStatus::Starting);
    let shutdown = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));
    wait_until(
        Duration::from_secs(3),
        Duration::from_millis(10),
        "worker did not report ready health",
        || async { health.snapshot().status == WorkerHealthStatus::Ready },
    )
    .await;

    shutdown.cancel();
    run.await.unwrap().unwrap();
    assert_eq!(health.snapshot().status, WorkerHealthStatus::Stopped);
}

#[sqlx::test(migrations = "./migrations")]
async fn test_worker_builder_run_processes_jobs_without_an_explicit_build(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let counter = Arc::new(AtomicU32::new(0));
    let handle = db.queue.enqueue(counts::job(())).await.unwrap().unwrap();

    test_worker(db.queue.clone())
        .register_job(counts)
        .state(counter.clone())
        .burst(true)
        .dequeue_timeout(Duration::from_millis(50))
        .run()
        .await
        .unwrap();

    assert_eq!(counter.load(Ordering::SeqCst), 1);
    assert_eq!(
        handle.fetch_job().await.unwrap().status,
        JobStatus::Complete
    );
}

#[sqlx::test(migrations = "./migrations")]
async fn test_run_until_returns_without_starting_when_shutdown_is_pre_cancelled(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let counter = Arc::new(AtomicU32::new(0));
    let handle = db.queue.enqueue(counts::job(())).await.unwrap().unwrap();
    let worker = test_worker(db.queue.clone())
        .register_job(counts)
        .state(counter.clone())
        .build()
        .unwrap();
    let worker_id = worker.id();
    let shutdown = CancellationToken::new();
    shutdown.cancel();

    tokio::time::timeout(Duration::from_secs(1), worker.run_until(shutdown))
        .await
        .expect("pre-cancelled worker should stop promptly")
        .expect("pre-cancelled worker should stop cleanly");

    assert_eq!(counter.load(Ordering::SeqCst), 0);
    let row = handle.fetch_job().await.unwrap();
    assert_eq!(row.status, JobStatus::Queued);
    assert_eq!(row.attempts, 0);
    assert_eq!(row.max_attempts, 1);
    let worker_exists = sqlx::query_scalar::<_, bool>(
        "SELECT EXISTS (SELECT 1 FROM pgqueue.workers WHERE id = $1)",
    )
    .bind(worker_id)
    .fetch_one(&pool)
    .await
    .unwrap();
    assert!(!worker_exists);
}

#[sqlx::test(migrations = "./migrations")]
async fn test_notification_listener_recovers_after_postgres_terminates_connection(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let counter = Arc::new(AtomicU32::new(0));
    let worker = test_worker(db.queue.clone())
        .register_job(counts)
        .state(counter.clone())
        .poll_interval(Duration::from_secs(30))
        .build()
        .unwrap();
    let health = worker.health();
    let shutdown = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));
    wait_until(
        Duration::from_secs(3),
        Duration::from_millis(10),
        "worker did not report ready health",
        || async { health.snapshot().status == WorkerHealthStatus::Ready },
    )
    .await;

    let initial_pid = wait_for_some(
        Duration::from_secs(5),
        Duration::from_millis(20),
        "notification listener did not subscribe",
        || async {
            sqlx::query_scalar::<_, i32>(
                "SELECT pid FROM pg_stat_activity \
                 WHERE datname = current_database() AND query LIKE 'LISTEN %' \
                 ORDER BY backend_start LIMIT 1",
            )
            .fetch_optional(&pool)
            .await
            .unwrap()
        },
    )
    .await;
    let mut health_changes = health.clone();
    let degraded = tokio::spawn(async move {
        loop {
            let snapshot = health_changes.changed().await;
            if snapshot
                .failures
                .iter()
                .any(|failure| failure.component == WorkerComponent::Notification)
            {
                return;
            }
        }
    });
    tokio::task::yield_now().await;

    let terminated = sqlx::query_scalar::<_, bool>("SELECT pg_terminate_backend($1)")
        .bind(initial_pid)
        .fetch_one(&pool)
        .await
        .unwrap();
    assert!(terminated);
    tokio::time::timeout(Duration::from_secs(5), degraded)
        .await
        .expect("notification failure was not reported")
        .unwrap();

    let replacement_pid = wait_for_some(
        Duration::from_secs(5),
        Duration::from_millis(20),
        "notification listener did not reconnect",
        || async {
            sqlx::query_scalar::<_, i32>(
                "SELECT pid FROM pg_stat_activity \
                 WHERE datname = current_database() AND query LIKE 'LISTEN %' \
                 ORDER BY backend_start LIMIT 1",
            )
            .fetch_optional(&pool)
            .await
            .unwrap()
            .filter(|pid| *pid != initial_pid)
        },
    )
    .await;
    assert_ne!(replacement_pid, initial_pid);
    wait_until(
        Duration::from_secs(5),
        Duration::from_millis(20),
        "notification health did not recover",
        || async { health.snapshot().status == WorkerHealthStatus::Ready },
    )
    .await;

    let handle = db.queue.enqueue(counts::job(())).await.unwrap().unwrap();
    // The counter is bumped *inside* the handler, so it goes up one full
    // `Database::finish` round trip before the row is terminal. Waiting on the
    // counter alone and then asserting the status raced that round trip and
    // read `running`, so the terminal row is part of what is waited for.
    wait_for_some(
        Duration::from_secs(5),
        Duration::from_millis(20),
        "reconnected listener did not wake the worker",
        || {
            let counter = counter.clone();
            let handle = handle.clone();
            async move {
                (counter.load(Ordering::SeqCst) == 1
                    && handle.fetch_job().await.ok()?.status == JobStatus::Complete)
                    .then_some(())
            }
        },
    )
    .await;

    shutdown.cancel();
    run.await.unwrap().unwrap();
}

#[sqlx::test(migrations = "./migrations")]
async fn test_worker_processes_typed_jobs_end_to_end(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let log: Log = Arc::new(Mutex::new(Vec::new()));

    let mut handles = Vec::new();
    for i in 0..3 {
        let handle = db
            .queue
            .enqueue(record::job(Payload {
                tag: format!("job{i}"),
            }))
            .await
            .unwrap()
            .unwrap();
        handles.push(handle);
    }

    let worker = test_worker(db.queue.clone())
        .register_job(record)
        .state(log.clone())
        .concurrency(2)
        .build()
        .unwrap();
    assert_ne!(worker.id(), Uuid::nil());
    assert_eq!(worker.queue().name(), "default");
    assert!(format!("{worker:?}").contains("Worker"));

    let token = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(token.clone()));

    for (i, handle) in handles.iter().enumerate() {
        let row = wait_terminal(&db.queue, handle.id(), 10).await;
        assert_eq!(row.status, JobStatus::Complete, "{:?}", row.error);
        assert_eq!(row.result, Some(json!(format!("done:job{i}"))));
        assert!(row.completed_at.is_some());
        assert!(row.worker_id.is_some());
    }
    let mut seen = log.lock().unwrap().clone();
    seen.sort();
    assert_eq!(seen, vec!["job0", "job1", "job2"]);

    token.cancel();
    run.await.unwrap().unwrap();
    assert_eq!(db.queue.stats().complete, 3);
}

#[sqlx::test(migrations = "./migrations")]
async fn test_job_context_cancellation_does_not_cancel_attempt(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let handle = db
        .queue
        .enqueue(cancels_observer_token::job(()))
        .await
        .unwrap()
        .unwrap();
    let worker = test_worker(db.queue.clone())
        .register_job(cancels_observer_token)
        .build()
        .unwrap();
    let token = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(token.clone()));

    let row = wait_terminal(&db.queue, handle.id(), 10).await;
    token.cancel();
    run.await.unwrap().unwrap();

    assert_eq!(row.status, JobStatus::Complete);
    assert_eq!(row.attempts, 1);
    assert_eq!(db.queue.stats().complete, 1);
    assert_eq!(db.queue.stats().retried, 0);
}

#[sqlx::test(migrations = "./migrations")]
async fn test_job_context_cancellation_fires_when_shutdown_begins(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let handle = db
        .queue
        .enqueue(observes_shutdown_cancellation::job(()))
        .await
        .unwrap()
        .unwrap();
    let probe = CancellationObservedProbe {
        started: Arc::new(tokio::sync::Notify::new()),
        observed: Arc::new(tokio::sync::Notify::new()),
    };
    let worker = test_worker(db.queue.clone())
        .register_job(observes_shutdown_cancellation)
        .state(probe.clone())
        .shutdown_grace(Duration::from_secs(5))
        .build()
        .unwrap();
    let shutdown = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));

    tokio::time::timeout(Duration::from_secs(5), probe.started.notified())
        .await
        .expect("handler did not start");
    shutdown.cancel();
    tokio::time::timeout(Duration::from_secs(2), probe.observed.notified())
        .await
        .expect("handler did not observe cancellation at shutdown start");
    run.await.unwrap().unwrap();

    assert_eq!(
        handle.fetch_job().await.unwrap().status,
        JobStatus::Complete
    );
}

#[sqlx::test(migrations = "./migrations")]
async fn test_shutdown_requeues_a_handler_that_reports_cancellation_as_an_error(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let handle = db
        .queue
        .enqueue(errs_on_shutdown_cancellation::job(()))
        .await
        .unwrap()
        .unwrap();
    let probe = CancellationObservedProbe {
        started: Arc::new(tokio::sync::Notify::new()),
        observed: Arc::new(tokio::sync::Notify::new()),
    };
    let worker = test_worker(db.queue.clone())
        .register_job(errs_on_shutdown_cancellation)
        .state(probe.clone())
        .shutdown_grace(Duration::from_secs(5))
        .build()
        .unwrap();
    let shutdown = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));

    tokio::time::timeout(Duration::from_secs(5), probe.started.notified())
        .await
        .expect("handler did not start");
    shutdown.cancel();
    tokio::time::timeout(Duration::from_secs(2), probe.observed.notified())
        .await
        .expect("handler did not observe cancellation at shutdown start");
    run.await.unwrap().unwrap();

    // Returning early for shutdown is not a failed attempt: the job goes back
    // to the queue with its attempt refunded, exactly like a handler that is
    // force-stopped at grace expiry, and the reason stays on the row.
    let row = handle.fetch_job().await.unwrap();
    assert_eq!(row.status, JobStatus::Queued);
    assert_eq!(row.attempts, 1);
    assert_eq!(row.max_attempts, 2);
    assert_eq!(row.error.as_deref(), Some("failed: stopped for shutdown"));
    assert_eq!(db.queue.stats().failed, 0);
}

#[sqlx::test(migrations = "./migrations")]
async fn test_shutdown_requeue_is_unconfirmed_when_the_row_is_aborting(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let handle = db
        .queue
        .enqueue(errs_on_shutdown_cancellation::job(()))
        .await
        .unwrap()
        .unwrap();
    let probe = CancellationObservedProbe {
        started: Arc::new(tokio::sync::Notify::new()),
        observed: Arc::new(tokio::sync::Notify::new()),
    };
    let worker = test_worker(db.queue.clone())
        .register_job(errs_on_shutdown_cancellation)
        .state(probe.clone())
        // The abort poll must not see the abort, so the attempt ends as a
        // shutdown return that the requeue guard then refuses.
        .timers(WorkerTimers {
            abort: Duration::from_secs(600),
            ..test_timers()
        })
        .shutdown_grace(Duration::from_secs(5))
        .build()
        .unwrap();
    let shutdown = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));

    tokio::time::timeout(Duration::from_secs(5), probe.started.notified())
        .await
        .expect("handler did not start");
    assert!(handle.abort("user abort during shutdown").await.unwrap());
    shutdown.cancel();
    run.await.unwrap().unwrap();

    // The row belongs to the pending abort; the sweeper finishes it later.
    let row = handle.fetch_job().await.unwrap();
    assert_eq!(row.status, JobStatus::Aborting);
    assert_eq!(row.attempts, 1);
    assert_eq!(row.max_attempts, 1, "a refused requeue refunds nothing");
}

#[sqlx::test(migrations = "./migrations")]
async fn test_deleted_job_row_stops_its_handler_without_waiting_for_the_abort_grace(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let id = db
        .queue
        .enqueue(ticks_until_forced_to_stop::job(()))
        .await
        .unwrap()
        .unwrap()
        .id();
    let probe = HandlerTickProbe {
        started: Arc::new(tokio::sync::Notify::new()),
        ticks: Arc::new(AtomicU32::new(0)),
    };
    let worker = test_worker(db.queue.clone())
        .register_job(ticks_until_forced_to_stop)
        .state(probe.clone())
        // Long enough that a handler waiting out the grace would still be
        // running when this test's deadline passes.
        .abort_grace(Duration::from_secs(60))
        .shutdown_grace(Duration::from_secs(5))
        .build()
        .unwrap();
    let shutdown = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));

    tokio::time::timeout(Duration::from_secs(5), probe.started.notified())
        .await
        .expect("handler did not start");
    assert_eq!(
        sqlx::query("DELETE FROM pgqueue.jobs WHERE id = $1")
            .bind(id)
            .execute(db.queue.pool())
            .await
            .unwrap()
            .rows_affected(),
        1
    );

    // The row was the attempt's only claim to dedupe exclusivity, so the handler
    // is force-stopped as soon as the abort poll notices, without the
    // cooperative grace a user abort gets.
    let deleted_at = tokio::time::Instant::now();
    wait_until(
        Duration::from_secs(5),
        Duration::from_millis(25),
        "handler kept running after its job row was deleted",
        || async {
            let before = probe.ticks.load(Ordering::SeqCst);
            tokio::time::sleep(Duration::from_millis(100)).await;
            probe.ticks.load(Ordering::SeqCst) == before
        },
    )
    .await;
    assert!(deleted_at.elapsed() < Duration::from_secs(5));

    shutdown.cancel();
    run.await.unwrap().unwrap();
}

/// The same immediacy, but with a user abort already under way. The abort
/// reason is recorded once, so the deletion loses that race — and losing it used
/// to skip the force-cancel with it, leaving the handler running, and producing
/// side effects, for the whole remaining `abort_grace` with no row left in the
/// database to guard its writes. The library reaches this state on its own:
/// `Database::abort_stuck_abandoned_batch` deletes an `aborting` row whose
/// `result_ttl_ms` is `0` out from under a live attempt.
#[sqlx::test(migrations = "./migrations")]
async fn test_deleted_job_row_stops_its_handler_when_a_user_abort_is_already_pending(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let handle = db
        .queue
        .enqueue(ticks_through_a_cooperative_abort::job(()))
        .await
        .unwrap()
        .unwrap();
    let id = handle.id();
    let probe = CooperativeTickProbe {
        started: Arc::new(tokio::sync::Notify::new()),
        cancelled: Arc::new(tokio::sync::Notify::new()),
        ticks: Arc::new(AtomicU32::new(0)),
    };
    let worker = test_worker(db.queue.clone())
        .register_job(ticks_through_a_cooperative_abort)
        .state(probe.clone())
        // Long enough that a handler waiting out the grace would still be
        // running when this test's deadline passes.
        .abort_grace(Duration::from_secs(60))
        .shutdown_grace(Duration::from_secs(5))
        .build()
        .unwrap();
    let shutdown = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));

    tokio::time::timeout(Duration::from_secs(5), probe.started.notified())
        .await
        .expect("handler did not start");
    assert!(handle.abort("user abort").await.unwrap());
    // Waiting for the handler to see the cooperative cancellation is what puts
    // the `User` reason in first: the deletion below is the second request.
    tokio::time::timeout(Duration::from_secs(5), probe.cancelled.notified())
        .await
        .expect("the user abort never reached the handler");
    assert_eq!(
        sqlx::query("DELETE FROM pgqueue.jobs WHERE id = $1")
            .bind(id)
            .execute(db.queue.pool())
            .await
            .unwrap()
            .rows_affected(),
        1
    );

    let deleted_at = tokio::time::Instant::now();
    wait_until(
        Duration::from_secs(5),
        Duration::from_millis(25),
        "handler kept running after its job row was deleted",
        || async {
            let before = probe.ticks.load(Ordering::SeqCst);
            tokio::time::sleep(Duration::from_millis(100)).await;
            probe.ticks.load(Ordering::SeqCst) == before
        },
    )
    .await;
    assert!(deleted_at.elapsed() < Duration::from_secs(5));

    shutdown.cancel();
    run.await.unwrap().unwrap();
}

#[sqlx::test(migrations = "./migrations")]
async fn test_processors_observe_refills_without_polling_after_startup_race(pool: PgPool) {
    const CONCURRENCY: usize = 32;

    let db = TestDb::new(pool.clone()).await;
    let probe = SlotFillProbe {
        barrier: Arc::new(tokio::sync::Barrier::new(CONCURRENCY + 1)),
    };
    let mut handles = Vec::with_capacity(CONCURRENCY);
    for _ in 0..CONCURRENCY {
        handles.push(
            db.queue
                .enqueue(fills_worker_slot::job(()))
                .await
                .unwrap()
                .unwrap(),
        );
    }
    let worker = test_worker(db.queue.clone())
        .register_job(fills_worker_slot)
        .state(probe.clone())
        .concurrency(CONCURRENCY)
        .poll_interval(Duration::from_secs(30))
        .build()
        .unwrap();
    let shutdown = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));

    tokio::time::timeout(Duration::from_secs(5), probe.barrier.wait())
        .await
        .expect("a processor missed the refill notification");
    for handle in handles {
        let row = wait_terminal(&db.queue, handle.id(), 10).await;
        assert_eq!(row.status, JobStatus::Complete);
    }

    shutdown.cancel();
    run.await.unwrap().unwrap();
}

#[sqlx::test(migrations = "./migrations")]
async fn test_one_connection_pool_still_processes_jobs_after_listener_start(pool: PgPool) {
    let pool = pool_with_max(&pool, 1).await;
    let db = TestDb::new(pool).await;
    let handle = db.queue.enqueue(counts::job(())).await.unwrap().unwrap();
    let counter = Arc::new(AtomicU32::new(0));
    let worker = test_worker(db.queue.clone())
        .register_job(counts)
        .state(counter.clone())
        .burst(true)
        .dequeue_timeout(Duration::from_millis(400))
        .build()
        .unwrap();

    tokio::time::timeout(
        Duration::from_secs(10),
        worker.run_until(CancellationToken::new()),
    )
    .await
    .expect("the LISTEN connection must not consume the only pooled connection")
    .unwrap();

    assert_eq!(counter.load(Ordering::SeqCst), 1);
    assert_eq!(
        handle.fetch_job().await.unwrap().status,
        JobStatus::Complete
    );
}

#[sqlx::test(migrations = "./migrations")]
async fn test_failing_job_retries_then_fails(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let handle = db
        .queue
        .enqueue(always_fails::job(()))
        .await
        .unwrap()
        .unwrap();

    let worker = test_worker(db.queue.clone())
        .register_job(always_fails)
        .build()
        .unwrap();
    let token = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(token.clone()));

    let row = wait_terminal(&db.queue, handle.id(), 10).await;
    assert_eq!(row.status, JobStatus::Failed);
    assert_eq!(row.attempts, 2, "one retry (max_attempts = 2)");
    assert_eq!(row.error.as_deref(), Some("failed: boom"));

    token.cancel();
    run.await.unwrap().unwrap();
    assert_eq!(db.queue.stats().failed, 1);
    assert_eq!(db.queue.stats().retried, 1);
}

/// The subject is the *worker's own* attempt timeout, so the sweeper must not
/// race it. Every other queue here uses `sweep_grace(ZERO)`, which under
/// parallel load let the sweep leader's abort land inside `sleeps_forever`'s
/// 200ms timeout and settle the job `Aborted` instead of `Failed`. Both
/// outcomes are intended product behaviour; only one of them is under test.
#[sqlx::test(migrations = "./migrations")]
async fn test_worker_times_out_slow_job(pool: PgPool) {
    let db = TestDb::with(pool.clone(), |builder| {
        builder.sweep_grace(Duration::from_secs(60))
    })
    .await;
    let handle = db
        .queue
        .enqueue(sleeps_forever::job(()))
        .await
        .unwrap()
        .unwrap();

    let worker = test_worker(db.queue.clone())
        .register_job(sleeps_forever)
        .build()
        .unwrap();
    let token = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(token.clone()));

    let row = wait_terminal(&db.queue, handle.id(), 10).await;
    assert_eq!(row.status, JobStatus::Failed);
    assert!(
        row.error
            .as_deref()
            .unwrap_or_default()
            .starts_with("timeout:"),
        "{:?}",
        row.error
    );

    token.cancel();
    run.await.unwrap().unwrap();
}

#[sqlx::test(migrations = "./migrations")]
async fn test_panicking_job_fails_without_killing_the_worker(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let boom = db.queue.enqueue(panics::job(())).await.unwrap().unwrap();
    let fine = db
        .queue
        .enqueue(record::job(Payload {
            tag: "survivor".into(),
        }))
        .await
        .unwrap()
        .unwrap();

    let boom_static = db
        .queue
        .enqueue(panics_static::job(()))
        .await
        .unwrap()
        .unwrap();
    let boom_weird = db
        .queue
        .enqueue(panics_weird::job(()))
        .await
        .unwrap()
        .unwrap();
    let log: Log = Arc::new(Mutex::new(Vec::new()));
    let worker = test_worker(db.queue.clone())
        .register_job(panics)
        .register_job(panics_static)
        .register_job(panics_weird)
        .register_job(record)
        .state(log)
        .build()
        .unwrap();
    let token = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(token.clone()));

    let row = wait_terminal(&db.queue, boom.id(), 10).await;
    assert_eq!(row.status, JobStatus::Failed);
    assert_eq!(row.error.as_deref(), Some("panic: kaboom 42"));

    let row = wait_terminal(&db.queue, boom_static.id(), 10).await;
    assert_eq!(row.error.as_deref(), Some("panic: static kaboom"));

    let row = wait_terminal(&db.queue, boom_weird.id(), 10).await;
    assert_eq!(row.error.as_deref(), Some("panic: handler panicked"));

    // The worker survived the panic and keeps processing.
    let row = wait_terminal(&db.queue, fine.id(), 10).await;
    assert_eq!(row.status, JobStatus::Complete);

    token.cancel();
    run.await.unwrap().unwrap();
}

#[sqlx::test(migrations = "./migrations")]
async fn test_abort_cancels_a_running_job(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let handle = db
        .queue
        .enqueue(slow_but_abortable::job(()))
        .await
        .unwrap()
        .unwrap();
    let worker = test_worker(db.queue.clone())
        .register_job(slow_but_abortable)
        .build()
        .unwrap();
    let token = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(token.clone()));

    wait_status(&db.queue, handle.id(), JobStatus::Running, 10).await;
    assert!(handle.abort("operator said stop").await.unwrap());

    let row = wait_terminal(&db.queue, handle.id(), 10).await;
    assert_eq!(row.status, JobStatus::Aborted);
    assert_eq!(row.error.as_deref(), Some("operator said stop"));

    token.cancel();
    run.await.unwrap().unwrap();
    assert_eq!(db.queue.stats().aborted, 1);
}

#[sqlx::test(migrations = "./migrations")]
async fn test_user_abort_allows_handler_cleanup_and_finishes_aborted(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let handle = db
        .queue
        .enqueue(cleans_up_after_user_abort::job(()))
        .await
        .unwrap()
        .unwrap();
    let probe = AbortCleanupProbe {
        started: Arc::new(tokio::sync::Notify::new()),
        observed: Arc::new(tokio::sync::Notify::new()),
        cleaned: Arc::new(tokio::sync::Notify::new()),
    };
    let worker = test_worker(db.queue.clone())
        .register_job(cleans_up_after_user_abort)
        .state(probe.clone())
        .abort_grace(Duration::from_secs(2))
        .build()
        .unwrap();
    let shutdown = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));

    tokio::time::timeout(Duration::from_secs(5), probe.started.notified())
        .await
        .expect("handler did not start");
    assert!(handle.abort("cleanup requested").await.unwrap());
    tokio::time::timeout(Duration::from_secs(2), probe.observed.notified())
        .await
        .expect("handler did not observe the user abort");
    tokio::time::timeout(Duration::from_secs(2), probe.cleaned.notified())
        .await
        .expect("handler cleanup did not finish within abort grace");

    let row = wait_terminal(&db.queue, handle.id(), 5).await;
    assert_eq!(row.status, JobStatus::Aborted);
    assert_eq!(row.error.as_deref(), Some("cleanup requested"));
    assert!(row.result.is_none());

    shutdown.cancel();
    run.await.unwrap().unwrap();
}

#[sqlx::test(migrations = "./migrations")]
async fn test_user_abort_forces_handler_stop_when_cleanup_exceeds_abort_grace(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let handle = db
        .queue
        .enqueue(exceeds_abort_grace::job(()))
        .await
        .unwrap()
        .unwrap();
    let probe = ForcedAbortProbe {
        started: Arc::new(tokio::sync::Notify::new()),
        observed: Arc::new(tokio::sync::Notify::new()),
        dropped: Arc::new(tokio::sync::Notify::new()),
    };
    let worker = test_worker(db.queue.clone())
        .register_job(exceeds_abort_grace)
        .state(probe.clone())
        .abort_grace(Duration::from_millis(100))
        .build()
        .unwrap();
    let shutdown = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));

    tokio::time::timeout(Duration::from_secs(5), probe.started.notified())
        .await
        .expect("handler did not start");
    assert!(handle.abort("cleanup timed out").await.unwrap());
    tokio::time::timeout(Duration::from_secs(2), probe.observed.notified())
        .await
        .expect("handler did not get a cooperative cancellation opportunity");
    tokio::time::timeout(Duration::from_secs(2), probe.dropped.notified())
        .await
        .expect("handler was not forcibly stopped after abort grace");

    let row = wait_terminal(&db.queue, handle.id(), 5).await;
    assert_eq!(row.status, JobStatus::Aborted);
    assert_eq!(row.error.as_deref(), Some("cleanup timed out"));

    shutdown.cancel();
    run.await.unwrap().unwrap();
}

#[sqlx::test(migrations = "./migrations")]
async fn test_user_abort_stops_handler_immediately_when_abort_grace_is_zero(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let handle = db
        .queue
        .enqueue(exceeds_abort_grace::job(()))
        .await
        .unwrap()
        .unwrap();
    let probe = ForcedAbortProbe {
        started: Arc::new(tokio::sync::Notify::new()),
        observed: Arc::new(tokio::sync::Notify::new()),
        dropped: Arc::new(tokio::sync::Notify::new()),
    };
    let worker = test_worker(db.queue.clone())
        .register_job(exceeds_abort_grace)
        .state(probe.clone())
        .abort_grace(Duration::ZERO)
        .build()
        .unwrap();
    let shutdown = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));

    tokio::time::timeout(Duration::from_secs(5), probe.started.notified())
        .await
        .expect("handler did not start");
    assert!(handle.abort("no cleanup grace").await.unwrap());
    tokio::time::timeout(Duration::from_secs(2), probe.dropped.notified())
        .await
        .expect("handler was not stopped for zero abort grace");

    let row = wait_terminal(&db.queue, handle.id(), 5).await;
    assert_eq!(row.status, JobStatus::Aborted);
    assert_eq!(row.error.as_deref(), Some("no cleanup grace"));

    shutdown.cancel();
    run.await.unwrap().unwrap();
}

#[sqlx::test(migrations = "./migrations")]
async fn test_pending_abort_wins_over_a_final_attempt_failure(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let handle = db
        .queue
        .enqueue(fails_during_abort::job(()))
        .await
        .unwrap()
        .unwrap();
    let state = AbortFailureRace {
        started: Arc::new(tokio::sync::Notify::new()),
        release: Arc::new(tokio::sync::Notify::new()),
    };
    let worker = test_worker(db.queue.clone())
        .register_job(fails_during_abort)
        .state(state.clone())
        .timers(WorkerTimers {
            abort: Duration::from_secs(5),
            ..test_timers()
        })
        .build()
        .unwrap();
    let token = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(token.clone()));

    state.started.notified().await;
    // Let the abort loop consume its immediate first interval tick. Its next
    // poll is deliberately later than the handler failure below.
    tokio::time::sleep(Duration::from_millis(100)).await;
    assert!(handle.abort("operator abort won").await.unwrap());
    state.release.notify_one();

    let row = wait_terminal(&db.queue, handle.id(), 5).await;
    assert_eq!(row.status, JobStatus::Aborted);
    assert_eq!(row.error.as_deref(), Some("operator abort won"));

    token.cancel();
    run.await.unwrap().unwrap();
}

#[sqlx::test(migrations = "./migrations")]
async fn test_pending_abort_wins_over_a_successful_handler(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let handle = db
        .queue
        .enqueue(succeeds_during_abort::job(()))
        .await
        .unwrap()
        .unwrap();
    let state = AbortSuccessRace {
        started: Arc::new(tokio::sync::Notify::new()),
        release: Arc::new(tokio::sync::Notify::new()),
    };
    let worker = test_worker(db.queue.clone())
        .register_job(succeeds_during_abort)
        .state(state.clone())
        .timers(WorkerTimers {
            abort: Duration::from_secs(5),
            ..test_timers()
        })
        .build()
        .unwrap();
    let token = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(token.clone()));

    state.started.notified().await;
    tokio::time::sleep(Duration::from_millis(100)).await;
    assert!(handle.abort("operator abort won").await.unwrap());
    state.release.notify_one();

    let row = wait_terminal(&db.queue, handle.id(), 5).await;
    assert_eq!(row.status, JobStatus::Aborted);
    assert_eq!(row.error.as_deref(), Some("operator abort won"));
    assert!(row.result.is_none());

    token.cancel();
    run.await.unwrap().unwrap();
}

/// Inserts `count` already-expired terminal job rows for the sweeper to purge.
async fn insert_expired_jobs(db: &TestDb, count: i64) {
    sqlx::query(
        "INSERT INTO pgqueue.jobs (queue, name, payload, status, expires_at, max_attempts)
         SELECT 'default', 'purge_me', '{}'::jsonb, 'complete',
                now() - interval '1 second', 1
         FROM generate_series(1, $1)",
    )
    .bind(count as i32)
    .execute(db.queue.pool())
    .await
    .expect("insert expired jobs");
}

async fn count_jobs_named(db: &TestDb, name: &str) -> i64 {
    sqlx::query_scalar::<_, i64>("SELECT count(*) FROM pgqueue.jobs WHERE name = $1")
        .bind(name)
        .fetch_one(db.queue.pool())
        .await
        .expect("count jobs")
}

#[sqlx::test(migrations = "./migrations")]
async fn test_sweep_reports_only_the_operations_that_filled_their_batch(pool: PgPool) {
    let db = TestDb::with(pool.clone(), |builder| builder.sweep_batch_size(1)).await;
    insert_expired_jobs(&db, 2).await;
    sqlx::query(
        "INSERT INTO pgqueue.cron_occurrences (queue, dedupe_key, scheduled_at, expires_at)
         SELECT 'default', 'cron:expired', now() - make_interval(secs => i),
                now() - interval '1 second'
         FROM generate_series(1, 2) AS s(i)",
    )
    .execute(db.queue.pool())
    .await
    .unwrap();

    let mut sweeper = db.queue.sweeper();
    let report = sweeper.sweep().await.unwrap();
    assert!(report.leader);
    assert_eq!(report.purged_jobs, 1);
    assert!(report.more_work());
    assert!(report.unfinished.expired_jobs);
    assert!(report.unfinished.cron_occurrences);
    assert!(!report.unfinished.workers);
    assert!(!report.unfinished.stuck_jobs);

    // A drain pass runs only the operations that reported more work, so an
    // operation left out is not re-issued at all.
    let only_jobs = pgqueue::SweepOperations {
        expired_jobs: true,
        ..pgqueue::SweepOperations::NONE
    };
    let next = sweeper.sweep_operations(only_jobs).await.unwrap();
    assert_eq!(next.purged_jobs, 1);
    assert_eq!(
        next.unfinished, only_jobs,
        "a full batch may have more work"
    );
    assert_eq!(count_jobs_named(&db, "purge_me").await, 0);

    let drained = sweeper.sweep_operations(only_jobs).await.unwrap();
    assert_eq!(drained.purged_jobs, 0);
    assert_eq!(drained.unfinished, pgqueue::SweepOperations::NONE);
    assert!(!drained.more_work());
    assert_eq!(
        sqlx::query_scalar::<_, i64>("SELECT count(*) FROM pgqueue.cron_occurrences")
            .fetch_one(db.queue.pool())
            .await
            .unwrap(),
        1,
        "the drain left the cron occurrence purge out, so it did not run"
    );
    sweeper.release().await;
}

#[sqlx::test(migrations = "./migrations")]
async fn test_sweep_drain_stops_at_the_pass_budget(pool: PgPool) {
    // One row per pass makes the drain's pass budget directly observable.
    const BACKLOG: i64 = 40;
    const MAX_SWEEP_DRAIN_PASSES: i64 = 16;

    let db = TestDb::with(pool.clone(), |builder| builder.sweep_batch_size(1)).await;
    insert_expired_jobs(&db, BACKLOG).await;
    let worker = Worker::builder(db.queue.clone())
        // Only the sweeper runs: every other loop is parked for this test.
        .timers(WorkerTimers {
            abort: Duration::from_secs(600),
            schedule: Duration::from_secs(600),
            sweep: Duration::from_secs(600),
            worker_info: Duration::from_secs(600),
        })
        .poll_interval(Duration::from_secs(600))
        .register_job(counts)
        .state(Arc::new(AtomicU32::new(0)))
        .build()
        .unwrap();
    let shutdown = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));

    wait_until(
        Duration::from_secs(5),
        Duration::from_millis(25),
        "sweeper never drained a batch",
        || async { count_jobs_named(&db, "purge_me").await < BACKLOG },
    )
    .await;
    // A drain is bounded by `MAX_SWEEP_DRAIN_TIME` as well as by its pass
    // budget, and on a loaded host the clock is the one that stops it — so wait
    // for the tick to settle rather than for a particular number of passes.
    // Requiring all sixteen inside a wall-clock second made this test fail under
    // load, with no second tick coming (the sweep timer here is 600s).
    let mut remaining = count_jobs_named(&db, "purge_me").await;
    let settled = tokio::time::Instant::now() + Duration::from_secs(20);
    loop {
        tokio::time::sleep(Duration::from_millis(400)).await;
        let next = count_jobs_named(&db, "purge_me").await;
        if next == remaining {
            break;
        }
        assert!(
            tokio::time::Instant::now() < settled,
            "the sweep drain never settled: {next} of {BACKLOG} left"
        );
        remaining = next;
    }

    // The sweeper shares the worker's pool, so one tick drains a bounded number
    // of batches instead of running back-to-back passes for its whole budget:
    // the backlog is more than twice the budget, and what is left proves the
    // tick stopped well short of draining it.
    let purged = BACKLOG - remaining;
    assert!(
        (1..=MAX_SWEEP_DRAIN_PASSES).contains(&purged),
        "one tick purged {purged} of {BACKLOG} rows, outside the 1..={MAX_SWEEP_DRAIN_PASSES} \
         pass budget"
    );

    shutdown.cancel();
    run.await.unwrap().unwrap();
}

#[sqlx::test(migrations = "./migrations")]
async fn test_sweeper_abort_racing_a_retryable_failure_still_retries(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let mut sweeper = db.queue.sweeper();
    assert!(sweeper.sweep().await.unwrap().leader);

    let handle = db
        .queue
        .enqueue(fails_as_sweeper_marks::job(()))
        .await
        .unwrap()
        .unwrap();
    let state = SweepFailureRace {
        started: Arc::new(tokio::sync::Notify::new()),
        release: Arc::new(tokio::sync::Notify::new()),
    };
    let worker = test_worker(db.queue.clone())
        .register_job(fails_as_sweeper_marks)
        .state(state.clone())
        .timers(WorkerTimers {
            abort: Duration::from_secs(5),
            ..test_timers()
        })
        .build()
        .unwrap();
    let token = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(token.clone()));

    state.started.notified().await;
    backdate_job_liveness(&db, handle.id()).await;
    assert_eq!(sweeper.sweep().await.unwrap().cancelling, vec![handle.id()]);
    state.release.notify_one();

    let row = wait_terminal(&db.queue, handle.id(), 5).await;
    assert_eq!(row.status, JobStatus::Complete);
    assert_eq!(row.attempts, 2);

    token.cancel();
    run.await.unwrap().unwrap();
    sweeper.release().await;
}

/// The user-abort half of the race above: an operator abort that lands while
/// the row is sweeper-marked `aborting` wins over the sweeper's pending
/// retry. The owning worker's failing attempt finalizes `aborted` with the
/// operator's reason instead of being requeued and run again.
#[sqlx::test(migrations = "./migrations")]
async fn test_user_abort_during_the_sweeper_marked_window_wins_over_the_retry(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let mut sweeper = db.queue.sweeper();
    assert!(sweeper.sweep().await.unwrap().leader);

    let handle = db
        .queue
        .enqueue(fails_as_sweeper_marks::job(()))
        .await
        .unwrap()
        .unwrap();
    let state = SweepFailureRace {
        started: Arc::new(tokio::sync::Notify::new()),
        release: Arc::new(tokio::sync::Notify::new()),
    };
    let worker = test_worker(db.queue.clone())
        .register_job(fails_as_sweeper_marks)
        .state(state.clone())
        .timers(WorkerTimers {
            abort: Duration::from_secs(5),
            ..test_timers()
        })
        .build()
        .unwrap();
    let token = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(token.clone()));

    state.started.notified().await;
    backdate_job_liveness(&db, handle.id()).await;
    assert_eq!(sweeper.sweep().await.unwrap().cancelling, vec![handle.id()]);
    assert!(
        db.queue
            .abort_job(handle.id(), "operator said stop")
            .await
            .unwrap(),
        "the abort claims the sweeper-marked row"
    );
    state.release.notify_one();

    let row = wait_terminal(&db.queue, handle.id(), 5).await;
    assert_eq!(row.status, JobStatus::Aborted);
    assert_eq!(row.error.as_deref(), Some("operator said stop"));
    assert_eq!(row.attempts, 1, "the job never ran again");

    token.cancel();
    run.await.unwrap().unwrap();
    sweeper.release().await;
}

/// The retry that carries a failed attempt past a sweeper abort must carry its
/// reason too. It used to store nothing, which left the sweeper's internal
/// `swept` marker standing as the row's `error` for the whole retry-backoff
/// window and the next attempt — so `fetch_job`, `jobs_page` and the dashboard
/// all reported "swept" for a job that failed with a real, actionable error.
/// The non-retryable half of the identical race has always preserved it (see
/// `test_final_handler_failure_finishes_through_a_sweeper_abort`).
#[sqlx::test(migrations = "./migrations")]
async fn test_sweeper_abort_racing_a_retryable_failure_keeps_the_handler_error(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let mut sweeper = db.queue.sweeper();
    assert!(sweeper.sweep().await.unwrap().leader);

    let handle = db
        .queue
        .enqueue(fails_then_parks_as_sweeper_marks::job(()))
        .await
        .unwrap()
        .unwrap();
    let state = SweepFailureReasonRace {
        started: Arc::new(tokio::sync::Notify::new()),
        release: Arc::new(tokio::sync::Notify::new()),
        retried: Arc::new(tokio::sync::Notify::new()),
        hold: Arc::new(tokio::sync::Notify::new()),
    };
    let worker = test_worker(db.queue.clone())
        .register_job(fails_then_parks_as_sweeper_marks)
        .state(state.clone())
        .timers(WorkerTimers {
            abort: Duration::from_secs(5),
            ..test_timers()
        })
        .build()
        .unwrap();
    let token = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(token.clone()));

    // The sweeper marks the attempt for abort while the handler is parked, so
    // the failure it returns next lands on an `aborting` row: `retry` is
    // refused and the swept-abort retry is what requeues it.
    state.started.notified().await;
    backdate_job_liveness(&db, handle.id()).await;
    assert_eq!(sweeper.sweep().await.unwrap().cancelling, vec![handle.id()]);
    state.release.notify_one();

    // The second attempt parks, so the row is read at exactly the point an
    // operator would see it: after the retry, before it is overwritten.
    state.retried.notified().await;
    let row = db
        .queue
        .fetch_job(handle.id())
        .await
        .unwrap()
        .expect("the requeued job row");
    assert_eq!(row.attempts, 2);
    assert_eq!(
        row.error.as_deref(),
        Some("failed: the real handler failure"),
        "the retry must report why the attempt failed, not the sweeper's marker"
    );

    state.hold.notify_one();
    let row = wait_terminal(&db.queue, handle.id(), 10).await;
    assert_eq!(row.status, JobStatus::Complete);

    token.cancel();
    run.await.unwrap().unwrap();
    sweeper.release().await;
}

#[sqlx::test(migrations = "./migrations")]
async fn test_successful_handler_finishes_through_a_sweeper_abort(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let mut sweeper = db.queue.sweeper();
    assert!(sweeper.sweep().await.unwrap().leader);
    let handle = db
        .queue
        .enqueue(succeeds_as_sweeper_marks::job(()))
        .await
        .unwrap()
        .unwrap();
    let state = AbortSuccessRace {
        started: Arc::new(tokio::sync::Notify::new()),
        release: Arc::new(tokio::sync::Notify::new()),
    };
    let worker = test_worker(db.queue.clone())
        .register_job(succeeds_as_sweeper_marks)
        .state(state.clone())
        .timers(WorkerTimers {
            abort: Duration::from_secs(5),
            ..test_timers()
        })
        .build()
        .unwrap();
    let token = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(token.clone()));

    state.started.notified().await;
    backdate_job_liveness(&db, handle.id()).await;
    assert_eq!(sweeper.sweep().await.unwrap().cancelling, vec![handle.id()]);
    state.release.notify_one();

    let row = wait_terminal(&db.queue, handle.id(), 5).await;
    assert_eq!(row.status, JobStatus::Complete);
    assert_eq!(row.attempts, 1);
    assert_eq!(db.queue.counts().await.unwrap().queued, 0);

    token.cancel();
    run.await.unwrap().unwrap();
    sweeper.release().await;
}

#[sqlx::test(migrations = "./migrations")]
async fn test_final_handler_failure_finishes_through_a_sweeper_abort(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let mut sweeper = db.queue.sweeper();
    assert!(sweeper.sweep().await.unwrap().leader);
    let handle = db
        .queue
        .enqueue(fails_as_sweeper_marks::job(()).max_attempts(1))
        .await
        .unwrap()
        .unwrap();
    let state = SweepFailureRace {
        started: Arc::new(tokio::sync::Notify::new()),
        release: Arc::new(tokio::sync::Notify::new()),
    };
    let worker = test_worker(db.queue.clone())
        .register_job(fails_as_sweeper_marks)
        .state(state.clone())
        .timers(WorkerTimers {
            abort: Duration::from_secs(5),
            ..test_timers()
        })
        .build()
        .unwrap();
    let token = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(token.clone()));

    state.started.notified().await;
    backdate_job_liveness(&db, handle.id()).await;
    assert_eq!(sweeper.sweep().await.unwrap().cancelling, vec![handle.id()]);
    state.release.notify_one();

    let row = wait_terminal(&db.queue, handle.id(), 5).await;
    assert_eq!(row.status, JobStatus::Failed);
    assert_eq!(
        row.error.as_deref(),
        Some("failed: handler failed as sweep abort landed")
    );

    token.cancel();
    run.await.unwrap().unwrap();
    sweeper.release().await;
}

#[sqlx::test(migrations = "./migrations")]
async fn test_undecodable_payload_fails_with_decode_error(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    // Enqueue raw JSON that does not match `Payload`.
    let id = db
        .queue
        .enqueue_raw(JobRequest::new("record", json!({"wrong": "shape"})))
        .await
        .unwrap()
        .unwrap();

    let log: Log = Arc::new(Mutex::new(Vec::new()));
    let worker = test_worker(db.queue.clone())
        .register_job(record)
        .state(log)
        .build()
        .unwrap();
    let token = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(token.clone()));

    let row = wait_terminal(&db.queue, id, 10).await;
    assert_eq!(row.status, JobStatus::Failed);
    assert!(
        row.error
            .as_deref()
            .unwrap_or_default()
            .starts_with("decode:"),
        "{:?}",
        row.error
    );

    token.cancel();
    run.await.unwrap().unwrap();
}

#[sqlx::test(migrations = "./migrations")]
async fn test_missing_state_fails_with_extract_error(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let handle = db
        .queue
        .enqueue(needs_missing_state::job(()))
        .await
        .unwrap()
        .unwrap();

    let worker = test_worker(db.queue.clone())
        .register_job(needs_missing_state)
        .build()
        .unwrap();
    let token = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(token.clone()));

    let row = wait_terminal(&db.queue, handle.id(), 10).await;
    assert_eq!(row.status, JobStatus::Failed);
    // Extract failures are deterministic: no retry despite max_attempts = 5.
    assert_eq!(row.attempts, 1);
    let error = row.error.as_deref().unwrap_or_default();
    assert!(
        error.starts_with("extract:") && error.contains("Uuid"),
        "{error:?}"
    );

    token.cancel();
    run.await.unwrap().unwrap();
}

#[sqlx::test(migrations = "./migrations")]
async fn test_undecodable_payload_fails_without_retry_when_attempts_remain(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let id = db
        .queue
        .enqueue_raw(JobRequest::new(
            "decodes_payload",
            json!({"wrong": "shape"}),
        ))
        .await
        .unwrap()
        .unwrap();

    let worker = test_worker(db.queue.clone())
        .register_job(decodes_payload)
        .build()
        .unwrap();
    let token = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(token.clone()));

    let row = wait_terminal(&db.queue, id, 10).await;
    assert_eq!(row.status, JobStatus::Failed);
    // Decode failures are deterministic: no retry despite max_attempts = 5.
    assert_eq!(row.attempts, 1);
    assert!(
        row.error
            .as_deref()
            .unwrap_or_default()
            .starts_with("decode:"),
        "{:?}",
        row.error
    );

    token.cancel();
    run.await.unwrap().unwrap();
}

#[sqlx::test(migrations = "./migrations")]
async fn test_returned_job_error_preserves_its_kind_and_retry_policy(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let handle = db
        .queue
        .enqueue(returns_decode_error::job(()))
        .await
        .unwrap()
        .unwrap();

    let worker = test_worker(db.queue.clone())
        .register_job(returns_decode_error)
        .build()
        .unwrap();
    let token = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(token.clone()));

    let row = wait_terminal(&db.queue, handle.id(), 10).await;
    assert_eq!(row.status, JobStatus::Failed);
    assert_eq!(row.attempts, 1, "decode errors must not retry");
    assert_eq!(row.error.as_deref(), Some("decode: handler decode failure"));

    token.cancel();
    run.await.unwrap().unwrap();
}

#[sqlx::test(migrations = "./migrations")]
async fn test_workers_only_dequeue_registered_job_names(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let handle = db.queue.enqueue(counts::job(())).await.unwrap().unwrap();

    let worker = test_worker(db.queue.clone())
        .register_job(always_fails)
        .burst(true)
        .dequeue_timeout(Duration::from_millis(200))
        .build()
        .unwrap();
    worker.run_until(CancellationToken::new()).await.unwrap();

    let row = handle.fetch_job().await.unwrap();
    assert_eq!(row.status, JobStatus::Queued);
    assert_eq!(row.attempts, 0, "an incompatible worker must not claim it");

    let counter = Arc::new(AtomicU32::new(0));
    let worker = test_worker(db.queue.clone())
        .register_job(counts)
        .state(counter.clone())
        .burst(true)
        .dequeue_timeout(Duration::from_millis(200))
        .build()
        .unwrap();
    worker.run_until(CancellationToken::new()).await.unwrap();
    assert_eq!(counter.load(Ordering::SeqCst), 1);
    assert_eq!(
        handle.fetch_job().await.unwrap().status,
        JobStatus::Complete
    );
}

#[sqlx::test(migrations = "./migrations")]
async fn test_registered_name_filter_applies_through_batch_dequeues(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    db.queue
        .enqueue_raw(JobRequest::new("unhandled", json!(null)))
        .await
        .unwrap();
    let handles = vec![
        db.queue.enqueue(counts::job(())).await.unwrap().unwrap(),
        db.queue.enqueue(counts::job(())).await.unwrap().unwrap(),
        db.queue.enqueue(counts::job(())).await.unwrap().unwrap(),
    ];

    let counter = Arc::new(AtomicU32::new(0));
    test_worker(db.queue.clone())
        .register_job(counts)
        .state(counter.clone())
        .concurrency(3)
        .burst(true)
        .dequeue_timeout(Duration::from_millis(200))
        .build()
        .unwrap()
        .run_until(CancellationToken::new())
        .await
        .unwrap();

    assert_eq!(counter.load(Ordering::SeqCst), 3);
    for handle in handles {
        assert_eq!(
            handle.fetch_job().await.unwrap().status,
            JobStatus::Complete
        );
    }
    let unhandled: String =
        sqlx::query_scalar::<_, String>("SELECT status FROM pgqueue.jobs WHERE name = 'unhandled'")
            .fetch_one(db.queue.pool())
            .await
            .unwrap();
    assert_eq!(unhandled, "queued");
}

/// `pg_stat_activity.query` is truncated at `track_activity_query_size`, so a
/// blocked dequeue is matched on the claim statement's opening CTE.
const DEQUEUE_STATEMENT: &str = "%WITH candidates AS (%";

const DEQUEUE_HANDOFF_GATE: i32 = 20_561;
const DEQUEUE_CONNECTION_GATE: i32 = 20_562;
const SHUTDOWN_REQUEUE_GATE: i32 = 20_563;

async fn install_dequeue_handoff_gate(pool: &PgPool) {
    crate::install_statement_gate(
        pool,
        "wait_at_dequeue_handoff",
        DEQUEUE_HANDOFF_GATE,
        "UPDATE",
        "OLD.status = 'queued' AND NEW.status = 'running'",
    )
    .await;
}

async fn install_shutdown_requeue_gate(pool: &PgPool) {
    crate::install_statement_gate(
        pool,
        "wait_at_shutdown_requeue",
        SHUTDOWN_REQUEUE_GATE,
        "UPDATE",
        "OLD.status = 'running' AND NEW.status = 'queued' AND NEW.error = 'cancelled'",
    )
    .await;
}

#[sqlx::test(migrations = "./migrations")]
async fn test_dequeue_worker_returns_committed_batch_when_post_commit_probe_fails(pool: PgPool) {
    let control = TestDb::new(pool_with_max(&pool, 5).await).await;
    let worker_pool = sqlx::postgres::PgPoolOptions::new()
        .max_connections(1)
        .acquire_timeout(Duration::from_millis(500))
        .connect_with(pool.connect_options().as_ref().clone())
        .await
        .unwrap();
    let worker_db = TestDb::new(worker_pool.clone()).await;
    install_dequeue_handoff_gate(control.queue.pool()).await;

    let dequeue_gate = crate::hold_gate(
        control.queue.pool(),
        DEQUEUE_HANDOFF_GATE,
        &control.database,
    )
    .await;
    let connection_gate = crate::hold_gate(
        control.queue.pool(),
        DEQUEUE_CONNECTION_GATE,
        &control.database,
    )
    .await;

    let worker_id = Uuid::now_v7();
    control
        .queue
        .write_worker_info(worker_id, json!({}), None, Duration::from_secs(60))
        .await
        .unwrap();
    let handle = control
        .queue
        .enqueue(counts::job(()))
        .await
        .unwrap()
        .unwrap();

    let worker_queue = worker_db.queue.clone();
    let mut dequeue = tokio::spawn(async move {
        pgqueue::__test_support::dequeue_worker(
            &worker_queue,
            2,
            worker_id,
            &["counts".to_owned()],
            false,
        )
        .await
    });
    crate::wait_for_lock_waiter(
        &control,
        DEQUEUE_STATEMENT,
        "worker did not pause while claiming the job",
    )
    .await;

    let database = control.database.clone();
    let connection_pool = worker_pool.clone();
    let mut connection_stealer = tokio::spawn(async move {
        sqlx::query("SELECT pg_advisory_xact_lock($1, hashtext($2))")
            .bind(DEQUEUE_CONNECTION_GATE)
            .bind(database)
            .execute(&connection_pool)
            .await
    });
    assert!(
        tokio::time::timeout(Duration::from_millis(50), &mut connection_stealer)
            .await
            .is_err(),
        "probe connection was not queued behind the dequeue"
    );

    dequeue_gate.rollback().await.unwrap();
    crate::wait_for_lock_waiter(
        &control,
        "%SELECT pg_advisory_xact_lock($1, hashtext($2))%",
        "connection stealer did not hold the committed dequeue connection",
    )
    .await;
    let jobs = tokio::time::timeout(Duration::from_secs(2), &mut dequeue)
        .await
        .expect("worker dequeue did not return after its probe timed out")
        .unwrap()
        .expect("post-commit probe failure discarded the committed batch");

    assert_eq!(jobs.len(), 1);
    assert_eq!(jobs[0].id, handle.id());
    assert_eq!(jobs[0].status, JobStatus::Running);
    assert_eq!(jobs[0].worker_id, Some(worker_id));

    connection_gate.rollback().await.unwrap();
    connection_stealer.await.unwrap().unwrap();
    assert!(
        control
            .queue
            .finish(&jobs[0], JobStatus::Complete, Some(json!(null)), None)
            .await
            .unwrap()
    );
    assert_eq!(
        handle.fetch_job().await.unwrap().status,
        JobStatus::Complete
    );
}

#[sqlx::test(migrations = "./migrations")]
async fn test_graceful_shutdown_requeues_inflight_jobs(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let handle = db
        .queue
        .enqueue(slow_but_abortable::job(()).retry_delay(Duration::from_secs(60 * 60)))
        .await
        .unwrap()
        .unwrap();
    let scheduled_at = handle.fetch_job().await.unwrap().scheduled_at;

    let worker = test_worker(db.queue.clone())
        .register_job(slow_but_abortable)
        .shutdown_grace(Duration::from_millis(100))
        .build()
        .unwrap();
    let token = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(token.clone()));

    wait_status(&db.queue, handle.id(), JobStatus::Running, 10).await;
    token.cancel();
    run.await.unwrap().unwrap();

    let row = handle.fetch_job().await.unwrap();
    assert_eq!(row.status, JobStatus::Queued, "requeued on shutdown");
    assert_eq!(row.error.as_deref(), Some("cancelled"));
    assert_eq!(row.attempts, 1, "execution history remains monotonic");
    assert_eq!(row.max_attempts, 2, "shutdown refunds the retry budget");
    assert_eq!(db.queue.stats().retried, 1);
    assert_eq!(
        row.scheduled_at, scheduled_at,
        "shutdown does not apply failure backoff"
    );
}

/// The subject is the shutdown handoff, so the worker's own sweeper must not
/// race it. This test holds a row lock on `pgqueue.workers` to freeze the
/// worker's heartbeat, so its 75ms lease lapses on purpose — and under
/// `sweep_grace(ZERO)` a lapsed lease makes the buffered attempt recoverable
/// immediately, letting the sweep leader mark it `aborting` before the assertion
/// below reads it. The cushion is the same one `test_worker_times_out_slow_job`
/// needs, for the same reason.
#[sqlx::test(migrations = "./migrations")]
async fn test_graceful_shutdown_waits_for_buffered_job_requeue(pool: PgPool) {
    let control = TestDb::new(pool_with_max(&pool, 6).await).await;
    let db = TestDb::with(pool_with_max(&pool, 5).await, |builder| {
        builder.sweep_grace(Duration::from_secs(60))
    })
    .await;
    install_dequeue_handoff_gate(control.queue.pool()).await;
    install_shutdown_requeue_gate(control.queue.pool()).await;

    let dequeue_gate = crate::hold_gate(
        control.queue.pool(),
        DEQUEUE_HANDOFF_GATE,
        &control.database,
    )
    .await;
    let requeue_gate = crate::hold_gate(
        control.queue.pool(),
        SHUTDOWN_REQUEUE_GATE,
        &control.database,
    )
    .await;

    let counter = Arc::new(AtomicU32::new(0));
    let handle = control
        .queue
        .enqueue(counts::job(()))
        .await
        .unwrap()
        .unwrap();
    let worker = test_worker(db.queue.clone())
        .register_job(counts)
        .state(counter.clone())
        .concurrency(1)
        .timers(WorkerTimers {
            abort: Duration::from_secs(60),
            worker_info: Duration::from_millis(25),
            ..test_timers()
        })
        .shutdown_grace(Duration::from_secs(10))
        .build()
        .unwrap();
    let worker_id = worker.id();
    let token = CancellationToken::new();
    let mut run = tokio::spawn(worker.run_until(token.clone()));

    crate::wait_for_lock_waiter(
        &control,
        DEQUEUE_STATEMENT,
        "worker did not pause while dequeuing",
    )
    .await;
    let mut worker_gate = control.queue.pool().begin().await.unwrap();
    sqlx::query(
        "UPDATE pgqueue.workers SET expires_at = now() - interval '1 second' WHERE id = $1",
    )
    .bind(worker_id)
    .execute(&mut *worker_gate)
    .await
    .unwrap();

    token.cancel();
    crate::wait_for_lock_waiter(
        &control,
        "%UPDATE pgqueue.workers SET accepting = false%",
        "shutdown did not freeze worker intake",
    )
    .await;
    dequeue_gate.rollback().await.unwrap();
    crate::wait_for_lock_waiter(
        &control,
        "%WITH requeued AS (%",
        "fetcher did not begin draining its buffered job",
    )
    .await;
    assert_eq!(handle.fetch_job().await.unwrap().status, JobStatus::Running);

    worker_gate.rollback().await.unwrap();
    wait_for_worker_intake_closed(&control, worker_id).await;
    assert!(
        tokio::time::timeout(Duration::from_millis(250), &mut run)
            .await
            .is_err(),
        "worker returned before its buffered job was requeued"
    );

    requeue_gate.rollback().await.unwrap();
    tokio::time::timeout(Duration::from_secs(5), run)
        .await
        .expect("worker did not finish after its buffered job was requeued")
        .unwrap()
        .unwrap();

    let row = handle.fetch_job().await.unwrap();
    assert_eq!(counter.load(Ordering::SeqCst), 0);
    assert_eq!(row.status, JobStatus::Queued);
    assert_eq!(row.error.as_deref(), Some("cancelled"));
    assert_eq!(db.queue.stats().retried, 1);
}

#[sqlx::test(migrations = "./migrations")]
async fn test_graceful_shutdown_finalizes_abort_when_job_is_buffered(pool: PgPool) {
    let control = TestDb::new(pool_with_max(&pool, 5).await).await;
    let db = TestDb::new(pool_with_max(&pool, 2).await).await;
    let counter = Arc::new(AtomicU32::new(0));
    let probe = DatabaseLossProbe {
        started: Arc::new(tokio::sync::Notify::new()),
        release: Arc::new(tokio::sync::Notify::new()),
    };
    let grace_job = control
        .queue
        .enqueue(quick_nap::job(()))
        .await
        .unwrap()
        .unwrap();

    let worker = test_worker(db.queue.clone())
        .register_job(counts)
        .register_job(quick_nap)
        .state(counter.clone())
        .state(probe.clone())
        .concurrency(3)
        .timers(WorkerTimers {
            abort: Duration::from_secs(60),
            worker_info: Duration::from_secs(60),
            ..test_timers()
        })
        .shutdown_grace(Duration::from_secs(10))
        .build()
        .unwrap();
    let worker_id = worker.id();
    let token = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(token.clone()));

    tokio::time::timeout(Duration::from_secs(5), probe.started.notified())
        .await
        .expect("grace job did not start");
    install_dequeue_handoff_gate(control.queue.pool()).await;
    let dequeue_gate = crate::hold_gate(
        control.queue.pool(),
        DEQUEUE_HANDOFF_GATE,
        &control.database,
    )
    .await;
    let connection_gate = crate::hold_gate(
        control.queue.pool(),
        DEQUEUE_CONNECTION_GATE,
        &control.database,
    )
    .await;
    let handle = control
        .queue
        .enqueue(counts::job(()).timeout(Duration::from_secs(60 * 60)))
        .await
        .unwrap()
        .unwrap();
    crate::wait_for_lock_waiter(
        &control,
        DEQUEUE_STATEMENT,
        "worker did not pause while dequeuing",
    )
    .await;

    let mut worker_gate = control.queue.pool().begin().await.unwrap();
    sqlx::query(
        "UPDATE pgqueue.workers SET expires_at = now() - interval '1 second' WHERE id = $1",
    )
    .bind(worker_id)
    .execute(&mut *worker_gate)
    .await
    .unwrap();
    token.cancel();
    crate::wait_for_lock_waiter(
        &control,
        "%UPDATE pgqueue.workers SET accepting = false%",
        "shutdown did not freeze worker intake",
    )
    .await;

    let worker_pool = db.queue.pool().clone();
    let database = db.database.clone();
    let mut connection_stealer = tokio::spawn(async move {
        sqlx::query("SELECT pg_advisory_xact_lock($1, hashtext($2))")
            .bind(DEQUEUE_CONNECTION_GATE)
            .bind(database)
            .execute(&worker_pool)
            .await
    });
    assert!(
        tokio::time::timeout(Duration::from_millis(100), &mut connection_stealer)
            .await
            .is_err(),
        "worker pool connections were not occupied by dequeue and shutdown"
    );

    dequeue_gate.rollback().await.unwrap();
    crate::wait_for_lock_waiter(
        &control,
        "%SELECT pg_advisory_xact_lock($1, hashtext($2))%",
        "worker connection was not held after committing its dequeue",
    )
    .await;
    assert_eq!(handle.fetch_job().await.unwrap().status, JobStatus::Running);

    assert!(handle.abort("buffered abort").await.unwrap());
    assert_eq!(
        handle.fetch_job().await.unwrap().status,
        JobStatus::Aborting
    );
    connection_gate.rollback().await.unwrap();
    connection_stealer.await.unwrap().unwrap();
    crate::wait_for_lock_waiter(
        &control,
        "%WITH requeued AS (%",
        "fetcher did not take responsibility for the buffered job",
    )
    .await;
    worker_gate.rollback().await.unwrap();

    let aborted = tokio::time::timeout(Duration::from_secs(5), async {
        loop {
            let row = handle.fetch_job().await.unwrap();
            if row.status == JobStatus::Aborted {
                return row;
            }
            tokio::time::sleep(Duration::from_millis(10)).await;
        }
    })
    .await;
    probe.release.notify_one();
    let run_result = tokio::time::timeout(Duration::from_secs(5), run)
        .await
        .expect("worker did not finish graceful shutdown");

    let row = aborted.expect("buffered abort was not finalized");
    run_result.unwrap().unwrap();
    assert_eq!(counter.load(Ordering::SeqCst), 0);
    assert_eq!(row.status, JobStatus::Aborted);
    assert_eq!(row.error.as_deref(), Some("buffered abort"));
    assert!(row.completed_at.is_some());
    assert_eq!(
        grace_job.fetch_job().await.unwrap().status,
        JobStatus::Complete
    );
}

#[sqlx::test(migrations = "./migrations")]
async fn test_run_until_requeues_inflight_jobs_when_aborted(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let handle = db
        .queue
        .enqueue(slow_but_abortable::job(()))
        .await
        .unwrap()
        .unwrap();
    let worker = test_worker(db.queue.clone())
        .register_job(slow_but_abortable)
        .shutdown_grace(Duration::from_millis(100))
        .build()
        .unwrap();
    let worker_id = worker.id();
    let run = tokio::spawn(worker.run_until(CancellationToken::new()));

    wait_status(&db.queue, handle.id(), JobStatus::Running, 10).await;
    run.abort();
    assert!(run.await.unwrap_err().is_cancelled());

    let row = wait_status(&db.queue, handle.id(), JobStatus::Queued, 10).await;
    assert_eq!(row.error.as_deref(), Some("cancelled"));
    assert_eq!(row.attempts, 1, "execution history remains monotonic");
    assert_eq!(row.max_attempts, 2, "shutdown refunds the retry budget");
    wait_for_some(
        Duration::from_secs(5),
        Duration::from_millis(25),
        "aborted run_until left a live worker lease",
        || async {
            db.queue
                .info()
                .await
                .unwrap()
                .workers
                .iter()
                .all(|worker| worker.id != worker_id)
                .then_some(())
        },
    )
    .await;
}

#[sqlx::test(migrations = "./migrations")]
async fn test_burst_mode_drains_the_queue_and_exits(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let counter = Arc::new(AtomicU32::new(0));
    for _ in 0..3 {
        db.queue.enqueue(counts::job(())).await.unwrap().unwrap();
    }

    let worker = test_worker(db.queue.clone())
        .register_job(counts)
        .state(counter.clone())
        .burst(true)
        .dequeue_timeout(Duration::from_millis(400))
        .concurrency(2)
        .build()
        .unwrap();

    // No external cancellation: burst mode returns when drained.
    tokio::time::timeout(
        Duration::from_secs(15),
        worker.run_until(CancellationToken::new()),
    )
    .await
    .expect("burst worker should exit on its own")
    .unwrap();
    assert_eq!(counter.load(Ordering::SeqCst), 3);
}

//noinspection SqlNoDataSourceInspection
#[sqlx::test(migrations = "./migrations")]
async fn test_burst_waits_for_ready_job_when_row_is_locked(pool: PgPool) {
    let control = TestDb::new(pool_with_max(&pool, 2).await).await.queue;
    let db = TestDb::new(pool_with_max(&pool, 1).await).await;
    let handle = db.queue.enqueue(counts::job(())).await.unwrap().unwrap();
    let mut lock = control.pool().begin().await.unwrap();
    sqlx::query("SELECT id FROM pgqueue.jobs WHERE id = $1 FOR UPDATE")
        .bind(handle.id())
        .fetch_one(&mut *lock)
        .await
        .unwrap();

    let counter = Arc::new(AtomicU32::new(0));
    let worker = test_worker(db.queue.clone())
        .register_job(counts)
        .state(counter.clone())
        .burst(true)
        .dequeue_timeout(Duration::from_millis(200))
        .build()
        .unwrap();
    let run = tokio::spawn(worker.run_until(CancellationToken::new()));

    tokio::time::sleep(Duration::from_millis(400)).await;
    assert!(
        !run.is_finished(),
        "a locked ready row must not make a burst worker report a drain"
    );
    assert_eq!(handle.fetch_job().await.unwrap().status, JobStatus::Queued);

    lock.rollback().await.unwrap();
    tokio::time::timeout(Duration::from_secs(10), run)
        .await
        .expect("worker should process the row after its lock is released")
        .unwrap()
        .unwrap();
    assert_eq!(counter.load(Ordering::SeqCst), 1);
    assert_eq!(
        handle.fetch_job().await.unwrap().status,
        JobStatus::Complete
    );
}

//noinspection SqlNoDataSourceInspection
#[sqlx::test(migrations = "./migrations")]
async fn test_worker_skips_locked_ready_row_and_processes_next(pool: PgPool) {
    let control = TestDb::new(pool_with_max(&pool, 2).await).await.queue;
    let db = TestDb::new(pool_with_max(&pool, 1).await).await;
    let locked = db.queue.enqueue(counts::job(())).await.unwrap().unwrap();
    let next = db.queue.enqueue(counts::job(())).await.unwrap().unwrap();
    let mut lock = control.pool().begin().await.unwrap();
    sqlx::query("SELECT id FROM pgqueue.jobs WHERE id = $1 FOR UPDATE")
        .bind(locked.id())
        .fetch_one(&mut *lock)
        .await
        .unwrap();

    let counter = Arc::new(AtomicU32::new(0));
    let worker = test_worker(db.queue.clone())
        .register_job(counts)
        .state(counter.clone())
        .concurrency(1)
        .burst(true)
        .dequeue_timeout(Duration::from_millis(200))
        .build()
        .unwrap();
    let run = tokio::spawn(worker.run_until(CancellationToken::new()));

    wait_for_some(
        Duration::from_secs(2),
        Duration::from_millis(10),
        "worker did not skip the locked row",
        || {
            let counter = counter.clone();
            let next = next.clone();
            async move {
                (counter.load(Ordering::SeqCst) == 1
                    && next.fetch_job().await.ok()?.status == JobStatus::Complete)
                    .then_some(())
            }
        },
    )
    .await;
    assert_eq!(locked.fetch_job().await.unwrap().status, JobStatus::Queued);
    assert_eq!(next.fetch_job().await.unwrap().status, JobStatus::Complete);
    assert!(!run.is_finished(), "the locked row is still ready");

    lock.rollback().await.unwrap();
    tokio::time::timeout(Duration::from_secs(10), run)
        .await
        .expect("worker should process the locked row after release")
        .unwrap()
        .unwrap();
    assert_eq!(counter.load(Ordering::SeqCst), 2);
    assert_eq!(
        locked.fetch_job().await.unwrap().status,
        JobStatus::Complete
    );
}

//noinspection SqlNoDataSourceInspection
#[sqlx::test(migrations = "./migrations")]
async fn test_burst_does_not_drain_when_worker_intake_is_closed(pool: PgPool) {
    let control = TestDb::new(pool_with_max(&pool, 2).await).await.queue;
    let db = TestDb::new(pool_with_max(&pool, 1).await).await;
    let handle = db.queue.enqueue(counts::job(())).await.unwrap().unwrap();
    // Holding the only ready row keeps the worker's first fetch empty until the
    // test has closed its intake lease.
    let mut lock = control.pool().begin().await.unwrap();
    sqlx::query("SELECT id FROM pgqueue.jobs WHERE id = $1 FOR UPDATE")
        .bind(handle.id())
        .fetch_one(&mut *lock)
        .await
        .unwrap();
    let counter = Arc::new(AtomicU32::new(0));
    let worker = test_worker(db.queue.clone())
        .register_job(counts)
        .state(counter.clone())
        .timers(WorkerTimers {
            worker_info: Duration::from_secs(10),
            ..test_timers()
        })
        .burst(true)
        .dequeue_timeout(Duration::from_millis(200))
        .build()
        .unwrap();
    let worker_id = worker.id();
    let run = tokio::spawn(worker.run_until(CancellationToken::new()));

    wait_for_some(
        Duration::from_secs(5),
        Duration::from_millis(10),
        "worker did not start",
        || async {
            control
                .info()
                .await
                .unwrap()
                .workers
                .iter()
                .any(|worker| worker.id == worker_id)
                .then_some(())
        },
    )
    .await;
    sqlx::query(
        "UPDATE pgqueue.workers SET accepting = false, expires_at = now() - interval '1 second' WHERE id = $1",
    )
    .bind(worker_id)
    .execute(control.pool())
    .await
    .unwrap();
    lock.rollback().await.unwrap();

    tokio::time::sleep(Duration::from_millis(900)).await;
    assert!(
        !run.is_finished(),
        "an intake-gated empty result must not satisfy burst drain"
    );
    assert_eq!(handle.fetch_job().await.unwrap().status, JobStatus::Queued);

    control
        .write_worker_info(worker_id, json!({}), None, Duration::from_secs(30))
        .await
        .unwrap();
    tokio::time::timeout(Duration::from_secs(10), run)
        .await
        .expect("worker should continue after its intake lease is restored")
        .unwrap()
        .unwrap();
    assert_eq!(counter.load(Ordering::SeqCst), 1);
    assert_eq!(
        handle.fetch_job().await.unwrap().status,
        JobStatus::Complete
    );
}

/// The claim uses `FOR UPDATE SKIP LOCKED` and the availability probe does not,
/// so a `queued`, due, name-matching row held under a row lock by an unrelated
/// open transaction reports work that no claim can ever take. The fill loop's
/// "empty batch but work is available" arm only backed off, capped at
/// `DEQUEUE_RETRY_MAX_MS` (100 ms), and never broke out — so every idle worker in
/// the fleet was pinned there issuing a claim *and* a probe roughly every 50 ms,
/// ignoring `poll_interval` entirely, for as long as the lock was held. Measured
/// before the fix at 45 claims + 45 probes in 2 s against the ~2 a one-second
/// poll interval implies, per worker.
//noinspection SqlNoDataSourceInspection
#[sqlx::test(migrations = "./migrations")]
async fn test_idle_worker_polls_at_its_poll_interval_while_a_ready_row_is_locked(pool: PgPool) {
    let control = TestDb::new(pool_with_max(&pool, 2).await).await.queue;
    let db = TestDb::new(pool_with_max(&pool, 2).await).await;
    let Some(mut stats) = Stats::new(&db.database).await else {
        return;
    };
    let handle = db.queue.enqueue(counts::job(())).await.unwrap().unwrap();
    let mut lock = control.pool().begin().await.unwrap();
    sqlx::query("SELECT id FROM pgqueue.jobs WHERE id = $1 FOR UPDATE")
        .bind(handle.id())
        .fetch_one(&mut *lock)
        .await
        .unwrap();

    let counter = Arc::new(AtomicU32::new(0));
    // Continuous, not burst: `poll_interval` is the whole contract here, and
    // `WorkerFetch::Drained` is unreachable without `dequeue_timeout` anyway.
    let worker = test_worker(db.queue.clone())
        .register_job(counts)
        .state(counter.clone())
        .timers(WorkerTimers {
            worker_info: Duration::from_secs(10),
            schedule: Duration::from_secs(10),
            ..test_timers()
        })
        .poll_interval(Duration::from_secs(1))
        .build()
        .unwrap();
    let shutdown = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));

    // Let the startup ramp finish before measuring, so the window covers the
    // steady state the fix is about rather than the deliberate initial backoff.
    tokio::time::sleep(Duration::from_millis(700)).await;
    let claims = stats.since_now(DEQUEUE_CLAIM).await;
    let probes = stats.since_now(DEQUEUE_PROBE).await;
    tokio::time::sleep(Duration::from_secs(2)).await;
    let claims = stats.delta(&claims).await;
    let probes = stats.delta(&probes).await;

    // Two seconds of a one-second poll interval is ~2 passes. The pre-fix loop
    // measured 45; anything in double digits means the backoff is still driving
    // the rate instead of `poll_interval`.
    assert!(
        (1..=8).contains(&claims),
        "an idle worker issued {claims} claims in 2s at a 1s poll interval"
    );
    assert!(
        probes <= 8,
        "an idle worker issued {probes} availability probes in 2s at a 1s poll interval"
    );
    assert_eq!(handle.fetch_job().await.unwrap().status, JobStatus::Queued);

    // Backing off must not mean giving up: the row is still claimed promptly
    // once its lock is released.
    lock.rollback().await.unwrap();
    wait_terminal(&db.queue, handle.id(), 10).await;
    assert_eq!(counter.load(Ordering::SeqCst), 1);
    shutdown.cancel();
    tokio::time::timeout(Duration::from_secs(10), run)
        .await
        .expect("worker did not stop")
        .unwrap()
        .unwrap();
}

#[sqlx::test(migrations = "./migrations")]
async fn test_max_burst_jobs_caps_processing_even_under_concurrency(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let counter = Arc::new(AtomicU32::new(0));
    for _ in 0..10 {
        db.queue.enqueue(counts::job(())).await.unwrap().unwrap();
    }

    // Ten processors race a cap of 2: the budget must hold exactly.
    let worker = test_worker(db.queue.clone())
        .register_job(counts)
        .state(counter.clone())
        .burst(true)
        .dequeue_timeout(Duration::from_millis(400))
        .max_burst_jobs(2)
        .concurrency(10)
        .build()
        .unwrap();

    tokio::time::timeout(
        Duration::from_secs(15),
        worker.run_until(CancellationToken::new()),
    )
    .await
    .expect("capped burst worker should exit")
    .unwrap();
    assert_eq!(counter.load(Ordering::SeqCst), 2, "cap must hold exactly");
    assert_eq!(
        db.queue.counts().await.unwrap().queued,
        8,
        "remaining jobs left untouched"
    );
}

/// One sweep tick drains far more than four full batches. The tick interval is
/// a minute, so nothing below can be finished by a *second* tick — but the
/// drain inside that tick is also bounded by `MAX_SWEEP_DRAIN_TIME` (one
/// second), and every other loop in this worker competes for the same pool
/// while it runs. None of them has anything to do here, so they are slowed to a
/// minute and the drain gets the pool to itself. The poll window is generous
/// for the same reason and gives nothing away: with a sixty second tick, a
/// drain observed at any point inside the window is still that first tick's.
#[sqlx::test(migrations = "./migrations")]
async fn test_sweep_loop_drains_more_than_four_full_batches_per_tick(pool: PgPool) {
    let db = TestDb::with(pool.clone(), |builder| builder.sweep_batch_size(1)).await;
    sqlx::query(
        r#"
        INSERT INTO pgqueue.jobs (
            queue, name, payload, status, completed_at, expires_at
        )
        SELECT $1, 'expired-worker-batch', 'null'::jsonb, 'complete', now(),
               now() - interval '1 second'
        FROM generate_series(1, 5)
        "#,
    )
    .bind(db.queue.name())
    .execute(db.queue.pool())
    .await
    .unwrap();

    let quiet = Duration::from_secs(60);
    let worker = test_worker(db.queue.clone())
        .register_job(always_fails)
        .poll_interval(quiet)
        .timers(WorkerTimers {
            sweep: quiet,
            abort: quiet,
            schedule: quiet,
            worker_info: quiet,
        })
        .build()
        .unwrap();
    let shutdown = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));

    wait_until(
        Duration::from_secs(20),
        Duration::from_millis(20),
        "worker did not drain all expired sweep batches on its first tick",
        || async {
            sqlx::query_scalar::<_, i64>(
                "SELECT count(*) FROM pgqueue.jobs WHERE queue = $1 AND name = 'expired-worker-batch'",
            )
            .bind(db.queue.name())
            .fetch_one(db.queue.pool())
            .await
            .unwrap()
                == 0
        },
    )
    .await;

    shutdown.cancel();
    run.await.unwrap().unwrap();
}

#[sqlx::test(migrations = "./migrations")]
async fn test_live_worker_retries_a_sweeper_cancelled_attempt(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let attempts = Arc::new(AtomicU32::new(0));
    let handle = db
        .queue
        .enqueue(swept_once::job(()))
        .await
        .unwrap()
        .unwrap();
    // Hold sweep leadership outside the worker so phase 2 cannot race the live
    // worker's abort poll and hide a terminal-abort regression.
    let mut sweeper = db.queue.sweeper();
    assert!(sweeper.sweep().await.unwrap().leader);
    let worker = test_worker(db.queue.clone())
        .register_job(swept_once)
        .state(attempts.clone())
        .timers(WorkerTimers {
            abort: Duration::from_millis(20),
            sweep: Duration::from_secs(60),
            ..test_timers()
        })
        .concurrency(1)
        .build()
        .unwrap();
    let token = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(token.clone()));

    wait_status(&db.queue, handle.id(), JobStatus::Running, 5).await;
    backdate_job_liveness(&db, handle.id()).await;
    let report = sweeper.sweep().await.unwrap();
    assert_eq!(report.cancelling, vec![handle.id()]);
    let row = wait_terminal(&db.queue, handle.id(), 10).await;
    assert_eq!(row.status, JobStatus::Complete);
    assert_eq!(row.attempts, 2, "the swept first attempt must be retried");
    assert_eq!(attempts.load(Ordering::SeqCst), 2);

    token.cancel();
    run.await.unwrap().unwrap();
    sweeper.release().await;
}

#[sqlx::test(migrations = "./migrations")]
async fn test_abort_loop_cancels_handler_when_swept_row_is_deleted_before_observation(
    pool: PgPool,
) {
    let db = TestDb::with(pool.clone(), |builder| builder.sweep_batch_size(1)).await;
    let (started_tx, mut started_rx) = tokio::sync::mpsc::unbounded_channel();
    let (dropped_tx, mut dropped_rx) = tokio::sync::mpsc::unbounded_channel();
    let completed = Arc::new(AtomicU32::new(0));
    let worker = test_worker(db.queue.clone())
        .register_job(waits_after_row_deletion)
        .register_job(counts)
        .state(MissingRowProbe {
            started: started_tx,
            dropped: dropped_tx,
        })
        .state(completed.clone())
        .timers(WorkerTimers {
            abort: Duration::from_millis(500),
            sweep: Duration::from_millis(25),
            ..test_timers()
        })
        .concurrency(1)
        .build()
        .unwrap();
    let shutdown = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));

    for (tag, retention) in [
        (1, JobRetention::DeleteImmediately),
        (2, JobRetention::For(Duration::from_millis(1))),
    ] {
        let handle = db
            .queue
            .enqueue(waits_after_row_deletion::job(tag).retention(retention))
            .await
            .unwrap()
            .unwrap();
        assert_eq!(
            tokio::time::timeout(Duration::from_secs(3), started_rx.recv())
                .await
                .unwrap(),
            Some(tag)
        );
        wait_until(
            Duration::from_secs(3),
            Duration::from_millis(10),
            "sweeper did not delete the stuck job row",
            || async { db.queue.fetch_job(handle.id()).await.unwrap().is_none() },
        )
        .await;
        assert_eq!(
            tokio::time::timeout(Duration::from_secs(2), dropped_rx.recv())
                .await
                .unwrap(),
            Some(tag),
            "the missing-row abort poll did not cancel the handler"
        );
    }

    let follow_up = db.queue.enqueue(counts::job(())).await.unwrap().unwrap();
    assert_eq!(
        wait_terminal(&db.queue, follow_up.id(), 3).await.status,
        JobStatus::Complete,
        "deleted attempts kept the worker's only processor slot"
    );
    assert_eq!(completed.load(Ordering::SeqCst), 1);

    shutdown.cancel();
    run.await.unwrap().unwrap();
}

#[sqlx::test(migrations = "./migrations")]
async fn test_worker_heartbeat_reports_only_jobs_processed_by_that_worker(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let counter = Arc::new(AtomicU32::new(0));
    let complete_worker = test_worker(db.queue.clone())
        .register_job(counts)
        .state(counter)
        .build()
        .unwrap();
    let failed_worker = test_worker(db.queue.clone())
        .register_job(always_fails)
        .build()
        .unwrap();
    let complete_worker_id = complete_worker.id();
    let failed_worker_id = failed_worker.id();

    let complete_job = db.queue.enqueue(counts::job(())).await.unwrap().unwrap();
    let failed_job = db
        .queue
        .enqueue(always_fails::job(()))
        .await
        .unwrap()
        .unwrap();

    let complete_token = CancellationToken::new();
    let failed_token = CancellationToken::new();
    let complete_run = tokio::spawn(complete_worker.run_until(complete_token.clone()));
    let failed_run = tokio::spawn(failed_worker.run_until(failed_token.clone()));

    wait_terminal(&db.queue, complete_job.id(), 5).await;
    wait_terminal(&db.queue, failed_job.id(), 5).await;

    let deadline = tokio::time::Instant::now() + Duration::from_secs(5);
    loop {
        let info = db.queue.info().await.unwrap();
        let complete_stats = info
            .workers
            .iter()
            .find(|worker| worker.id == complete_worker_id)
            .map(|worker| &worker.stats);
        let failed_stats = info
            .workers
            .iter()
            .find(|worker| worker.id == failed_worker_id)
            .map(|worker| &worker.stats);
        if complete_stats.is_some_and(|stats| {
            stats["complete"] == 1
                && stats["failed"] == 0
                && stats["retried"] == 0
                && stats["aborted"] == 0
        }) && failed_stats.is_some_and(|stats| {
            stats["complete"] == 0
                && stats["failed"] == 1
                && stats["retried"] == 1
                && stats["aborted"] == 0
        }) {
            break;
        }
        assert!(
            tokio::time::Instant::now() < deadline,
            "worker heartbeats did not report isolated counters: {:?}",
            info.workers
        );
        tokio::time::sleep(Duration::from_millis(25)).await;
    }

    let aggregate = db.queue.stats();
    assert_eq!(aggregate.complete, 1);
    assert_eq!(aggregate.failed, 1);
    assert_eq!(aggregate.retried, 1);

    complete_token.cancel();
    failed_token.cancel();
    complete_run.await.unwrap().unwrap();
    failed_run.await.unwrap().unwrap();
}

#[sqlx::test(migrations = "./migrations")]
async fn test_worker_lease_stays_live_during_processor_shutdown_grace(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let probe = ShutdownLeaseProbe {
        started: Arc::new(tokio::sync::Notify::new()),
    };
    db.queue
        .enqueue(holds_during_shutdown::job(()))
        .await
        .unwrap()
        .unwrap();
    let worker = test_worker(db.queue.clone())
        .register_job(holds_during_shutdown)
        .state(probe.clone())
        // Coverage instrumentation and the parallel Postgres suite can delay
        // the intake-close observation; leave enough grace to inspect the
        // still-live lease before the processor is cancelled.
        .shutdown_grace(Duration::from_secs(2))
        .build()
        .unwrap();
    let worker_id = worker.id();
    let token = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(token.clone()));
    tokio::time::timeout(Duration::from_secs(5), probe.started.notified())
        .await
        .expect("handler did not claim the job");

    token.cancel();
    wait_for_worker_intake_closed(&db, worker_id).await;
    assert!(
        db.queue
            .info()
            .await
            .unwrap()
            .workers
            .iter()
            .any(|worker| worker.id == worker_id),
        "the lease expired while a processor still owned work"
    );
    run.await.unwrap().unwrap();
    assert!(
        !db.queue
            .info()
            .await
            .unwrap()
            .workers
            .iter()
            .any(|worker| worker.id == worker_id)
    );
}

#[sqlx::test(migrations = "./migrations")]
async fn test_worker_builder_rejects_invalid_configuration(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;

    let err = Worker::builder(db.queue.clone()).build().unwrap_err();
    assert!(err.to_string().contains("no jobs registered"), "{err}");

    let err = Worker::builder(db.queue.clone())
        .register_job(always_fails)
        .burst(true)
        .build()
        .unwrap_err();
    assert!(err.to_string().contains("dequeue_timeout"), "{err}");

    let err = Worker::builder(db.queue.clone())
        .register_job(always_fails)
        .max_burst_jobs(5)
        .build()
        .unwrap_err();
    assert!(err.to_string().contains("max_burst_jobs requires"), "{err}");

    Worker::builder(db.queue.clone())
        .register_job(always_fails)
        .register_job(always_fails)
        .build()
        .unwrap();

    let err = Worker::builder(db.queue.clone())
        .register_job(registration_collision_a)
        .register_job(registration_collision_b)
        .build()
        .unwrap_err();
    assert!(err.to_string().contains("multiple job types"), "{err}");

    Worker::builder(db.queue.clone())
        .schedule_cron("0 * * * *", counts::job(()))
        .build()
        .unwrap();

    let err = Worker::builder(db.queue.clone())
        .schedule_cron("not a cron", counts::job(()))
        .build()
        .unwrap_err();
    assert!(err.to_string().contains("invalid cron expression"), "{err}");

    let err = Worker::builder(db.queue.clone())
        .schedule_cron("0 * * * *", counts::job(()))
        .schedule_cron("30 * * * *", counts::job(()))
        .build()
        .unwrap_err();
    assert!(err.to_string().contains("cron dedupe key"), "{err}");

    let err = Worker::builder(db.queue.clone())
        .register_job(always_fails)
        .timers(WorkerTimers {
            abort: Duration::ZERO,
            ..WorkerTimers::default()
        })
        .build()
        .unwrap_err();
    assert!(err.to_string().contains("abort timer"), "{err}");

    let err = Worker::builder(db.queue.clone())
        .register_job(always_fails)
        .poll_interval(Duration::ZERO)
        .build()
        .unwrap_err();
    assert!(err.to_string().contains("poll interval"), "{err}");

    let err = Worker::builder(db.queue.clone())
        .register_job(always_fails)
        .abort_grace(Duration::MAX)
        .build()
        .unwrap_err();
    assert!(err.to_string().contains("abort grace"), "{err}");

    let err = Worker::builder(db.queue.clone())
        .register_job(always_fails)
        .burst(true)
        .dequeue_timeout(Duration::ZERO)
        .build()
        .unwrap_err();
    assert!(err.to_string().contains("dequeue timeout"), "{err}");

    if usize::BITS > i64::BITS {
        let err = Worker::builder(db.queue.clone())
            .register_job(always_fails)
            .concurrency(usize::MAX)
            .build()
            .unwrap_err();
        assert!(err.to_string().contains("concurrency"), "{err}");
    }
}

#[sqlx::test(migrations = "./migrations")]
async fn test_worker_builder_run_until_rejects_invalid_configuration(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let error = Worker::builder(db.queue)
        .run_until(CancellationToken::new())
        .await
        .unwrap_err();

    assert!(error.to_string().contains("no jobs registered"), "{error}");
}

#[derive(Clone)]
struct DatabaseLossProbe {
    started: Arc<tokio::sync::Notify>,
    release: Arc<tokio::sync::Notify>,
}

#[pgqueue::job]
async fn quick_nap(_: (), state: JobState<DatabaseLossProbe>) -> anyhow::Result<()> {
    state.0.started.notify_one();
    state.0.release.notified().await;
    Ok(())
}

#[sqlx::test(migrations = "./migrations")]
async fn test_abort_health_recovers_when_no_attempts_remain(pool: PgPool) {
    let control = TestDb::new(pool.clone()).await;
    let worker_pool = sqlx::postgres::PgPoolOptions::new()
        .max_connections(5)
        .connect_with(
            pool.connect_options()
                .as_ref()
                .clone()
                .options([("lock_timeout", "100ms")]),
        )
        .await
        .unwrap();
    let worker_db = TestDb::new(worker_pool).await;
    let probe = DatabaseLossProbe {
        started: Arc::new(tokio::sync::Notify::new()),
        release: Arc::new(tokio::sync::Notify::new()),
    };
    control
        .queue
        .enqueue(quick_nap::job(()))
        .await
        .unwrap()
        .unwrap();
    let worker = test_worker(worker_db.queue.clone())
        .register_job(quick_nap)
        .state(probe.clone())
        .timers(WorkerTimers {
            abort: Duration::from_secs(2),
            ..test_timers()
        })
        .concurrency(1)
        .build()
        .unwrap();
    let health = worker.health();
    let shutdown = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));
    tokio::time::timeout(Duration::from_secs(5), probe.started.notified())
        .await
        .expect("job did not start");

    let mut lock = control.queue.pool().begin().await.unwrap();
    sqlx::query("LOCK TABLE pgqueue.jobs IN ACCESS EXCLUSIVE MODE")
        .execute(&mut *lock)
        .await
        .unwrap();
    wait_until(
        Duration::from_secs(5),
        Duration::from_millis(10),
        "abort poll failure was not reported",
        || async {
            health
                .snapshot()
                .failures
                .iter()
                .any(|failure| failure.component == WorkerComponent::Abort)
        },
    )
    .await;

    lock.rollback().await.unwrap();
    probe.release.notify_one();
    wait_until(
        Duration::from_secs(5),
        Duration::from_millis(10),
        "abort health did not recover after the attempt finished",
        || async {
            !health
                .snapshot()
                .failures
                .iter()
                .any(|failure| failure.component == WorkerComponent::Abort)
        },
    )
    .await;

    shutdown.cancel();
    run.await.unwrap().unwrap();
}

#[pgqueue::job(max_attempts = 2)]
async fn fails_after_release(
    _: (),
    state: JobState<DatabaseLossProbe>,
    ctx: JobContext,
) -> anyhow::Result<()> {
    if ctx.attempt() == 1 {
        state.0.started.notify_one();
        state.0.release.notified().await;
    }
    anyhow::bail!("attempt failed")
}

async fn fail_first_running_transition(pool: &PgPool) {
    sqlx::raw_sql(
        r#"
        CREATE SEQUENCE pgqueue.finalization_failures;
        CREATE FUNCTION pgqueue.fail_first_finalization() RETURNS trigger
        LANGUAGE plpgsql AS $$
        BEGIN
            IF nextval('pgqueue.finalization_failures') = 1 THEN
                RAISE EXCEPTION 'injected transient finalization failure';
            END IF;
            RETURN NEW;
        END
        $$;
        CREATE TRIGGER fail_first_finalization
        BEFORE UPDATE ON pgqueue.jobs
        FOR EACH ROW
        WHEN (OLD.status = 'running' AND NEW.status IS DISTINCT FROM OLD.status)
        EXECUTE FUNCTION pgqueue.fail_first_finalization();
        "#,
    )
    .execute(pool)
    .await
    .expect("install transient finalization failure");
}

#[sqlx::test(migrations = "./migrations")]
async fn test_worker_retries_a_transient_finish_failure(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let handle = db.queue.enqueue(quick_nap::job(())).await.unwrap().unwrap();
    let probe = DatabaseLossProbe {
        started: Arc::new(tokio::sync::Notify::new()),
        release: Arc::new(tokio::sync::Notify::new()),
    };
    let worker = test_worker(db.queue.clone())
        .register_job(quick_nap)
        .state(probe.clone())
        .build()
        .unwrap();
    let token = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(token.clone()));

    probe.started.notified().await;
    fail_first_running_transition(&pool).await;
    probe.release.notify_one();

    let row = wait_terminal(&db.queue, handle.id(), 10).await;
    assert_eq!(row.status, JobStatus::Complete);
    assert_eq!(row.attempts, 1);

    token.cancel();
    run.await.unwrap().unwrap();
}

#[sqlx::test(migrations = "./migrations")]
async fn test_worker_retries_a_transient_retry_failure(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let handle = db
        .queue
        .enqueue(fails_after_release::job(()))
        .await
        .unwrap()
        .unwrap();
    let probe = DatabaseLossProbe {
        started: Arc::new(tokio::sync::Notify::new()),
        release: Arc::new(tokio::sync::Notify::new()),
    };
    let worker = test_worker(db.queue.clone())
        .register_job(fails_after_release)
        .state(probe.clone())
        .build()
        .unwrap();
    let token = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(token.clone()));

    probe.started.notified().await;
    fail_first_running_transition(&pool).await;
    probe.release.notify_one();

    let row = wait_terminal(&db.queue, handle.id(), 10).await;
    assert_eq!(row.status, JobStatus::Failed);
    assert_eq!(row.attempts, 2);
    assert_eq!(row.error.as_deref(), Some("failed: attempt failed"));

    token.cancel();
    run.await.unwrap().unwrap();
}

/// Drops the schema from a connection of its own, retrying while the worker
/// still holds the locks it needs.
///
/// Issuing it through the worker's pool made it compete with the very
/// statements it is trying to break — the drop needs `ACCESS EXCLUSIVE` on
/// tables a live worker is reading — and an unbounded wait for that lock is
/// what failed the test outright when it lost the race. A bounded wait that is
/// retried lets the worker's statements through in between, so the schema goes
/// once there is a gap, and any error other than that contention still fails
/// the test.
async fn drop_schema_outside_the_pool(db: &TestDb) {
    use sqlx::Connection;

    let mut conn = sqlx::PgConnection::connect_with(db.pool.connect_options().as_ref())
        .await
        .expect("connect for schema drop");
    sqlx::query("SET lock_timeout = '500ms'")
        .execute(&mut conn)
        .await
        .expect("bound the drop's lock wait");
    let deadline = tokio::time::Instant::now() + Duration::from_secs(30);
    loop {
        match sqlx::query("DROP SCHEMA pgqueue CASCADE")
            .execute(&mut conn)
            .await
        {
            Ok(_) => break,
            Err(error) => {
                let code = error
                    .as_database_error()
                    .and_then(|error| error.code())
                    .map(|code| code.to_string());
                // 55P03 lock_not_available, 40P01 deadlock_detected: both mean
                // the worker was mid-statement, which is exactly the state this
                // test creates on purpose.
                assert!(
                    matches!(code.as_deref(), Some("55P03" | "40P01")),
                    "dropping the schema failed for an unexpected reason: {error}"
                );
                assert!(
                    tokio::time::Instant::now() < deadline,
                    "the schema drop never won its lock against the worker"
                );
            }
        }
    }
    conn.close().await.expect("close schema drop connection");
}

#[sqlx::test(migrations = "./migrations")]
async fn test_worker_survives_the_database_disappearing(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    db.queue.enqueue(quick_nap::job(())).await.unwrap().unwrap();
    let probe = DatabaseLossProbe {
        started: Arc::new(tokio::sync::Notify::new()),
        release: Arc::new(tokio::sync::Notify::new()),
    };

    let worker = test_worker(db.queue.clone())
        .register_job(quick_nap)
        .state(probe.clone())
        .timers(WorkerTimers {
            abort: Duration::from_millis(50),
            schedule: Duration::from_millis(100),
            sweep: Duration::from_millis(200),
            worker_info: Duration::from_millis(100),
        })
        .concurrency(2)
        .build()
        .unwrap();
    let token = CancellationToken::new();
    let mut run = tokio::spawn(worker.run_until(token.clone()));

    // Wait until the nap job is mid-flight, then nuke the schema: dequeues,
    // abort polls, sweeps, heartbeats, and the job finalization all start
    // failing. The worker must log and keep running, never crash.
    tokio::time::timeout(Duration::from_secs(5), probe.started.notified())
        .await
        .expect("job did not start");
    drop_schema_outside_the_pool(&db).await;

    probe.release.notify_one();
    assert!(
        tokio::time::timeout(Duration::from_millis(500), &mut run)
            .await
            .is_err(),
        "worker must survive database loss"
    );

    token.cancel();
    run.await.unwrap().unwrap();
}

#[sqlx::test(migrations = "./migrations")]
async fn test_cron_with_unserializable_payload_fails_at_build(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let err = Worker::builder(db.queue.clone())
        .schedule_cron(
            "* * * * *",
            bad_payload::job([((1u32, 2u32), 3u32)].into_iter().collect()),
        )
        .build()
        .unwrap_err();
    assert!(matches!(err, Error::Serde(_)), "{err}");
}

/// JSON object keys must be strings; a tuple-keyed map cannot serialize.
#[pgqueue::job]
async fn bad_payload(_args: std::collections::HashMap<(u32, u32), u32>) -> anyhow::Result<()> {
    Ok(())
}

#[sqlx::test(migrations = "./migrations")]
#[ignore = "stress test"]
async fn test_dedupe_enqueue_accepts_one_winner_under_stress(pool: PgPool) {
    let db = TestDb::new(pool).await;
    for round in 0..100 {
        let key = format!("stress-dedupe-{round}");
        let mut tasks = Vec::new();
        for _ in 0..32 {
            let queue = db.queue.clone();
            let key = key.clone();
            tasks.push(tokio::spawn(async move {
                queue.enqueue(counts::job(()).dedupe_key(key)).await
            }));
        }
        let mut winners = 0;
        for task in tasks {
            if task.await.unwrap().unwrap().is_some() {
                winners += 1;
            }
        }
        assert_eq!(winners, 1, "round {round}");
    }
}

#[sqlx::test(migrations = "./migrations")]
#[ignore = "stress test"]
async fn test_shutdown_abort_retry_and_sweep_interoperate_under_stress(pool: PgPool) {
    let db = TestDb::new(pool).await;
    for _ in 0..25 {
        let handle = db.queue.enqueue(counts::job(())).await.unwrap().unwrap();
        // Hold the only ready row so the worker starts, finds nothing
        // claimable, and shuts down with the job still queued.
        let mut lock = db.queue.pool().begin().await.unwrap();
        sqlx::query("SELECT id FROM pgqueue.jobs WHERE id = $1 FOR UPDATE")
            .bind(handle.id())
            .fetch_one(&mut *lock)
            .await
            .unwrap();

        let counter = Arc::new(AtomicU32::new(0));
        let worker = test_worker(db.queue.clone())
            .register_job(counts)
            .state(counter.clone())
            .build()
            .unwrap();
        let token = CancellationToken::new();
        let run = tokio::spawn(worker.run_until(token.clone()));
        tokio::time::sleep(Duration::from_millis(100)).await;
        token.cancel();
        tokio::time::timeout(Duration::from_secs(1), run)
            .await
            .expect("contended worker shutdown timed out")
            .unwrap()
            .unwrap();
        lock.rollback().await.unwrap();

        assert!(handle.abort("stress abort").await.unwrap());
        assert!(
            db.queue
                .retry_job(handle.id(), "stress retry")
                .await
                .unwrap()
        );
        let mut sweeper = db.queue.sweeper();
        assert!(sweeper.sweep().await.unwrap().leader);
        sweeper.release().await;

        test_worker(db.queue.clone())
            .register_job(counts)
            .state(counter.clone())
            .burst(true)
            .dequeue_timeout(Duration::from_millis(400))
            .build()
            .unwrap()
            .run_until(CancellationToken::new())
            .await
            .unwrap();
        assert_eq!(counter.load(Ordering::SeqCst), 1);
    }
}

/// Blocks its runtime thread for a fixed time without ever yielding, like a
/// synchronous HTTP client or a CPU-bound loop inside a handler.
#[pgqueue::job(name = "thread_blocking", timeout_ms = 200, max_attempts = 1)]
async fn thread_blocking(_: ()) -> anyhow::Result<()> {
    std::thread::sleep(Duration::from_secs(3));
    Ok(())
}

/// `JoinHandle::abort` only lands at the next yield point, so an uncancellable
/// handler must not be able to hold the attempt — and its late `Ok` must not
/// overwrite the timeout that already fired.
///
/// Needs a multi-threaded runtime: on `#[sqlx::test]`'s current-thread one the
/// blocking handler would stall the test itself.
#[tokio::test(flavor = "multi_thread", worker_threads = 4)]
async fn test_worker_times_out_an_attempt_that_blocks_its_runtime_thread() {
    crate::init_tracing();
    let url = crate::fresh_database("blocking_timeout").await;
    let queue = Queue::connect(&url).await.unwrap();
    let id = queue
        .enqueue(thread_blocking::job(()))
        .await
        .unwrap()
        .job_id();

    let shutdown = CancellationToken::new();
    let worker = Worker::builder(queue.clone())
        .register_job(thread_blocking)
        .concurrency(1)
        .timers(crate::test_timers())
        .build()
        .unwrap();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));

    wait_until(
        Duration::from_secs(30),
        Duration::from_millis(20),
        "the blocked attempt was never finalized",
        || async {
            queue
                .fetch_job(id)
                .await
                .unwrap()
                .is_some_and(|row| row.status.is_terminal())
        },
    )
    .await;

    // The outcome is the signal, not the clock: waiting for the handle without
    // a bound would let the handler's eventual `Ok(())` land instead, marking a
    // job that ran 15x over its timeout `complete` with no error at all.
    let row = queue.fetch_job(id).await.unwrap().unwrap();
    assert_eq!(row.status, JobStatus::Failed);
    assert!(
        row.error.unwrap_or_default().contains("attempt exceeded"),
        "the timeout must win; a late handler success must not overwrite it"
    );

    shutdown.cancel();
    tokio::time::timeout(Duration::from_secs(10), run)
        .await
        .expect("worker shutdown must not wait for the blocking handler")
        .unwrap()
        .unwrap();
}

#[pgqueue::job(name = "listenerless", max_attempts = 1)]
async fn listenerless(_: ()) -> anyhow::Result<()> {
    Ok(())
}

/// The dedicated LISTEN connection lives outside the query pool, so it can be
/// refused while the pool is fine. Fetching already has a polling fallback, so
/// the worker must degrade instead of dying (which would be a crash loop).
#[tokio::test(flavor = "multi_thread", worker_threads = 4)]
async fn test_worker_processes_jobs_by_polling_when_the_listener_cannot_connect() {
    crate::init_tracing();
    let url = crate::fresh_database("listenerless").await;
    Queue::connect(&url).await.unwrap();
    // Warm a full pool, then revoke the role's right to open *new* connections.
    // Established connections keep working, so the queue stays usable while the
    // listener — which needs its own connection outside the pool — cannot start.
    let client_url = crate::limited_role_url(&url, -1).await;
    let pool = sqlx::postgres::PgPoolOptions::new()
        .min_connections(4)
        .max_connections(4)
        .connect(&client_url)
        .await
        .unwrap();
    crate::revoke_connect(&url, &client_url).await;
    let queue = pgqueue::Queue::builder(&client_url)
        .pool(pool)
        .migration_mode(pgqueue::MigrationMode::Skip)
        .connect()
        .await
        .unwrap();
    let id = queue.enqueue(listenerless::job(())).await.unwrap().job_id();

    let shutdown = CancellationToken::new();
    let worker = Worker::builder(queue.clone())
        .register_job(listenerless)
        .timers(crate::test_timers())
        .poll_interval(Duration::from_millis(50))
        .build()
        .unwrap();
    let health = worker.health();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));

    wait_until(
        Duration::from_secs(60),
        Duration::from_millis(50),
        "job was never processed by the polling fallback",
        || async {
            queue
                .fetch_job(id)
                .await
                .unwrap()
                .is_some_and(|row| row.status == JobStatus::Complete)
        },
    )
    .await;
    // Losing notifications is a real degradation, so it is reported as one.
    // Nothing orders the listener's failed connect against the poll loop that
    // completes the job, so the failure can land after the job does.
    wait_until(
        Duration::from_secs(60),
        Duration::from_millis(50),
        "notification failure was never reported",
        || async {
            health
                .snapshot()
                .failures
                .iter()
                .any(|failure| failure.component == WorkerComponent::Notification)
        },
    )
    .await;

    shutdown.cancel();
    // Shutdown wants connections this role is deliberately not allowed, so its
    // outcome is not what this test asserts.
    let _ = tokio::time::timeout(Duration::from_secs(30), run).await;
}

/// Burns CPU without reaching an `await`, so `JoinHandle::abort` cannot take
/// effect and the handler runs to completion after the deadline has fired.
fn spin_for(duration: Duration) {
    let deadline = std::time::Instant::now() + duration;
    while std::time::Instant::now() < deadline {
        std::hint::spin_loop();
    }
}

// ---------------------------------------------------------------------------
// The timeout arm must not invent an outcome the handler already produced
// ---------------------------------------------------------------------------

/// Counts handler bodies that ran all the way to their final statement.
#[derive(Clone)]
struct SideEffects(Arc<AtomicUsize>);

/// The last `await` resolves on the same instant as the attempt deadline, so
/// the biased select can take the timeout arm while this handler is already
/// running on another worker thread. Past that point it has no yield point
/// left, `abort()` cannot stop it, and it settles with a real error.
///
/// (Waking *earlier* does not exercise the race: while the handler holds a
/// runtime thread the select is never polled, so the task arm wins. Waking
/// *later* means `abort()` lands at a yield point and there is no outcome to
/// keep.) The counter is bumped immediately before returning, so it is exactly
/// how many attempts completed — which of them win the race depends on machine
/// load, but the invariant asserted below does not.
#[pgqueue::job(name = "repro_late_error", max_attempts = 1, timeout_ms = 200)]
async fn repro_late_error(_: (), state: JobState<SideEffects>) -> anyhow::Result<()> {
    tokio::time::sleep(Duration::from_millis(200)).await;
    spin_for(Duration::from_millis(50));
    state.0.0.fetch_add(1, Ordering::SeqCst);
    anyhow::bail!("payment gateway declined: card_expired")
}

#[tokio::test(flavor = "multi_thread", worker_threads = 4)]
async fn test_attempt_records_the_handler_error_when_it_settles_after_the_timeout() {
    crate::init_tracing();
    let url = crate::fresh_database("late_error").await;
    let queue = Queue::connect(&url).await.unwrap();
    let mut ids = Vec::new();
    for _ in 0..8 {
        ids.push(
            queue
                .enqueue(repro_late_error::job(()))
                .await
                .unwrap()
                .job_id(),
        );
    }

    let completions = Arc::new(AtomicUsize::new(0));
    let shutdown = CancellationToken::new();
    let worker = Worker::builder(queue.clone())
        .register_job(repro_late_error)
        .state(SideEffects(completions.clone()))
        // One at a time: a handler that is spinning starves this runtime, and
        // the race under test needs the worker's select to stay pollable.
        .concurrency(1)
        .timers(test_timers())
        .poll_interval(Duration::from_millis(50))
        .build()
        .unwrap();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));

    let mut errors = Vec::new();
    for id in ids {
        errors.push(
            wait_terminal(&queue, id, 30)
                .await
                .error
                .unwrap_or_default(),
        );
    }
    shutdown.cancel();
    let _ = tokio::time::timeout(Duration::from_secs(10), run).await;

    // Every attempt that ran to completion must have its own diagnosis
    // recorded; the rest were genuinely cancelled at a yield point and
    // correctly report the deadline. Replacing a completed handler's error with
    // a synthetic timeout would break this equality.
    let completed = completions.load(Ordering::SeqCst);
    let real = errors.iter().filter(|e| e.contains("card_expired")).count();
    assert_eq!(
        real, completed,
        "every completed attempt must record its own error; got {errors:?}"
    );
    assert!(
        completed > 0,
        "no attempt settled after its deadline, so the race went untested"
    );
}

/// Reaches the counter only by running to completion, so the count is proof the
/// attempt genuinely succeeded rather than timing out.
#[pgqueue::job(
    name = "repro_late_success",
    max_attempts = 2,
    timeout_ms = 200,
    retry_delay_ms = 0
)]
async fn repro_late_success(_: (), state: JobState<SideEffects>) -> anyhow::Result<()> {
    tokio::time::sleep(Duration::from_millis(200)).await;
    spin_for(Duration::from_millis(50));
    state.0.0.fetch_add(1, Ordering::SeqCst);
    Ok(())
}

/// A handler that overran its deadline still failed the attempt — the timeout
/// is a real limit, not advisory — but it must not be reported as a timeout
/// twice over: the attempt is retried at most as far as `max_attempts`, and the
/// recorded reason names the deadline.
#[tokio::test(flavor = "multi_thread", worker_threads = 4)]
async fn test_attempt_that_overruns_its_timeout_is_not_retried_past_max_attempts() {
    crate::init_tracing();
    let url = crate::fresh_database("late_success").await;
    let queue = Queue::connect(&url).await.unwrap();
    let id = queue
        .enqueue(repro_late_success::job(()))
        .await
        .unwrap()
        .job_id();

    let effects = Arc::new(AtomicUsize::new(0));
    let shutdown = CancellationToken::new();
    let worker = Worker::builder(queue.clone())
        .register_job(repro_late_success)
        .state(SideEffects(effects.clone()))
        .timers(test_timers())
        .poll_interval(Duration::from_millis(50))
        .build()
        .unwrap();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));

    let row = wait_terminal(&queue, id, 30).await;
    shutdown.cancel();
    let _ = tokio::time::timeout(Duration::from_secs(10), run).await;

    let error = row.error.unwrap_or_default();
    assert_eq!(row.status, JobStatus::Failed, "{error}");
    assert!(error.contains("attempt exceeded"), "{error:?}");
    assert_eq!(row.attempts, 2, "the attempt budget must still be honoured");
    assert!(
        effects.load(Ordering::SeqCst) <= 2,
        "a late success must not run more attempts than the budget allows"
    );
}

// ---------------------------------------------------------------------------
// A transient reconciliation failure must not disable a cron permanently
// ---------------------------------------------------------------------------

async fn grant_connect(admin: &str, client_url: &str) {
    let (_, db_name) = admin.rsplit_once('/').unwrap();
    let role = client_url
        .split_once("://")
        .and_then(|(_, rest)| rest.split_once(':'))
        .unwrap()
        .0
        .to_string();
    let mut conn = PgConnection::connect(admin).await.unwrap();
    sqlx::raw_sql(sqlx::AssertSqlSafe(format!(
        r#"GRANT CONNECT ON DATABASE "{db_name}" TO "{role}";
           GRANT CONNECT ON DATABASE "{db_name}" TO PUBLIC;"#
    )))
    .execute(&mut conn)
    .await
    .unwrap();
    conn.close().await.unwrap();
}

/// Warms a full pool for a role, then withdraws its right to open *new*
/// connections. Established connections keep working, so the query pool stays
/// healthy while the listener — which needs its own connection outside the
/// pool — cannot start.
async fn queue_without_a_listener(tag: &str) -> (String, String, Queue) {
    let url = crate::fresh_database(tag).await;
    Queue::connect(&url).await.unwrap();
    let client_url = crate::limited_role_url(&url, -1).await;
    let pool = sqlx::postgres::PgPoolOptions::new()
        .min_connections(4)
        .max_connections(4)
        .connect(&client_url)
        .await
        .unwrap();
    crate::revoke_connect(&url, &client_url).await;
    let queue = Queue::builder(&client_url)
        .pool(pool)
        .migration_mode(pgqueue::MigrationMode::Skip)
        .connect()
        .await
        .unwrap();
    (url, client_url, queue)
}

#[pgqueue::job(name = "repro_noop", max_attempts = 1)]
async fn repro_noop(_: ()) -> anyhow::Result<()> {
    Ok(())
}

/// The listener is refused at startup, so the worker falls back to polling and
/// reports the degradation. Once the database stops refusing connections it
/// must reconnect on its own: a one-second refusal that permanently downgraded
/// a worker to polling — and pinned it Degraded — would need an operator to
/// notice and restart it.
#[tokio::test(flavor = "multi_thread", worker_threads = 4)]
async fn test_notification_listener_recovers_after_a_refused_start() {
    crate::init_tracing();
    let (url, client_url, queue) = queue_without_a_listener("listener_restart").await;

    let shutdown = CancellationToken::new();
    let worker = Worker::builder(queue.clone())
        .register_job(repro_noop)
        .timers(test_timers())
        .poll_interval(Duration::from_millis(50))
        .build()
        .unwrap();
    let health = worker.health();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));

    wait_until(
        Duration::from_secs(60),
        Duration::from_millis(50),
        "notification listener never reported a failure",
        || async {
            health
                .snapshot()
                .failures
                .iter()
                .any(|failure| failure.component == WorkerComponent::Notification)
        },
    )
    .await;

    grant_connect(&url, &client_url).await;

    let admin = sqlx::PgPool::connect(&url).await.unwrap();
    wait_until(
        Duration::from_secs(30),
        Duration::from_millis(100),
        "the listener never reconnected after the database healed",
        || async {
            sqlx::query_scalar::<_, i64>(
                "SELECT count(*) FROM pg_stat_activity
                 WHERE datname = current_database() AND query LIKE 'LISTEN %'",
            )
            .fetch_one(&admin)
            .await
            .unwrap()
                > 0
        },
    )
    .await;
    wait_until(
        Duration::from_secs(30),
        Duration::from_millis(100),
        "notification health never recovered",
        || async { health.snapshot().status == WorkerHealthStatus::Ready },
    )
    .await;

    shutdown.cancel();
    let _ = tokio::time::timeout(Duration::from_secs(30), run).await;
}

/// A sustained outage must not be retried at a fixed cadence: the reconnect
/// delay doubles per failed attempt, so a long outage costs one connection
/// attempt (and one warn) per capped interval — and the listener must still
/// reconnect on its own once the outage ends. Only lower bounds are asserted:
/// doubling from 500ms puts at least three seconds of sleep between the first
/// and fourth failures the health watch reports, where the old fixed cadence
/// spaced them 1.5s apart, and a loaded machine only widens the gaps.
#[tokio::test(flavor = "multi_thread", worker_threads = 4)]
async fn test_notification_listener_reconnect_backs_off_during_an_outage() {
    crate::init_tracing();
    let (url, client_url, queue) = queue_without_a_listener("listener_backoff").await;

    // Subscribing starts the listener, whose every failed attempt re-sends on
    // the health watch; gaps are >= 500ms, so none are coalesced away.
    let mut health = pgqueue::__test_support::listener_health(&queue);
    let started = tokio::time::Instant::now();
    let mut failures = Vec::new();
    while failures.len() < 4 {
        tokio::time::timeout(Duration::from_secs(30), health.changed())
            .await
            .expect("listener health stalled during the outage")
            .expect("listener dropped its health channel");
        if health.borrow_and_update().is_some() {
            failures.push(started.elapsed());
        }
    }
    let spread = failures[3] - failures[0];
    assert!(
        spread >= Duration::from_secs(3),
        "four reconnect failures within {spread:?} imply a fixed retry cadence"
    );

    // Ending the outage must heal the listener within one capped delay.
    grant_connect(&url, &client_url).await;
    tokio::time::timeout(Duration::from_secs(15), async {
        while health.borrow_and_update().is_some() {
            health
                .changed()
                .await
                .expect("listener dropped its health channel");
        }
    })
    .await
    .expect("the listener never reconnected after the outage ended");
}

/// The backend pid holding the single-key advisory lock `key` in the database
/// `pool` is connected to — the queue's current sweep leader, if any.
async fn sweep_leader_pid(pool: &PgPool, key: i64) -> Option<i32> {
    let class_id = i64::from((key as u64 >> 32) as u32);
    let object_id = i64::from(key as u64 as u32);
    sqlx::query_scalar::<_, i32>(
        "SELECT pid FROM pg_locks
         WHERE locktype = 'advisory' AND granted AND objsubid = 1
           AND classid::bigint = $1 AND objid::bigint = $2
           AND database = (SELECT oid FROM pg_database WHERE datname = current_database())",
    )
    .bind(class_id)
    .bind(object_id)
    .fetch_optional(pool)
    .await
    .expect("inspect sweep leadership lock")
}

/// Sweep leadership is revalidated by a liveness probe on the dedicated
/// leadership connection, not by sweep progress — and the two can diverge: a
/// firewall or NAT change that blocks new flows leaves established sessions
/// working, so the leader's *pooled* connections (which sweep passes run on)
/// die while the leadership connection answers every probe. Retaining the lock
/// then stops cluster-wide stuck-job recovery and expired-row purging silently,
/// because every peer's `pg_try_advisory_lock` reports the ordinary
/// `leader: false`. A leader whose passes keep failing must release the lock so
/// a healthy peer can take over.
#[tokio::test(flavor = "multi_thread", worker_threads = 4)]
async fn test_sweep_leadership_fails_over_when_the_leader_cannot_sweep() {
    crate::init_tracing();
    let url = crate::fresh_database("sweep_failover").await;
    Queue::connect(&url).await.unwrap();
    let admin = sqlx::PgPool::connect(&url).await.unwrap();

    // Worker A runs as a dedicated role so its right to open *new* connections
    // can be withdrawn while everyone else's stays. A short acquire timeout
    // bounds how long each doomed pass waits on the refused pool.
    let client_url = crate::limited_role_url(&url, -1).await;
    let role = client_url
        .split_once("://")
        .and_then(|(_, rest)| rest.split_once(':'))
        .unwrap()
        .0
        .to_string();
    let pool_a = sqlx::postgres::PgPoolOptions::new()
        .min_connections(3)
        .max_connections(3)
        .acquire_timeout(Duration::from_millis(500))
        .connect(&client_url)
        .await
        .unwrap();
    let queue_a = Queue::builder(&client_url)
        .pool(pool_a)
        .sweep_grace(Duration::ZERO)
        .migration_mode(pgqueue::MigrationMode::Skip)
        .connect()
        .await
        .unwrap();

    let shutdown_a = CancellationToken::new();
    let worker_a = Worker::builder(queue_a.clone())
        .register_job(repro_noop)
        .timers(WorkerTimers {
            sweep: Duration::from_millis(100),
            ..test_timers()
        })
        .build()
        .unwrap();
    let health_a = worker_a.health();
    let run_a = tokio::spawn(worker_a.run_until(shutdown_a.clone()));

    let (_, db_name) = url.rsplit_once('/').unwrap();
    let key = pgqueue::__test_support::sweep_lock_key(db_name, queue_a.name());
    let leader_pid = wait_for_some(
        Duration::from_secs(30),
        Duration::from_millis(20),
        "worker A never took sweep leadership",
        || async { sweep_leader_pid(&admin, key).await },
    )
    .await;

    // The outage: new flows are refused while established sessions survive.
    // Killing every backend of A's role *except* the leadership session leaves
    // exactly the claimed shape — the liveness probe keeps succeeding on the
    // leadership connection while every sweep pass fails, because the pool it
    // sweeps through can neither reuse its dead connections nor open new ones.
    crate::revoke_connect(&url, &client_url).await;
    wait_until(
        Duration::from_secs(10),
        Duration::from_millis(50),
        "worker A's pooled connections were never terminated",
        || async {
            sqlx::query(
                "SELECT pg_terminate_backend(pid) FROM pg_stat_activity
                 WHERE datname = current_database() AND usename = $1 AND pid <> $2",
            )
            .bind(&role)
            .bind(leader_pid)
            .execute(&admin)
            .await
            .unwrap();
            sqlx::query_scalar::<_, i64>(
                "SELECT count(*) FROM pg_stat_activity
                 WHERE datname = current_database() AND usename = $1 AND pid <> $2",
            )
            .bind(&role)
            .bind(leader_pid)
            .fetch_one(&admin)
            .await
            .unwrap()
                == 0
        },
    )
    .await;

    // Work only a sweep can recover: a running attempt whose worker vanished.
    let queue_b = Queue::builder(&url)
        .sweep_grace(Duration::ZERO)
        .connect()
        .await
        .unwrap();
    let id = queue_b
        .enqueue(repro_noop::job(()).max_attempts(1))
        .await
        .unwrap()
        .job_id();
    let claimed = queue_b.dequeue(1, Uuid::now_v7()).await.unwrap();
    assert_eq!(claimed.len(), 1, "the stuck job was not claimed");
    sqlx::query(
        "UPDATE pgqueue.jobs
         SET started_at = now() - interval '1 hour', touched_at = now() - interval '1 hour'
         WHERE id = $1",
    )
    .bind(id)
    .execute(&admin)
    .await
    .unwrap();

    // A's passes are failing — and it still holds the lock, exactly the state
    // that used to persist for as long as the leadership connection lived.
    wait_until(
        Duration::from_secs(30),
        Duration::from_millis(50),
        "worker A's sweep passes never started failing",
        || async {
            health_a
                .snapshot()
                .failures
                .iter()
                .any(|failure| failure.component == WorkerComponent::Sweeper)
        },
    )
    .await;

    let shutdown_b = CancellationToken::new();
    let worker_b = Worker::builder(queue_b.clone())
        .register_job(repro_noop)
        .timers(WorkerTimers {
            sweep: Duration::from_millis(100),
            ..test_timers()
        })
        .build()
        .unwrap();
    let run_b = tokio::spawn(worker_b.run_until(shutdown_b.clone()));

    // The failing leader must surrender the lock, and the healthy worker must
    // pick it up: a new backend holds leadership and the stuck job is swept.
    wait_until(
        Duration::from_secs(60),
        Duration::from_millis(50),
        "sweep leadership never failed over to the healthy worker",
        || async {
            sweep_leader_pid(&admin, key)
                .await
                .is_some_and(|pid| pid != leader_pid)
        },
    )
    .await;
    wait_until(
        Duration::from_secs(60),
        Duration::from_millis(50),
        "the new leader never recovered the stuck job",
        || async {
            queue_b
                .fetch_job(id)
                .await
                .unwrap()
                .is_some_and(|row| row.status.is_terminal())
        },
    )
    .await;

    shutdown_b.cancel();
    shutdown_a.cancel();
    let _ = tokio::time::timeout(Duration::from_secs(30), run_b).await;
    // Worker A's shutdown wants connections its role is deliberately refused,
    // so its outcome is not what this test asserts.
    let _ = tokio::time::timeout(Duration::from_secs(30), run_a).await;
}

/// `run_until_inner` registers a lease before the fetcher — and with it the
/// shutdown machinery — exists. Stopping in that window must still retire the
/// lease, or the worker keeps advertising itself as live and accepting for up
/// to three heartbeat intervals after it is gone.
#[tokio::test(flavor = "multi_thread", worker_threads = 4)]
async fn test_worker_retires_its_lease_when_shutdown_lands_during_startup() {
    crate::init_tracing();
    let (url, _client_url, queue) = queue_without_a_listener("startup_lease").await;
    let admin = sqlx::PgPool::connect(&url).await.unwrap();

    let shutdown = CancellationToken::new();
    let worker = Worker::builder(queue.clone())
        .register_job(repro_noop)
        .timers(test_timers())
        .poll_interval(Duration::from_millis(50))
        .build()
        .unwrap();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));

    let worker_id: Uuid = crate::wait_for_some(
        Duration::from_secs(30),
        Duration::from_millis(1),
        "worker never registered its lease",
        || async {
            sqlx::query("SELECT id FROM pgqueue.workers")
                .fetch_optional(&admin)
                .await
                .unwrap()
                .map(|row| row.get::<Uuid, _>("id"))
        },
    )
    .await;
    shutdown.cancel();

    tokio::time::timeout(Duration::from_secs(60), run)
        .await
        .expect("worker run did not return")
        .unwrap()
        .unwrap();

    let live: bool = sqlx::query_scalar(
        "SELECT EXISTS (
             SELECT 1 FROM pgqueue.workers
             WHERE id = $1 AND accepting AND expires_at > now()
         )",
    )
    .bind(worker_id)
    .fetch_one(&admin)
    .await
    .unwrap();
    assert!(
        !live,
        "a worker that returned must not still advertise a live, accepting lease"
    );
}

// ---------------------------------------------------------------------------
// A heartbeat that recreates a purged lease must not reopen intake
// ---------------------------------------------------------------------------

/// Parks a handler mid-attempt so the shutdown drain stays open for the test.
#[derive(Clone)]
struct DrainGate {
    started: Arc<tokio::sync::Notify>,
    release: Arc<tokio::sync::Notify>,
}

#[pgqueue::job(name = "repro_drain", max_attempts = 1)]
async fn repro_drain(_: (), state: JobState<DrainGate>) -> anyhow::Result<()> {
    state.0.started.notify_one();
    state.0.release.notified().await;
    Ok(())
}

/// A worker that stalls past its lease TTL has its row deleted by the sweep
/// leader's `purge_worker_leases`. Its next heartbeat therefore inserts rather
/// than updates — and `stop_worker_intake` left nothing behind for the insert
/// to inherit, so a lease created during the shutdown drain has to start
/// closed on its own.
///
/// Getting this wrong is not cosmetic. `accepting` is read by the two claim
/// paths — the dequeue statement and its underfilled-batch probe — so a worker
/// that republishes itself as accepting keeps claiming jobs it has already
/// promised to stop taking, and then has to abandon them at the end of its
/// drain. (Sweeper suppression comes from the lease being *live*, which this
/// heartbeat preserves by design: it is what protects the attempt still
/// draining.)
#[sqlx::test(migrations = "./migrations")]
async fn test_shutting_down_worker_recreates_a_purged_lease_closed(pool: PgPool) {
    // A liveness grace, unlike the suite's usual zero: deleting the lease below
    // is also what makes the attempt still draining look abandoned, and with no
    // grace this worker's own sweeper raced the heartbeat for it — when the
    // sweep won, the attempt was aborted, the drain ended, and the worker
    // stopped heartbeating the very lease under test.
    let db = TestDb::with(crate::pool_with_max(&pool, 10).await, |builder| {
        builder.sweep_grace(Duration::from_secs(30))
    })
    .await;
    let gate = DrainGate {
        started: Arc::new(tokio::sync::Notify::new()),
        release: Arc::new(tokio::sync::Notify::new()),
    };
    db.queue.enqueue(repro_drain::job(())).await.unwrap();

    let shutdown = CancellationToken::new();
    let worker = Worker::builder(db.queue.clone())
        .register_job(repro_drain)
        .state(gate.clone())
        .timers(test_timers())
        .poll_interval(Duration::from_millis(50))
        .shutdown_grace(Duration::from_secs(20))
        .build()
        .unwrap();
    let worker_id = worker.id();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));

    // An attempt is in flight, so the drain — and with it the heartbeat that
    // keeps the lease alive — has to stay open.
    gate.started.notified().await;
    shutdown.cancel();
    crate::wait_for_worker_intake_closed(&db, worker_id).await;

    // What the sweep leader does to a lease that outlived its TTL.
    sqlx::query("DELETE FROM pgqueue.workers WHERE id = $1")
        .bind(worker_id)
        .execute(&pool)
        .await
        .unwrap();

    let accepting = crate::wait_for_some(
        Duration::from_secs(10),
        Duration::from_millis(10),
        "the draining worker never recreated its purged lease",
        || async {
            sqlx::query("SELECT accepting FROM pgqueue.workers WHERE id = $1")
                .bind(worker_id)
                .fetch_optional(&pool)
                .await
                .unwrap()
                .map(|row| row.get::<bool, _>("accepting"))
        },
    )
    .await;
    // The invariant under test, asserted on the recreated row itself.
    assert!(
        !accepting,
        "a shutting-down worker must not recreate its lease as accepting"
    );

    // Liveness is the other half — it is what keeps the sweeper off the attempt
    // still draining — but it is a property of the heartbeat, not of that one
    // read: the lease lives for three heartbeat intervals, so a single
    // observation can land in a window a stalled heartbeat has not refreshed
    // yet. Poll for it rather than requiring the read above to have caught it.
    wait_until(
        Duration::from_secs(10),
        Duration::from_millis(10),
        "the draining worker never kept its recreated lease live",
        || async {
            sqlx::query_scalar::<_, bool>(
                "SELECT expires_at > now() FROM pgqueue.workers WHERE id = $1",
            )
            .bind(worker_id)
            .fetch_optional(&pool)
            .await
            .unwrap()
            .unwrap_or(false)
        },
    )
    .await;

    gate.release.notify_one();
    tokio::time::timeout(Duration::from_secs(30), run)
        .await
        .expect("worker did not finish its drain")
        .unwrap()
        .unwrap();

    let live: bool = sqlx::query_scalar(
        "SELECT EXISTS (
             SELECT 1 FROM pgqueue.workers
             WHERE id = $1 AND accepting AND expires_at > now()
         )",
    )
    .bind(worker_id)
    .fetch_one(&pool)
    .await
    .unwrap();
    assert!(!live, "the retired lease must not be live and accepting");
}

// ---------------------------------------------------------------------------
// Shutdown while a sweep is in flight
// ---------------------------------------------------------------------------

/// A sweep pass issues several statements against the shared pool and can
/// outlast the shutdown budget on a loaded database. Without a cancellation
/// point inside the pass, an ordinary graceful shutdown that lands mid-sweep
/// reports a timer-shutdown failure and the process exits non-zero.
#[sqlx::test(migrations = "./migrations")]
async fn test_shutdown_succeeds_when_a_sweep_is_in_flight(pool: PgPool) {
    let worker_pool = crate::pool_with_max(&pool, 12).await;
    let db = TestDb::with(pool.clone(), |builder| builder.pool(worker_pool)).await;

    let owner = Uuid::now_v7();
    let handle = db
        .queue
        .enqueue_raw(new_job("stuck", |_| {}))
        .await
        .unwrap();
    let claimed = db.queue.dequeue(1, owner).await.unwrap();
    assert_eq!(claimed.len(), 1);
    backdate_job_liveness(&db, handle.job_id()).await;

    install_statement_gate(
        &pool,
        "repro_sweep_gate",
        4242,
        "UPDATE",
        "NEW.status = 'aborting' AND OLD.status = 'running'",
    )
    .await;
    let gate = hold_gate(&pool, 4242, &db.database).await;

    let shutdown = CancellationToken::new();
    let worker = Worker::builder(db.queue.clone())
        .register_job(repro_noop)
        .timers(WorkerTimers {
            sweep: Duration::from_millis(100),
            ..test_timers()
        })
        .poll_interval(Duration::from_millis(50))
        .shutdown_grace(Duration::from_secs(2))
        .build()
        .unwrap();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));

    wait_for_lock_waiter(
        &db,
        "%SET status = 'aborting'%",
        "the sweeper never reached the gated statement",
    )
    .await;

    shutdown.cancel();
    tokio::time::timeout(Duration::from_secs(20), run)
        .await
        .expect("shutdown never returned")
        .unwrap()
        .expect("a shutdown landing mid-sweep is still a clean shutdown");

    gate.rollback().await.unwrap();
}

// ---------------------------------------------------------------------------
// Statement counts, measured with pg_stat_statements
// ---------------------------------------------------------------------------

/// The worker fetch loop *does* consume the probe, so it must keep running.
#[sqlx::test(migrations = "./migrations")]
async fn test_worker_dequeue_still_runs_the_availability_probe(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let Some(mut stats) = Stats::new(&db.database).await else {
        return;
    };
    let worker_id = Uuid::now_v7();
    db.queue
        .write_worker_info(
            worker_id,
            serde_json::json!({}),
            None,
            Duration::from_secs(30),
        )
        .await
        .unwrap();

    let probes = stats.since_now(DEQUEUE_PROBE).await;
    let names = vec!["handled".to_string()];
    pgqueue::__test_support::dequeue_worker(&db.queue, 4, worker_id, &names, false)
        .await
        .unwrap();

    assert_eq!(stats.delta(&probes).await, 1);
}

/// Finishing an attempt the sweeper marked `aborting` used to be refused by the
/// owner-only guards and retried under a second set, running the same 40-line
/// statement twice. One predicate covers both.
#[sqlx::test(migrations = "./migrations")]
async fn test_finish_of_a_swept_attempt_costs_one_round_trip(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let Some(mut stats) = Stats::new(&db.database).await else {
        return;
    };

    // A live owner, so the sweeper marks the attempt `aborting` (phase one) and
    // leaves recovery to it rather than requeueing it itself.
    let owner = Uuid::now_v7();
    db.queue
        .write_worker_info(owner, serde_json::json!({}), None, Duration::from_secs(30))
        .await
        .unwrap();
    let handle = db
        .queue
        .enqueue_raw(new_job("swept", |_| {}))
        .await
        .unwrap();
    let job = db.queue.dequeue(1, owner).await.unwrap().remove(0);
    backdate_job_liveness(&db, handle.job_id()).await;

    db.queue.sweeper().sweep().await.unwrap();
    let status: String = sqlx::query_scalar("SELECT status::text FROM pgqueue.jobs WHERE id = $1")
        .bind(handle.job_id())
        .fetch_one(&pool)
        .await
        .unwrap();
    assert_eq!(status, "aborting", "the sweeper did not mark the attempt");

    let finishes = stats.since_now(FINISH_STATEMENT).await;
    assert!(
        db.queue
            .finish(
                &job,
                JobStatus::Complete,
                Some(serde_json::json!("ok")),
                None
            )
            .await
            .unwrap(),
        "the owner must still be able to finish an attempt the sweeper marked"
    );

    assert_eq!(stats.delta(&finishes).await, 1);
}

// ---------------------------------------------------------------------------
// Cycle 2
// ---------------------------------------------------------------------------

// ---------------------------------------------------------------------------
// A configured timeout must not disable dead-owner recovery
// ---------------------------------------------------------------------------

/// `pgqueue.job_is_stuck` used to make its two recovery triggers mutually
/// exclusive: the "owner's lease is provably gone" branch was gated on
/// `timeout_ms IS NULL`. So a SIGKILLed worker's hour-long attempt stayed
/// `running` for the full hour — holding its dedupe key, which silently
/// deduplicates every re-enqueue and every cron occurrence under that key.
///
/// The two rows here differ only in `timeout_ms`, so the assertion isolates the
/// gate: `timeout_ms` must only ever *add* a way to recover an attempt.
#[sqlx::test(migrations = "./migrations")]
async fn test_a_timed_attempt_is_recovered_when_its_worker_lease_is_gone(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    for (name, timeout) in [
        ("timed", Some(Duration::from_secs(3600))),
        ("untimed", None),
    ] {
        db.queue
            .enqueue_raw(new_job(name, |job| {
                job.config.timeout = timeout;
                job.config.max_attempts = 2;
                job.dedupe_key = Some(name.to_string());
            }))
            .await
            .unwrap();
    }

    let owner = Uuid::now_v7();
    db.queue
        .write_worker_info(owner, serde_json::json!({}), None, Duration::from_secs(30))
        .await
        .unwrap();
    assert_eq!(db.queue.dequeue(2, owner).await.unwrap().len(), 2);
    // SIGKILL: the lease expires and the sweep leader purges the row. Both
    // attempts are minutes old at most, so neither timeout is anywhere near
    // elapsed and only the dead owner can recover them.
    sqlx::query("DELETE FROM pgqueue.workers WHERE id = $1")
        .bind(owner)
        .execute(&pool)
        .await
        .unwrap();

    let stuck: Vec<(String, bool)> = sqlx::query(
        "SELECT j.name, pgqueue.job_is_stuck(j, 0, lease.expires_at) AS stuck
         FROM pgqueue.jobs j
         LEFT JOIN pgqueue.workers lease
             ON lease.id = j.worker_id AND lease.queue = j.queue
         WHERE j.queue = $1 ORDER BY j.name",
    )
    .bind(db.queue.name())
    .fetch_all(&pool)
    .await
    .unwrap()
    .into_iter()
    .map(|row| (row.get("name"), row.get("stuck")))
    .collect();
    assert_eq!(
        stuck,
        vec![("timed".to_string(), true), ("untimed".to_string(), true)],
        "a provably dead owner must make an attempt recoverable with or without a timeout"
    );

    // Phase one marks both `aborting`, phase two requeues them.
    db.queue.sweeper().sweep().await.unwrap();
    db.queue.sweeper().sweep().await.unwrap();
    let statuses: Vec<(String, String)> =
        sqlx::query("SELECT name, status::text AS status FROM pgqueue.jobs ORDER BY name")
            .fetch_all(&pool)
            .await
            .unwrap()
            .into_iter()
            .map(|row| (row.get("name"), row.get("status")))
            .collect();
    assert_eq!(
        statuses,
        vec![
            ("timed".to_string(), "queued".to_string()),
            ("untimed".to_string(), "queued".to_string()),
        ],
        "the timed attempt is still held by a worker that no longer exists"
    );

    // The consequence the gate had in production: the dedupe key was held for
    // the whole timeout, so nothing under it could be enqueued again.
    assert!(
        db.queue
            .enqueue_raw(new_job("timed", |job| {
                job.dedupe_key = Some("timed".to_string());
            }))
            .await
            .unwrap()
            .is_deduplicated(),
        "the recovered row is queued again, so it legitimately still dedupes"
    );
}

/// The other half of the same gate: an attempt whose owner is *alive* must not
/// become recoverable just because the liveness grace elapsed. Only its
/// configured timeout may end it while the lease still covers it.
#[sqlx::test(migrations = "./migrations")]
async fn test_an_attempt_is_not_stuck_while_its_worker_lease_is_live(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let handle = db
        .queue
        .enqueue_raw(new_job("live_owner", |job| {
            job.config.timeout = Some(Duration::from_secs(86_400));
        }))
        .await
        .unwrap();
    let owner = Uuid::now_v7();
    db.queue
        .write_worker_info(owner, serde_json::json!({}), None, Duration::from_secs(30))
        .await
        .unwrap();
    assert_eq!(db.queue.dequeue(1, owner).await.unwrap().len(), 1);
    // Far past any liveness grace, but nowhere near the configured timeout.
    backdate_job_liveness(&db, handle.job_id()).await;

    let stuck: bool = sqlx::query_scalar(
        "SELECT pgqueue.job_is_stuck(j, 0, lease.expires_at)
             FROM pgqueue.jobs j
             LEFT JOIN pgqueue.workers lease
                 ON lease.id = j.worker_id AND lease.queue = j.queue
             WHERE j.id = $1",
    )
    .bind(handle.job_id())
    .fetch_one(&pool)
    .await
    .unwrap();
    assert!(
        !stuck,
        "a live lease still protects an in-flight attempt from recovery"
    );

    db.queue.sweeper().sweep().await.unwrap();
    let status: String = sqlx::query_scalar("SELECT status::text FROM pgqueue.jobs WHERE id = $1")
        .bind(handle.job_id())
        .fetch_one(&pool)
        .await
        .unwrap();
    assert_eq!(status, "running");
}

/// `Sweeper::recover_stuck_jobs` applies this predicate to every `running` and
/// `aborting` row of the queue, unbounded by the sweep batch size and with an
/// `ORDER BY` that gives the executor no early exit. PostgreSQL's
/// `inline_function` refuses any SQL function whose body holds a sublink, so
/// looking the lease up inside the body kept the function an opaque per-row
/// call: the whole `pgqueue.jobs` tuple was built as a composite datum and the
/// lease was re-read per row instead of being pulled into one hashed join.
/// Measured over 20,000 active rows and 50 leases at 180 ms / 20,484 buffers
/// against 6.6 ms / 460 inlined — so the shape of the body is the behaviour
/// here, and the plan is the only place it is observable.
#[sqlx::test(migrations = "./migrations")]
async fn test_stuck_predicate_inlines_into_the_plan_that_scans_for_it(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let plan = sqlx::query_scalar::<_, String>(
        "EXPLAIN (COSTS OFF)
         SELECT j.id
         FROM pgqueue.jobs AS j
         LEFT JOIN pgqueue.workers AS lease
             ON lease.id = j.worker_id AND lease.queue = j.queue
         WHERE j.queue = $1
           AND j.status IN ('running', 'aborting')
           AND pgqueue.job_is_stuck(j, $2, lease.expires_at)",
    )
    .bind(db.queue.name())
    .bind(30_000_i64)
    .fetch_all(&pool)
    .await
    .unwrap()
    .join("\n");
    assert!(
        !plan.contains("job_is_stuck"),
        "the stuck predicate must inline into the scan that applies it, not stay \
         a per-row function call: {plan}"
    );
    // The inlined body is what the plan filters on, so it is there to be seen.
    assert!(
        plan.contains("timeout_ms") && plan.contains("expires_at"),
        "the inlined plan must carry both recovery triggers: {plan}"
    );
}

// ---------------------------------------------------------------------------
// `run_until` must not return leaving a live lease behind
// ---------------------------------------------------------------------------

/// Cancelling `run_until` while the startup heartbeat's INSERT is executing is
/// the one startup step where "the future was cancelled" does not mean "it did
/// not happen": the future is client-side, the INSERT is server-side. The
/// early return above the `retire_startup_lease` guard therefore returned
/// `Ok(())` while PostgreSQL went on to commit a live, accepting lease that
/// `Queue::info`, the dashboard, and the dequeue path all honoured for a full
/// TTL.
#[sqlx::test(migrations = "./migrations")]
async fn test_worker_retires_a_lease_committed_by_a_cancelled_startup_heartbeat(pool: PgPool) {
    let db = TestDb::new(crate::pool_with_max(&pool, 8).await).await;
    // Parks the startup heartbeat's INSERT inside PostgreSQL so the test can
    // cancel `run_until` while the statement is in flight.
    sqlx::raw_sql(
        "CREATE FUNCTION pgqueue.repro_lease_gate() RETURNS trigger
         LANGUAGE plpgsql AS $$
         BEGIN
             PERFORM pg_advisory_xact_lock(9911, hashtext(current_database()));
             RETURN NEW;
         END $$;
         CREATE TRIGGER repro_lease_gate
         BEFORE INSERT ON pgqueue.workers
         FOR EACH ROW EXECUTE FUNCTION pgqueue.repro_lease_gate();",
    )
    .execute(&pool)
    .await
    .unwrap();
    let gate = hold_gate(&pool, 9911, &db.database).await;

    let shutdown = CancellationToken::new();
    let worker = Worker::builder(db.queue.clone())
        .register_job(repro_noop)
        .timers(test_timers())
        .poll_interval(Duration::from_millis(50))
        .build()
        .unwrap();
    let worker_id = worker.id();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));

    wait_for_lock_waiter(
        &db,
        "%INSERT INTO pgqueue.workers%",
        "the startup heartbeat never reached the gated INSERT",
    )
    .await;
    shutdown.cancel();
    // The INSERT commits after the cancellation, exactly as a server-side
    // statement that outlived its client-side future does.
    gate.rollback().await.unwrap();

    tokio::time::timeout(Duration::from_secs(30), run)
        .await
        .expect("worker run did not return")
        .unwrap()
        .unwrap();

    let live: Option<bool> = sqlx::query_scalar(
        "SELECT accepting AND expires_at > now() FROM pgqueue.workers WHERE id = $1",
    )
    .bind(worker_id)
    .fetch_optional(&pool)
    .await
    .unwrap();
    assert_ne!(
        live,
        Some(true),
        "run_until returned Ok(()) while its committed lease still advertised a live, \
         accepting worker"
    );
}

// ---------------------------------------------------------------------------
// A client-side-detectable input error must not abort the caller's transaction
// ---------------------------------------------------------------------------

/// `retire_startup_lease` is awaited by `run_until` itself, and it was the only
/// database step in shutdown with no bound — every sibling wraps the identical
/// calls in `SHUTDOWN_STEP_TIMEOUT`. A backend wedged on a lock therefore hung
/// `run_until` forever instead of degrading to a lease that expires on its own.
#[sqlx::test(migrations = "./migrations")]
async fn test_startup_lease_retirement_is_bounded_when_the_backend_is_wedged(pool: PgPool) {
    let db = TestDb::with(crate::pool_with_max(&pool, 8).await, |builder| builder).await;
    sqlx::raw_sql(
        "CREATE FUNCTION pgqueue.repro_retire_gate() RETURNS trigger
         LANGUAGE plpgsql AS $$
         BEGIN
             PERFORM pg_advisory_xact_lock(9912, hashtext(current_database()));
             RETURN NEW;
         END $$;
         CREATE TRIGGER repro_retire_gate
         BEFORE INSERT ON pgqueue.workers
         FOR EACH ROW EXECUTE FUNCTION pgqueue.repro_retire_gate();",
    )
    .execute(&pool)
    .await
    .unwrap();
    // Held for the rest of the test: the backend never recovers, which is the
    // condition the bound exists for.
    let gate = hold_gate(&pool, 9912, &db.database).await;

    let shutdown = CancellationToken::new();
    let worker = Worker::builder(db.queue.clone())
        .register_job(repro_noop)
        .timers(test_timers())
        .poll_interval(Duration::from_millis(50))
        .build()
        .unwrap();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));

    // Parked inside the startup heartbeat, so cancelling lands on the startup
    // retirement path — whose own lease write hits the same wedged gate.
    wait_for_lock_waiter(
        &db,
        "%INSERT INTO pgqueue.workers%",
        "the startup heartbeat never reached the gated INSERT",
    )
    .await;
    shutdown.cancel();

    tokio::time::timeout(Duration::from_secs(20), run)
        .await
        .expect("run_until never returned while its lease retirement was wedged")
        .unwrap()
        .unwrap();
    gate.rollback().await.unwrap();
}

// ---------------------------------------------------------------------------
// Cycle 3
// ---------------------------------------------------------------------------

// ---------------------------------------------------------------------------
// The dead-owner grace must run from the lease, not from the attempt
// ---------------------------------------------------------------------------

/// Cycle 2 made `pgqueue.job_is_stuck` additive, so a configured `timeout_ms`
/// stopped disabling dead-owner recovery. It measured that branch's grace from
/// the *attempt* (`COALESCE(touched_at, started_at)`), which for anything
/// running longer than the grace is already in the past — so an attempt became
/// recoverable the instant its owner missed one heartbeat window. A workers-row
/// lock wait, a pool stall, a GC pause or a failover was then enough to cancel
/// and re-run work that was still in flight, where before it had the whole
/// `timeout + grace`.
///
/// The grace now also runs from `expires_at`, and expired leases are retained
/// that long so the lapse stays observable.
#[sqlx::test(migrations = "./migrations")]
async fn test_a_recently_lapsed_lease_still_covers_its_attempt(pool: PgPool) {
    let grace = Duration::from_secs(30);
    let db = TestDb::with(pool.clone(), |builder| builder.sweep_grace(grace)).await;
    let handle = db
        .queue
        .enqueue_raw(new_job("stalled_heartbeat", |job| {
            job.config.timeout = Some(Duration::from_secs(3600));
        }))
        .await
        .unwrap();
    let owner = Uuid::now_v7();
    db.queue
        .write_worker_info(owner, serde_json::json!({}), None, Duration::from_secs(30))
        .await
        .unwrap();
    assert_eq!(db.queue.dequeue(1, owner).await.unwrap().len(), 1);
    // The attempt has been running far longer than the grace and its heartbeat
    // has just stalled out: the whole point is that this is *not* a crash.
    backdate_job_liveness(&db, handle.job_id()).await;
    crate::expire_worker(&db, owner).await;

    let stuck = |grace_ms: i64| {
        let pool = pool.clone();
        let id = handle.job_id();
        async move {
            sqlx::query_scalar::<_, bool>(
                "SELECT pgqueue.job_is_stuck(j, $2, lease.expires_at)
                 FROM pgqueue.jobs j
                 LEFT JOIN pgqueue.workers lease
                     ON lease.id = j.worker_id AND lease.queue = j.queue
                 WHERE j.id = $1",
            )
            .bind(id)
            .bind(grace_ms)
            .fetch_one(&pool)
            .await
            .unwrap()
        }
    };
    assert!(
        !stuck(30_000).await,
        "a lease that lapsed a second ago still covers the attempt it leased"
    );

    let mut sweeper = db.queue.sweeper();
    let report = sweeper.sweep().await.unwrap();
    assert!(report.cancelling.is_empty(), "{report:?}");
    let lease_exists = |owner: Uuid| {
        let pool = pool.clone();
        async move {
            sqlx::query_scalar::<_, bool>(
                "SELECT EXISTS (SELECT 1 FROM pgqueue.workers WHERE id = $1)",
            )
            .bind(owner)
            .fetch_one(&pool)
            .await
            .unwrap()
        }
    };
    assert!(
        lease_exists(owner).await,
        "purging the lease immediately would make its expiry unobservable, and a \
         missing row is indistinguishable from one that lapsed an hour ago"
    );
    let status: String = sqlx::query_scalar("SELECT status::text FROM pgqueue.jobs WHERE id = $1")
        .bind(handle.job_id())
        .fetch_one(&pool)
        .await
        .unwrap();
    assert_eq!(status, "running");

    // Past the grace the owner is provably gone, and the hour of timeout still
    // left on the attempt does not hold recovery back.
    sqlx::query(
        "UPDATE pgqueue.workers SET expires_at = now() - interval '1 minute' WHERE id = $1",
    )
    .bind(owner)
    .execute(&pool)
    .await
    .unwrap();
    assert!(stuck(30_000).await);
    assert_eq!(
        sweeper.sweep().await.unwrap().cancelling,
        vec![handle.job_id()]
    );
    assert!(!lease_exists(owner).await, "the lapsed lease is purged too");
    sweeper.release().await;
}

// ---------------------------------------------------------------------------
// A transient finalize failure during the shutdown drain is still retried
// ---------------------------------------------------------------------------

#[pgqueue::job(name = "repro_drain_result", max_attempts = 1)]
async fn repro_drain_result(_: (), state: JobState<DrainGate>) -> anyhow::Result<i64> {
    state.0.started.notify_one();
    state.0.release.notified().await;
    Ok(42)
}

/// Installs a `BEFORE UPDATE` trigger that fails the first attempt to move a
/// row out of `running`, standing in for one transient database error — a pool
/// timeout is entirely plausible during a drain, where the drain, the sweeper,
/// both heartbeaters and every other processor contend for the same pool.
async fn fail_first_finalization(pool: &PgPool) {
    sqlx::raw_sql(
        r#"
        CREATE SEQUENCE pgqueue.repro_finalization_failures;
        CREATE FUNCTION pgqueue.repro_fail_first_finalization() RETURNS trigger
        LANGUAGE plpgsql AS $$
        BEGIN
            IF nextval('pgqueue.repro_finalization_failures') = 1 THEN
                RAISE EXCEPTION 'injected transient finalization failure';
            END IF;
            RETURN NEW;
        END
        $$;
        CREATE TRIGGER repro_fail_first_finalization
        BEFORE UPDATE ON pgqueue.jobs
        FOR EACH ROW
        WHEN (OLD.status = 'running' AND NEW.status IS DISTINCT FROM OLD.status)
        EXECUTE FUNCTION pgqueue.repro_fail_first_finalization();
        "#,
    )
    .execute(pool)
    .await
    .expect("install transient finalization failure");
}

/// Closing intake is shutdown's *first* durable act, so a finalize retry bound
/// to that token has an already-ready cancellation branch for the whole drain:
/// a handler that completed during the drain and hit one transient error got
/// zero retries, whatever `shutdown_grace` said. The row then stayed
/// `running`/`worker_id = W`, the sweeper's dead-owner branch marked it
/// `aborting`, and with the default `max_attempts = 1` it was finalized
/// `aborted` with `result = NULL` — a job that succeeded reported as aborted,
/// its result lost, and `enqueue_and_wait` handed an `Error::Job`.
///
/// The lease is deliberately kept alive for the whole drain, so nothing can
/// recover the row while the retry is in flight; the retry belongs to the grace
/// window, not to the instant intake closes.
#[sqlx::test(migrations = "./migrations")]
async fn test_finalize_retries_a_transient_failure_when_shutdown_has_started(pool: PgPool) {
    let db = TestDb::new(crate::pool_with_max(&pool, 10).await).await;
    let gate = DrainGate {
        started: Arc::new(tokio::sync::Notify::new()),
        release: Arc::new(tokio::sync::Notify::new()),
    };
    let handle = db.queue.enqueue(repro_drain_result::job(())).await.unwrap();

    let shutdown = CancellationToken::new();
    let worker = Worker::builder(db.queue.clone())
        .register_job(repro_drain_result)
        .state(gate.clone())
        .timers(test_timers())
        .poll_interval(Duration::from_millis(50))
        .shutdown_grace(Duration::from_secs(30))
        .build()
        .unwrap();
    let worker_id = worker.id();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));

    gate.started.notified().await;
    fail_first_finalization(&pool).await;
    // Shutdown is under way and intake is durably closed *before* the handler
    // returns, so the finalize below happens entirely inside the drain.
    shutdown.cancel();
    crate::wait_for_worker_intake_closed(&db, worker_id).await;
    gate.release.notify_one();

    tokio::time::timeout(Duration::from_secs(30), run)
        .await
        .expect("worker did not finish its drain")
        .unwrap()
        .unwrap();

    let row = db
        .queue
        .fetch_job(handle.job_id())
        .await
        .unwrap()
        .expect("the job row must survive its own successful attempt");
    assert_eq!(
        (row.status, row.attempts, row.result),
        (JobStatus::Complete, 1, Some(serde_json::json!(42))),
        "a handler that succeeded during the drain must not lose its result to \
         one transient finalize error"
    );
}

// ---------------------------------------------------------------------------
// `/health` must be single-flight, not merely cached
// ---------------------------------------------------------------------------

/// Every sweeper test used `retry_delay: Duration::ZERO`, so the delayed arm of
/// `retry_swept_abandoned_batch` — the `$4::bigint[]` the per-row delays ride
/// in on — had never run. A recovered attempt has to respect its own backoff:
/// requeueing it to run immediately is how a crash loop becomes a hot loop.
#[sqlx::test(migrations = "./migrations")]
async fn test_swept_attempt_is_requeued_behind_its_own_retry_delay(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let handle = db
        .queue
        .enqueue_raw(crate::with_config("delayed_sweep", |config| {
            config.max_attempts = 3;
            config.retry_delay = Duration::from_secs(600);
        }))
        .await
        .unwrap();
    let owner = Uuid::now_v7();
    db.queue
        .write_worker_info(owner, serde_json::json!({}), None, Duration::from_secs(30))
        .await
        .unwrap();
    assert_eq!(db.queue.dequeue(1, owner).await.unwrap().len(), 1);
    backdate_job_liveness(&db, handle.job_id()).await;
    crate::expire_worker(&db, owner).await;

    let mut sweeper = db.queue.sweeper();
    assert_eq!(
        sweeper.sweep().await.unwrap().cancelling,
        vec![handle.job_id()]
    );
    assert_eq!(sweeper.sweep().await.unwrap().swept, vec![handle.job_id()]);
    sweeper.release().await;

    let row = db
        .queue
        .fetch_job(handle.job_id())
        .await
        .unwrap()
        .expect("the swept job row");
    assert_eq!(row.status, JobStatus::Queued);
    assert!(
        row.scheduled_at > chrono::Utc::now() + chrono::Duration::seconds(300),
        "a recovered attempt must wait out its retry delay, not run immediately: \
         scheduled_at {}",
        row.scheduled_at
    );
}

/// The underfilled-batch probe's two diagnostic branches: the sorted, capped
/// list of queued names this worker has no handler for, and the `ELSE` that
/// skips building it when the caller's warning is not due. Both were only ever
/// observed as "the probe ran", never as what it reported.
#[sqlx::test(migrations = "./migrations")]
async fn test_dequeue_probe_reports_the_queued_names_the_worker_cannot_handle(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    for name in ["zeta", "alpha", "handled", "mu"] {
        db.queue.enqueue_raw(new_job(name, |_| {})).await.unwrap();
    }
    let worker_id = Uuid::now_v7();
    db.queue
        .write_worker_info(
            worker_id,
            serde_json::json!({}),
            None,
            Duration::from_secs(30),
        )
        .await
        .unwrap();
    let registered = vec!["handled".to_string()];

    // Nothing is claimed, so the batch is underfilled and the probe runs.
    let (work_available, unhandled) =
        pgqueue::__test_support::dequeue_worker_probe(&db.queue, 8, worker_id, &registered, true)
            .await
            .unwrap();
    assert!(
        !work_available,
        "the handled job was just claimed, so nothing runnable is left"
    );
    assert_eq!(
        unhandled,
        vec!["alpha".to_string(), "mu".into(), "zeta".into()],
        "the unhandled names are reported sorted, and only the unregistered ones"
    );

    // The warning is rate-limited, so most passes ask for nothing.
    let (_, unhandled) =
        pgqueue::__test_support::dequeue_worker_probe(&db.queue, 8, worker_id, &registered, false)
            .await
            .unwrap();
    assert!(
        unhandled.is_empty(),
        "the name scan must not run when the caller's warning is not due: {unhandled:?}"
    );
}

/// PostgreSQL `jsonb` cannot represent `\0` (`22P05`) and `text` cannot store
/// it either (`22021`), so finalizing either of these attempts is a write the
/// server refuses permanently. Finalization retries every database error once a
/// second until shutdown, so before the fix each of these attempts held its
/// processor slot forever, left its row `running` under a live lease, and — once
/// that lease finally lapsed — handed the sweeper a job whose next attempt
/// wedged identically.
#[pgqueue::job(name = "repro_nul_result", max_attempts = 3, retry_delay_ms = 0)]
async fn repro_nul_result(_: ()) -> anyhow::Result<String> {
    Ok("bad\u{0}value".to_string())
}

#[pgqueue::job(name = "repro_nul_error", max_attempts = 1)]
async fn repro_nul_error(_: ()) -> anyhow::Result<()> {
    anyhow::bail!("bad\u{0}message")
}

#[sqlx::test(migrations = "./migrations")]
async fn test_worker_finalizes_an_attempt_whose_result_or_error_carries_a_nul(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let result_id = db
        .queue
        .enqueue(repro_nul_result::job(()))
        .await
        .unwrap()
        .job_id();
    let error_id = db
        .queue
        .enqueue(repro_nul_error::job(()))
        .await
        .unwrap()
        .job_id();

    let shutdown = CancellationToken::new();
    let worker = Worker::builder(db.queue.clone())
        .register_job(repro_nul_result)
        .register_job(repro_nul_error)
        // One slot, so the second job runs only once the first has genuinely
        // let go of it: an attempt that cannot be finalized never does.
        .concurrency(1)
        .timers(test_timers())
        .poll_interval(Duration::from_millis(50))
        .build()
        .unwrap();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));

    let result_row = wait_terminal(&db.queue, result_id, 30).await;
    let error_row = wait_terminal(&db.queue, error_id, 30).await;
    shutdown.cancel();
    tokio::time::timeout(Duration::from_secs(10), run)
        .await
        .expect("worker did not stop")
        .unwrap()
        .unwrap();

    // A result that cannot be encoded is a decode failure — deterministic, so
    // the two remaining attempts are not spent rediscovering it.
    assert_eq!(result_row.status, JobStatus::Failed);
    assert_eq!(result_row.attempts, 1);
    assert_eq!(
        result_row.error.as_deref(),
        Some("decode: result encode: a job result must not contain NUL")
    );
    assert!(result_row.result.is_none(), "{:?}", result_row.result);

    // The handler's own message survives; only the byte PostgreSQL cannot store
    // is substituted, and visibly so.
    assert_eq!(error_row.status, JobStatus::Failed);
    assert_eq!(
        error_row.error.as_deref(),
        Some("failed: bad\u{fffd}message")
    );
}

/// `JobError::new` substitutes the NUL, but it is not the only way to make a
/// `JobError`: the fields are public, and `IntoJobResult` hands a handler's own
/// error back verbatim rather than rebuilding it. An `anyhow::bail!` is
/// `String`-backed and so goes through `JobError::failed`, which is why the
/// constructor's guard looked sufficient; this shape skips the constructor
/// entirely and reaches the `text` column with the byte still in it.
#[pgqueue::job(name = "repro_nul_job_error", max_attempts = 1)]
async fn repro_nul_job_error(_: ()) -> Result<(), pgqueue::JobError> {
    Err(pgqueue::JobError {
        kind: pgqueue::JobErrorKind::Failed,
        message: "bad\u{0}input".to_string(),
    })
}

#[sqlx::test(migrations = "./migrations")]
async fn test_worker_finalizes_a_handler_built_job_error_whose_message_carries_a_nul(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let wedge_id = db
        .queue
        .enqueue(repro_nul_job_error::job(()))
        .await
        .unwrap()
        .job_id();
    let next_id = db
        .queue
        .enqueue(repro_noop::job(()))
        .await
        .unwrap()
        .job_id();

    let shutdown = CancellationToken::new();
    let worker = Worker::builder(db.queue.clone())
        .register_job(repro_nul_job_error)
        .register_job(repro_noop)
        // One slot, so the follow-up job runs only once the unstorable error has
        // genuinely released it.
        .concurrency(1)
        .timers(test_timers())
        .poll_interval(Duration::from_millis(50))
        .build()
        .unwrap();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));

    let wedge_row = wait_terminal(&db.queue, wedge_id, 30).await;
    let next_row = wait_terminal(&db.queue, next_id, 30).await;
    shutdown.cancel();
    tokio::time::timeout(Duration::from_secs(10), run)
        .await
        .expect("worker did not stop")
        .unwrap()
        .unwrap();

    assert_eq!(wedge_row.status, JobStatus::Failed);
    assert_eq!(wedge_row.error.as_deref(), Some("failed: bad\u{fffd}input"));
    assert_eq!(
        next_row.status,
        JobStatus::Complete,
        "the processor slot must come back"
    );
}

// ---------------------------------------------------------------------------
// A dedupe key stolen between the scheduler's check and its insert
// ---------------------------------------------------------------------------

/// A JSON document of `depth` nested objects wrapped around `null`.
fn nested_json(depth: usize) -> serde_json::Value {
    let mut value = serde_json::Value::Null;
    for _ in 0..depth {
        value = serde_json::json!({ "a": value });
    }
    value
}

/// The mirror image of the NUL result above: `jsonb` stores nesting happily,
/// but `serde_json`'s deserializer stops at 128 nested containers, so writing
/// one poisoned every later read of the queue — `fetch_job`, `jobs_page`, the
/// dashboard listing, and the dequeue batch, which commits `running` and spends
/// an attempt server-side before the client decodes what it claimed. Refusing it
/// only in `validate_finalization` is not enough either: `finalize` retries every
/// error once a second until shutdown, so the attempt would hold its processor
/// slot forever. It has to fail the attempt where a handler's value becomes a
/// success.
#[pgqueue::job(name = "repro_deep_result", max_attempts = 3, retry_delay_ms = 0)]
async fn repro_deep_result(_: ()) -> anyhow::Result<serde_json::Value> {
    Ok(nested_json(128))
}

#[sqlx::test(migrations = "./migrations")]
async fn test_worker_fails_an_attempt_whose_result_nests_deeper_than_it_can_be_read_back(
    pool: PgPool,
) {
    let db = TestDb::new(pool.clone()).await;
    let deep_id = db
        .queue
        .enqueue(repro_deep_result::job(()))
        .await
        .unwrap()
        .job_id();
    let next_id = db
        .queue
        .enqueue(repro_noop::job(()))
        .await
        .unwrap()
        .job_id();

    let shutdown = CancellationToken::new();
    let worker = Worker::builder(db.queue.clone())
        .register_job(repro_deep_result)
        .register_job(repro_noop)
        // One slot, so the follow-up runs only once the undecodable result has
        // genuinely released it.
        .concurrency(1)
        .timers(test_timers())
        .poll_interval(Duration::from_millis(50))
        .build()
        .unwrap();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));

    let deep_row = wait_terminal(&db.queue, deep_id, 30).await;
    let next_row = wait_terminal(&db.queue, next_id, 30).await;
    shutdown.cancel();
    tokio::time::timeout(Duration::from_secs(10), run)
        .await
        .expect("worker did not stop")
        .unwrap()
        .unwrap();

    // Deterministic, so the two remaining attempts are not spent rediscovering
    // it — exactly as the NUL result is treated.
    assert_eq!(deep_row.status, JobStatus::Failed);
    assert_eq!(deep_row.attempts, 1);
    assert_eq!(
        deep_row.error.as_deref(),
        Some("decode: result encode: a job result must not nest deeper than 127 levels")
    );
    assert!(deep_row.result.is_none(), "{:?}", deep_row.result);
    assert_eq!(
        next_row.status,
        JobStatus::Complete,
        "the processor slot must come back"
    );
}

/// `pgqueue.workers.metadata` is `jsonb`, which cannot hold `\0`. The lease
/// write reports its failure through health and a log rather than to a caller,
/// so a worker built with such metadata started, created no lease, and — since
/// dequeueing requires a live accepting lease — processed nothing for as long as
/// it ran. The enqueue side already refuses the same byte in a payload or in
/// job meta, so this is validated where the rest of the worker configuration is.
#[sqlx::test(migrations = "./migrations")]
async fn test_worker_build_rejects_metadata_containing_a_nul(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;

    let built = Worker::builder(db.queue.clone())
        .register_job(repro_noop)
        .metadata(serde_json::json!({ "host": "web-01\u{0}" }))
        .build();
    let Err(error) = built else {
        panic!("metadata PostgreSQL cannot store must be refused");
    };
    match error {
        pgqueue::Error::Config(message) => {
            assert!(message.contains("must not contain NUL"), "{message}");
        }
        other => panic!("unstorable metadata must be a config error: {other}"),
    }

    // The same metadata without the byte still builds, so the guard is about
    // NUL and not about metadata.
    Worker::builder(db.queue.clone())
        .register_job(repro_noop)
        .metadata(serde_json::json!({ "host": "web-01" }))
        .build()
        .expect("valid metadata must still build");
}

/// The mirror image of the NUL above, and just as terminal: `jsonb` stores the
/// nesting happily, but `serde_json` stops decoding at 128 nested containers, so
/// the lease write succeeds and every later read of `pgqueue.workers` — the
/// dashboard's worker listing and detail pages — fails for the whole queue
/// instead. Nothing surfaces it to the operator who set the metadata, so it is
/// refused at build time next to the byte guard.
#[sqlx::test(migrations = "./migrations")]
async fn test_worker_build_rejects_metadata_nested_deeper_than_it_can_be_read_back(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;

    let built = Worker::builder(db.queue.clone())
        .register_job(repro_noop)
        .metadata(nested_json(128))
        .build();
    let Err(error) = built else {
        panic!("metadata this crate can never read back must be refused");
    };
    match error {
        pgqueue::Error::Config(message) => {
            assert_eq!(
                message,
                "worker metadata must not nest deeper than 127 levels"
            );
        }
        other => panic!("undecodable metadata must be a config error: {other}"),
    }

    // 127 is the deepest `serde_json` decodes, so it must still build: an
    // off-by-one here silently narrows the documented metadata space.
    Worker::builder(db.queue.clone())
        .register_job(repro_noop)
        .metadata(nested_json(127))
        .build()
        .expect("the deepest readable metadata must still build");
}

// ---------------------------------------------------------------------------
// One worker id cannot be shared by two queues
// ---------------------------------------------------------------------------

/// How many backends hold the single-key advisory lock `key` in this database.
async fn sweep_lock_holders(pool: &PgPool, key: i64) -> i64 {
    let class_id = i64::from((key as u64 >> 32) as u32);
    let object_id = i64::from(key as u64 as u32);
    sqlx::query_scalar::<_, i64>(
        "SELECT count(*) FROM pg_locks
         WHERE locktype = 'advisory' AND granted AND objsubid = 1
           AND classid::bigint = $1 AND objid::bigint = $2
           AND database = (SELECT oid FROM pg_database WHERE datname = current_database())",
    )
    .bind(class_id)
    .bind(object_id)
    .fetch_one(pool)
    .await
    .expect("count sweep lock holders")
}

/// Sweep leadership is a *session*-scoped `pg_try_advisory_lock`, so the lock
/// outlives the statement that took it. Cancelling the acquisition between the
/// server granting the lock and the client storing the connection handed a
/// locked connection back to the pool: sqlx resets nothing on release, so the
/// lock sat on an idle pooled connection with nothing left holding a handle to
/// it — `release` and `Drop` both saw `None`. Sweeping then stopped **cluster
/// wide** and silently, because a refused sweeper reports the ordinary
/// `leader: false`. `sweep_loop` drops exactly this future on every worker
/// shutdown, and the first tick fires immediately at startup.
#[sqlx::test(migrations = "./migrations")]
async fn test_cancelled_sweep_acquisition_leaves_no_stranded_leadership_lock(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let key = pgqueue::__test_support::sweep_lock_key(&db.database, db.queue.name());
    // Its own pool: another worker process in the cluster, which is what a
    // stranded lock locks out until sqlx reaps the connection holding it.
    let elsewhere = Queue::builder("postgres://unused")
        .pool(crate::pool_with_max(&pool, 2).await)
        .connect()
        .await
        .unwrap();

    for attempt in 1..=8 {
        let mut sweeper = db.queue.sweeper();
        {
            let mut sweep = Box::pin(sweeper.sweep());
            // One poll at a time, with the task's own waker, stopping the moment
            // the server reports the lock granted: the answer is then in flight
            // and the future has not seen it — the exact window a `select!` on a
            // cancellation token drops the future in.
            let mut granted = false;
            for _ in 0..200 {
                let progress = std::future::poll_fn(|context| {
                    std::task::Poll::Ready(std::future::Future::poll(sweep.as_mut(), context))
                })
                .await;
                assert!(
                    progress.is_pending(),
                    "attempt {attempt}: the sweep finished before its lock could be cancelled"
                );
                if sweep_lock_holders(&pool, key).await > 0 {
                    granted = true;
                    break;
                }
            }
            assert!(
                granted,
                "attempt {attempt}: the sweep never took its leadership lock"
            );
        }
        drop(sweeper);

        wait_until(
            Duration::from_secs(5),
            Duration::from_millis(20),
            &format!("attempt {attempt}: a cancelled acquisition stranded its advisory lock"),
            || async { sweep_lock_holders(&pool, key).await == 0 },
        )
        .await;

        let mut replacement = elsewhere.sweeper();
        assert!(
            replacement.sweep().await.unwrap().leader,
            "attempt {attempt}: another process was refused leadership by a stranded lock"
        );
        replacement.release().await;
    }
}

// ---------------------------------------------------------------------------
// A proxied deployment can charge a guess to the client that made it
// ---------------------------------------------------------------------------

#[derive(Clone)]
struct SupersededProbe {
    started: Arc<tokio::sync::Notify>,
    ticks: Arc<AtomicUsize>,
}

/// Never reads its cancellation token and has no timeout, so nothing but the
/// abort loop can end it. Each tick stands in for an externally visible side
/// effect the attempt is no longer entitled to produce.
#[pgqueue::job(max_attempts = 3, timeout_ms = 0)]
async fn repro_superseded(_: (), probe: JobState<SupersededProbe>) -> anyhow::Result<()> {
    probe.0.started.notify_one();
    loop {
        tokio::time::sleep(Duration::from_millis(20)).await;
        probe.0.ticks.fetch_add(1, Ordering::SeqCst);
    }
}

/// Runs only once the superseded attempt has given its processor slot back.
#[pgqueue::job(max_attempts = 1)]
async fn repro_after_supersede(_: ()) -> anyhow::Result<()> {
    Ok(())
}

/// Recovery hands a stuck attempt to another worker by requeueing the row and
/// letting the next dequeue claim it with `attempts + 1` under a new owner. The
/// original handler keeps running: its row is neither `aborting` (the new
/// attempt is `running`) nor gone, so the abort poll used to have nothing to
/// match on, and the attempt held its processor slot for as long as it lived —
/// forever, with the timeout disabled.
#[sqlx::test(migrations = "./migrations")]
async fn test_superseded_attempt_is_cancelled_and_releases_its_processor_slot(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let id = db
        .queue
        .enqueue(repro_superseded::job(()))
        .await
        .unwrap()
        .job_id();
    let probe = SupersededProbe {
        started: Arc::new(tokio::sync::Notify::new()),
        ticks: Arc::new(AtomicUsize::new(0)),
    };
    let worker = Worker::builder(db.queue.clone())
        .timers(test_timers())
        .poll_interval(Duration::from_millis(50))
        .concurrency(1)
        // Long enough that an attempt waiting out the cooperative grace would
        // still be ticking when this test's deadline passes: the row already
        // belongs to another attempt, so there is nothing left to clean up.
        .abort_grace(Duration::from_secs(60))
        .shutdown_grace(Duration::from_secs(5))
        .register_job(repro_superseded)
        .register_job(repro_after_supersede)
        .state(probe.clone())
        .build()
        .unwrap();
    let shutdown = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));
    tokio::time::timeout(Duration::from_secs(10), probe.started.notified())
        .await
        .expect("handler did not start");

    // The new owner is a live worker: without a lease of its own the sweeper
    // would treat the re-claimed row as abandoned, which is a different story.
    let thief = Uuid::now_v7();
    let _thief_lease = leased_consumer(&db.queue, thief).await;
    assert_eq!(
        sqlx::query(
            "UPDATE pgqueue.jobs
             SET attempts = attempts + 1, worker_id = $2,
                 started_at = now(), touched_at = now()
             WHERE id = $1 AND status = 'running'"
        )
        .bind(id)
        .bind(thief)
        .execute(db.queue.pool())
        .await
        .unwrap()
        .rows_affected(),
        1,
        "the row was not running when the re-claim was simulated"
    );

    wait_until(
        Duration::from_secs(10),
        Duration::from_millis(25),
        "the superseded handler kept running after its row was re-claimed",
        || async {
            let before = probe.ticks.load(Ordering::SeqCst);
            tokio::time::sleep(Duration::from_millis(100)).await;
            probe.ticks.load(Ordering::SeqCst) == before
        },
    )
    .await;

    // The row is the new attempt's; a cancelled predecessor must not write it.
    let row = db.queue.fetch_job(id).await.unwrap().expect("job row");
    assert_eq!(row.status, JobStatus::Running);
    assert_eq!(row.attempts, 2);
    assert_eq!(row.worker_id, Some(thief));

    // The slot is the point: with one processor, nothing else runs until the
    // superseded attempt lets go of it.
    let next = db
        .queue
        .enqueue(repro_after_supersede::job(()))
        .await
        .unwrap()
        .job_id();
    wait_until(
        Duration::from_secs(10),
        Duration::from_millis(25),
        "the processor slot was never released",
        || async {
            db.queue
                .fetch_job(next)
                .await
                .unwrap()
                .is_some_and(|row| row.status == JobStatus::Complete)
        },
    )
    .await;

    shutdown.cancel();
    run.await.unwrap().unwrap();
}

// ---------------------------------------------------------------------------
// The sweeper's own requeue must end the attempt it takes the row from
// ---------------------------------------------------------------------------

/// Tick counters per attempt number, so a job that is briefly in flight twice
/// at once can be asked *which* of its attempts is still producing side
/// effects. Indexed by attempt; `max_attempts` bounds the index.
#[derive(Clone)]
struct AttemptTicks(Arc<[AtomicUsize; 4]>);

impl AttemptTicks {
    fn new() -> Self {
        Self(Arc::new(std::array::from_fn(|_| AtomicUsize::new(0))))
    }

    fn count(&self, attempt: u32) -> usize {
        self.0[attempt as usize].load(Ordering::SeqCst)
    }

    /// Whether `attempt` produced a side effect during `window`.
    async fn advanced(&self, attempt: u32, window: Duration) -> bool {
        let before = self.count(attempt);
        tokio::time::sleep(window).await;
        self.count(attempt) > before
    }
}

/// Ticks under its own attempt number forever: no timeout and no cancellation
/// check, so nothing but the abort loop can end it, and each tick stands in for
/// an externally visible side effect that attempt is no longer entitled to
/// produce.
#[pgqueue::job(max_attempts = 3, timeout_ms = 0)]
async fn repro_sweep_requeued(
    _: (),
    ticks: JobState<AttemptTicks>,
    ctx: JobContext,
) -> anyhow::Result<()> {
    loop {
        ticks.0.0[ctx.attempt() as usize].fetch_add(1, Ordering::SeqCst);
        tokio::time::sleep(Duration::from_millis(20)).await;
    }
}

/// Builds the worker both tests below drive by hand: it sweeps and heartbeats
/// only when they say so, and polls for aborts on a long enough interval that
/// the whole recovery lands between two polls.
fn requeue_worker(db: &TestDb, ticks: &AttemptTicks, concurrency: usize) -> Worker {
    Worker::builder(db.queue.clone())
        .timers(WorkerTimers {
            // Polls once at startup and then well after the recovery below: a
            // poll landing inside the `aborting` window would cancel the
            // attempt for a reason these tests are not about.
            abort: Duration::from_secs(5),
            // Recovery and the lease are driven by hand here.
            sweep: Duration::from_secs(3_600),
            worker_info: Duration::from_secs(3_600),
            ..test_timers()
        })
        .poll_interval(Duration::from_millis(50))
        .concurrency(concurrency)
        // Long enough that an attempt waiting out a cooperative grace would
        // still be ticking at the end of these tests: a row that is no longer
        // this attempt's leaves it nothing to clean up, so it gets none.
        .abort_grace(Duration::from_secs(60))
        .shutdown_grace(Duration::from_secs(1))
        .register_job(repro_sweep_requeued)
        .state(ticks.clone())
        .build()
        .unwrap()
}

/// Parks every lease write the worker makes until the returned transaction
/// ends, so a lease these tests expire stays expired for the sweep that has to
/// see it lapsed.
///
/// A heartbeat is an `INSERT ... ON CONFLICT`, and `BEFORE INSERT` fires before
/// the conflict is resolved, so a parked heartbeat holds no row lock: the
/// tests' own updates of that row run straight past it.
async fn park_worker_heartbeats(db: &TestDb) -> sqlx::Transaction<'static, sqlx::Postgres> {
    sqlx::raw_sql(
        "CREATE FUNCTION pgqueue.repro_park_heartbeat() RETURNS trigger
         LANGUAGE plpgsql AS $$
         BEGIN
             PERFORM pg_advisory_xact_lock(919, hashtext(current_database()));
             RETURN NEW;
         END $$;
         CREATE TRIGGER repro_park_heartbeat
         BEFORE INSERT ON pgqueue.workers
         FOR EACH ROW EXECUTE FUNCTION pgqueue.repro_park_heartbeat();",
    )
    .execute(db.queue.pool())
    .await
    .expect("install the heartbeat park");
    hold_gate(db.queue.pool(), 919, &db.database).await
}

/// Brings a stalled worker's lease back, as its next heartbeat does.
async fn revive_worker_lease(db: &TestDb, worker_id: Uuid) {
    let updated = sqlx::query(
        "UPDATE pgqueue.workers
         SET expires_at = now() + interval '1 hour', heartbeat_at = now()
         WHERE id = $1",
    )
    .bind(worker_id)
    .execute(db.queue.pool())
    .await
    .expect("revive worker lease")
    .rows_affected();
    assert_eq!(updated, 1, "the worker lease to revive is gone");
}

/// Runs the recovery both tests below share: the owner's lease lapses and its
/// attempt passes the grace, so phase one marks the row `aborting` and phase
/// two requeues it — all while the handler is still running.
async fn sweep_away_the_attempt(db: &TestDb, sweeper: &mut Sweeper, id: Uuid, worker_id: Uuid) {
    // Not `ALL`: purging the lapsed lease would delete the row the worker's
    // returning heartbeat writes to, and a lease that has only just lapsed is
    // kept on disk for exactly that reason (`Sweeper::purge_worker_leases`).
    let operations = SweepOperations {
        workers: false,
        ..SweepOperations::ALL
    };
    expire_worker(db, worker_id).await;
    backdate_job_liveness(db, id).await;
    assert_eq!(
        sweeper
            .sweep_operations(operations)
            .await
            .unwrap()
            .cancelling,
        vec![id],
        "phase one did not mark the abandoned attempt"
    );
    assert_eq!(
        sweeper.sweep_operations(operations).await.unwrap().swept,
        vec![id],
        "phase two did not requeue the abandoned attempt"
    );
}

/// Recovery's second phase requeues an abandoned attempt, and it used to leave
/// `worker_id` — like `attempts`, which it deliberately keeps — exactly as the
/// still-live owner holds it. `aborting_of` then read that row back as "still
/// running as claimed" and signalled nothing, so a worker that was only
/// *presumed* dead (a stalled heartbeat, a pool stall, a GC pause) kept running
/// the handler, kept producing side effects it was no longer entitled to, and
/// kept its processor slot — forever, with the timeout disabled.
///
/// The queued row is all the worker has to notice here: nothing has re-claimed
/// it, and with one processor nothing can until this attempt lets go.
#[sqlx::test(migrations = "./migrations")]
async fn test_sweep_requeued_attempt_is_cancelled_before_anything_reclaims_the_row(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    // Leadership is taken here and held for the whole test, so the worker's own
    // sweep loop cannot slip a pass between this test's two.
    let mut sweeper = db.queue.sweeper();
    assert!(sweeper.sweep().await.unwrap().leader);

    let ticks = AttemptTicks::new();
    let id = db
        .queue
        .enqueue(repro_sweep_requeued::job(()))
        .await
        .unwrap()
        .job_id();
    let worker = requeue_worker(&db, &ticks, 1);
    let worker_id = worker.id();
    let shutdown = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));
    wait_until(
        Duration::from_secs(10),
        Duration::from_millis(10),
        "the first attempt never started",
        || async { ticks.count(1) > 0 },
    )
    .await;

    let gate = park_worker_heartbeats(&db).await;
    sweep_away_the_attempt(&db, &mut sweeper, id, worker_id).await;
    let row = db.queue.fetch_job(id).await.unwrap().expect("job row");
    assert_eq!(row.status, JobStatus::Queued);
    assert_eq!(row.attempts, 1, "recovery leaves the attempt counter alone");
    assert_eq!(
        row.worker_id, None,
        "a requeued row must not still advertise the owner it was taken from"
    );

    // The heartbeat comes back, so the worker may take work again — it just has
    // no processor free to take any with.
    gate.rollback().await.unwrap();
    revive_worker_lease(&db, worker_id).await;
    wait_until(
        Duration::from_secs(30),
        Duration::from_millis(25),
        "the attempt recovery took the row from kept running",
        || async { !ticks.advanced(1, Duration::from_millis(100)).await },
    )
    .await;
    // The slot is the point: with one processor, the requeued row cannot be
    // worked at all until the displaced attempt lets go of it.
    wait_until(
        Duration::from_secs(30),
        Duration::from_millis(25),
        "the processor slot was never released",
        || async { ticks.count(2) > 0 },
    )
    .await;

    shutdown.cancel();
    run.await.unwrap().unwrap();
}

/// Clearing the owner is only half of it: the same worker can re-claim the very
/// row recovery took from it, as the next attempt. While in-flight attempts
/// were keyed by job id alone, that newcomer overwrote its predecessor's entry
/// and the displaced attempt was never asked about again — so it kept running,
/// two handlers deep on one job.
#[sqlx::test(migrations = "./migrations")]
async fn test_sweep_requeued_attempt_is_cancelled_when_its_own_worker_reclaims_the_row(
    pool: PgPool,
) {
    let db = TestDb::new(pool.clone()).await;
    let mut sweeper = db.queue.sweeper();
    assert!(sweeper.sweep().await.unwrap().leader);

    let ticks = AttemptTicks::new();
    let id = db
        .queue
        .enqueue(repro_sweep_requeued::job(()))
        .await
        .unwrap()
        .job_id();
    // Two processors, so the replacement attempt can start while the displaced
    // one is still holding a slot.
    let worker = requeue_worker(&db, &ticks, 2);
    let worker_id = worker.id();
    let shutdown = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));
    wait_until(
        Duration::from_secs(10),
        Duration::from_millis(10),
        "the first attempt never started",
        || async { ticks.count(1) > 0 },
    )
    .await;

    let gate = park_worker_heartbeats(&db).await;
    sweep_away_the_attempt(&db, &mut sweeper, id, worker_id).await;
    assert!(
        ticks.advanced(1, Duration::from_millis(60)).await,
        "the displaced attempt ended before its worker could re-claim the row, so \
         this run never reached the case the test is here for"
    );

    // The stalled worker's heartbeat comes back and it takes the same row as
    // attempt 2: two live attempts of one job on one worker.
    gate.rollback().await.unwrap();
    revive_worker_lease(&db, worker_id).await;
    wait_until(
        Duration::from_secs(10),
        Duration::from_millis(10),
        "the worker never re-claimed the requeued row",
        || async { ticks.count(2) > 0 },
    )
    .await;

    wait_until(
        Duration::from_secs(30),
        Duration::from_millis(25),
        "the attempt recovery took the row from kept running",
        || async { !ticks.advanced(1, Duration::from_millis(100)).await },
    )
    .await;
    assert!(
        ticks.advanced(2, Duration::from_millis(100)).await,
        "the attempt that owns the row must not be cancelled with its predecessor"
    );

    // The row is attempt 2's, and its cancelled predecessor wrote nothing.
    let row = db.queue.fetch_job(id).await.unwrap().expect("job row");
    assert_eq!(row.status, JobStatus::Running);
    assert_eq!(row.attempts, 2);
    assert_eq!(row.worker_id, Some(worker_id));

    shutdown.cancel();
    run.await.unwrap().unwrap();
}

// ---------------------------------------------------------------------------
// A worker lease that is already expired when it is written
// ---------------------------------------------------------------------------

/// `backoff` is a tagged `jsonb` this crate only ever writes from
/// `JobRetryBackoff`, but a row written by hand — or by a newer build during a
/// mixed-version rollout — can carry a tag this build has never heard of. The
/// dequeue statement commits server-side (`running`, `attempts + 1`,
/// `worker_id` set) and the client decodes the returned rows only afterwards,
/// so a strict decoder failed *after* the whole batch was already claimed:
/// every healthy job beside the poison row was stranded in `running`,
/// recoverable only by a sweeper that re-claimed them alongside the poison row
/// and lost them again, burning an attempt each cycle.
#[sqlx::test(migrations = "./migrations")]
async fn test_dequeue_claims_a_batch_carrying_an_unreadable_backoff(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let mut healthy = Vec::new();
    for index in 0..4 {
        healthy.push(
            db.queue
                .enqueue_raw(new_job(&format!("healthy-{index}"), |_| {}))
                .await
                .unwrap()
                .job_id(),
        );
    }
    let poison = db
        .queue
        .enqueue_raw(new_job("poison", |_| {}))
        .await
        .unwrap()
        .job_id();

    // A row that predates the column's CHECK is exactly what the decoder has to
    // survive; dropping it here is what puts one on disk.
    sqlx::query("ALTER TABLE pgqueue.jobs DROP CONSTRAINT IF EXISTS jobs_backoff_check")
        .execute(&pool)
        .await
        .unwrap();
    sqlx::query(r#"UPDATE pgqueue.jobs SET backoff = '{"type":"linear"}' WHERE id = $1"#)
        .bind(poison)
        .execute(&pool)
        .await
        .unwrap();

    let consumer = leased_consumer(&db.queue, Uuid::now_v7()).await;
    let batch = consumer
        .dequeue(10)
        .await
        .expect("one unreadable strategy must not fail the batch it rode in on");
    assert_eq!(
        batch.len(),
        5,
        "every row the statement claimed must reach the caller"
    );
    let claimed = batch
        .iter()
        .map(pgqueue::Attempt::job)
        .find(|row| row.id == poison)
        .expect("the poison row is claimed like any other");
    assert_eq!(
        claimed.backoff,
        pgqueue::JobRetryBackoff::None,
        "an unreadable strategy falls back to the flat retry delay"
    );

    // And the listing the operator would reach for to find the bad row keeps
    // working for the whole queue instead of failing outright.
    let page = db
        .queue
        .jobs_page(pgqueue::JobFilter::default())
        .await
        .expect("the listing must survive one unreadable strategy");
    assert_eq!(page.len(), 5, "the listing must still page the queue");
}

#[pgqueue::job(name = "repro_zero_timeout", max_attempts = 1)]
async fn repro_zero_timeout(_: ()) -> anyhow::Result<()> {
    tokio::time::sleep(Duration::from_millis(50)).await;
    Ok(())
}

/// `#[pgqueue::job(timeout_ms = 0)]` means "no timeout" and `JobConfig` refuses
/// a zero `Duration`, so 0 in the column is a value only a hand-written row
/// carries — and it decoded as `Some(Duration::ZERO)`, cancelling every attempt
/// before the handler could run its first statement. That is the harmful
/// reading of the two, which is the one `JobRetention::from_result_ttl_ms`
/// deliberately avoids for its own column.
#[sqlx::test(migrations = "./migrations")]
async fn test_worker_runs_an_attempt_whose_stored_timeout_is_zero(pool: PgPool) {
    // A grace the attempt cannot outlive: `pgqueue.job_is_stuck` reads the same
    // zero as `started_at + grace < now()`, so the default zero grace would
    // sweep the attempt out from under the reading actually under test.
    let db = TestDb::with(pool.clone(), |builder| {
        builder.sweep_grace(Duration::from_secs(300))
    })
    .await;
    let id = db
        .queue
        .enqueue(repro_zero_timeout::job(()))
        .await
        .unwrap()
        .job_id();

    // A row that predates the column's CHECK, as above.
    sqlx::query("ALTER TABLE pgqueue.jobs DROP CONSTRAINT IF EXISTS jobs_timeout_ms_check")
        .execute(&pool)
        .await
        .unwrap();
    sqlx::query("UPDATE pgqueue.jobs SET timeout_ms = 0 WHERE id = $1")
        .bind(id)
        .execute(&pool)
        .await
        .unwrap();

    Worker::builder(db.queue.clone())
        .register_job(repro_zero_timeout)
        .burst(true)
        .timers(test_timers())
        .dequeue_timeout(Duration::from_millis(50))
        .run()
        .await
        .unwrap();

    let row = db.queue.fetch_job(id).await.unwrap().unwrap();
    let error = row.error.clone().unwrap_or_default();
    assert_eq!(
        row.status,
        JobStatus::Complete,
        "a stored zero timeout must mean unlimited, not instant: {error}"
    );
}

#[sqlx::test(migrations = "./migrations")]
async fn test_shutdown_interrupts_the_dequeue_error_backoff(pool: PgPool) {
    let db = TestDb::new(pool.clone()).await;
    let worker = test_worker(db.queue.clone())
        .register_job(counts)
        .state(Arc::new(AtomicU32::new(0)))
        .build()
        .unwrap();
    let health = worker.health();
    let shutdown = CancellationToken::new();
    let run = tokio::spawn(worker.run_until(shutdown.clone()));
    wait_until(
        Duration::from_secs(3),
        Duration::from_millis(10),
        "worker did not report ready health",
        || async { health.snapshot().status == WorkerHealthStatus::Ready },
    )
    .await;

    // Break dequeues (and only dequeues, among the shutdown-path statements):
    // the workers table stays intact so intake close and lease writes succeed.
    sqlx::query("ALTER TABLE pgqueue.jobs RENAME TO jobs_hidden")
        .execute(&pool)
        .await
        .unwrap();

    // The fetch loop reports the dequeue failure immediately before its
    // 1-second error sleep, so health flipping to a Dequeue failure means the
    // sleep has just started.
    wait_until(
        Duration::from_secs(3),
        Duration::from_millis(5),
        "worker never reported a dequeue failure",
        || async {
            health
                .snapshot()
                .failures
                .iter()
                .any(|failure| failure.component == WorkerComponent::Dequeue)
        },
    )
    .await;

    // The fetcher is now no more than a few polls into its 1-second error
    // backoff. An uncancellable backoff holds shutdown for the rest of that
    // second (the caretaker joins the fetcher before releasing its lease);
    // racing it against `stop` ends it immediately. The bound leaves generous
    // headroom over a normal sub-100ms shutdown while staying well under the
    // ~1s an uninterrupted backoff would force.
    let started = std::time::Instant::now();
    shutdown.cancel();
    run.await.unwrap().unwrap();
    let elapsed = started.elapsed();
    assert!(
        elapsed < Duration::from_millis(700),
        "shutdown during the dequeue error backoff took {elapsed:?}"
    );
}
