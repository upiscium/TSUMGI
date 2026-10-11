"""PostgreSQL implementation of AstrumWeaver durable control state."""

from __future__ import annotations

from collections.abc import Iterator, Mapping
from hashlib import sha256
from contextlib import contextmanager
from datetime import datetime, timedelta
from typing import Any
from uuid import uuid4

from ..contracts import AcceleratorDevice, ResourceShape, WorkerSpec
from ..execution import JobResult
from ..scheduling import worker_matches
from ..serving import (
    ServingJobBinding,
    WorkerServingAdvertisement,
    worker_serving_accepts_job,
)
from .migrate import required_migration_names
from .models import (
    JobEventRecord,
    JobRecord,
    JobStatus,
    JobSubmission,
    WorkerHeartbeat,
    WorkerRecord,
    WorkerRegistration,
    WorkerState,
    utc_now,
)
from .repository import (
    ConflictError,
    DeadlineExceededError,
    EventBufferFull,
    NoCompatibleDeployment,
    NotFoundError,
    OverloadedError,
    RepositoryError,
    StorageUnavailable,
    _assert_worker_epoch,
    _aware,
    _event_size,
    _failure_payload,
    _lease_expiry,
    _submission_matches,
)
from .serde import (
    job_result_from_dict,
    job_result_to_dict,
    requirements_from_dict,
    requirements_to_dict,
)

try:
    import psycopg
    from psycopg.rows import dict_row
    from psycopg.types.json import Jsonb
except ImportError:  # pragma: no cover - optional dependency path
    psycopg = None  # type: ignore[assignment]
    dict_row = None  # type: ignore[assignment]
    Jsonb = None  # type: ignore[assignment,misc]


def _json(value: Any) -> Any:
    return Jsonb(value) if Jsonb is not None else value


def _json_optional(value: Any) -> Any:
    """Persist absent optional JSON as SQL NULL, not JSONB null."""
    return None if value is None else _json(value)


# Separate advisory namespaces prevent Worker identity locks and GPU locks
# from aliasing. Stable digest collisions only serialize unrelated identities.
_WORKER_OWNERSHIP_LOCK = 0x41535701
_GPU_OWNERSHIP_LOCK = 0x41535702


def _ownership_lock_key(identity: str) -> int:
    return int.from_bytes(sha256(identity.encode("utf-8")).digest()[:4], "big", signed=True)


class PostgresControlRepository:
    """Transactional PostgreSQL control-plane repository."""

    def check_storage(self) -> None:
        try:
            required = required_migration_names()
        except RuntimeError as exc:
            raise StorageUnavailable(
                "postgresql migration metadata is unavailable"
            ) from exc

        with self._connection() as connection:
            row = connection.execute(
                """
                SELECT
                    to_regclass('public.workers') AS workers,
                    to_regclass('public.jobs') AS jobs,
                    to_regclass('public.job_events') AS job_events,
                    to_regclass('public.schema_migrations') AS schema_migrations
                """
            ).fetchone()
            if (
                not row
                or row.get("workers") is None
                or row.get("jobs") is None
                or row.get("job_events") is None
                or row.get("schema_migrations") is None
            ):
                raise StorageUnavailable("postgresql schema is unavailable")

            applied_rows = connection.execute(
                "SELECT name FROM schema_migrations"
            ).fetchall()

        applied = {str(item["name"]) for item in applied_rows}
        missing = [name for name in required if name not in applied]
        if missing:
            raise StorageUnavailable(
                "postgresql schema migrations are incomplete: "
                + ", ".join(missing)
            )


    def __init__(
        self,
        database_url: str,
        *,
        worker_ttl_seconds: int = 60,
        lease_seconds: int = 300,
        event_max_count: int = 4096,
        event_max_payload_bytes: int = 65536,
        event_max_total_bytes: int = 4 * 1024 * 1024,
        event_max_read: int = 512,
    ) -> None:
        if not database_url:
            raise ValueError("database_url is required")
        for value, name in (
            (worker_ttl_seconds, "worker_ttl_seconds"),
            (lease_seconds, "lease_seconds"),
            (event_max_count, "event_max_count"),
            (event_max_payload_bytes, "event_max_payload_bytes"),
            (event_max_total_bytes, "event_max_total_bytes"),
            (event_max_read, "event_max_read"),
        ):
            if type(value) is not int or value < 1:
                raise ValueError(f"{name} must be a positive integer")
        self.database_url = database_url
        self.worker_ttl_seconds = worker_ttl_seconds
        self.lease_seconds = lease_seconds
        self.event_max_count = event_max_count
        self.event_max_payload_bytes = event_max_payload_bytes
        self.event_max_total_bytes = event_max_total_bytes
        self.event_max_read = event_max_read

    @contextmanager
    def _connection(self) -> Iterator[Any]:
        if psycopg is None:
            raise StorageUnavailable(
                "PostgreSQL support requires the astrumweaver postgres dependency"
            )
        try:
            connection = psycopg.connect(self.database_url, row_factory=dict_row)
        except Exception as exc:
            raise StorageUnavailable("postgresql is unavailable") from exc
        try:
            yield connection
        finally:
            connection.close()

    @contextmanager
    def _transaction(self) -> Iterator[Any]:
        with self._connection() as connection:
            try:
                with connection.transaction():
                    # Ownership predicates must see a fresh snapshot after an
                    # advisory-lock wait, independent of the database default.
                    connection.execute("SET TRANSACTION ISOLATION LEVEL READ COMMITTED")
                    yield connection
            except RepositoryError:
                raise
            except Exception as exc:
                raise StorageUnavailable("postgresql transaction failed") from exc

    @staticmethod
    def _worker(row: dict[str, Any]) -> WorkerRecord:
        spec = WorkerSpec(
            worker_id=row["id"],
            worker_class=row["worker_class"],
            gpu_uuids=tuple(row.get("gpu_uuids") or ()),
            accelerators=tuple(
                AcceleratorDevice(
                    uuid=str(item["uuid"]),
                    memory_mb=int(item["memory_mb"]),
                    compute_capability=item.get("compute_capability"),
                    device_class=item.get("device_class"),
                )
                for item in row.get("accelerators") or ()
            ),
            capabilities=frozenset(row.get("capabilities") or ()),
            labels=row.get("labels") or {},
            resources=ResourceShape(
                gpu_count=int(row.get("gpu_count") or 0),
                total_vram_mb=int(row.get("total_vram_mb") or 0),
                max_single_gpu_vram_mb=int(row.get("max_single_gpu_vram_mb") or 0),
            ),
        )
        return WorkerRecord(
            spec=spec,
            max_concurrency=int(row["max_concurrency"]),
            state=WorkerState(row["state"]),
            active_jobs=int(row.get("active_jobs") or 0),
            registered_at=row["registered_at"],
            last_seen_at=row["last_seen_at"],
            metadata=row.get("metadata") or {},
            serving=(
                None
                if row.get("serving") is None
                else WorkerServingAdvertisement.from_dict(row["serving"])
            ),
        )

    @staticmethod
    def _event(row: dict[str, Any]) -> JobEventRecord:
        return JobEventRecord(
            job_id=str(row["job_id"]),
            attempt=int(row["attempt"]),
            sequence=int(row["sequence"]),
            worker_id=str(row["worker_id"]),
            runtime_instance_epoch=row.get("runtime_instance_epoch"),
            kind=str(row["kind"]),
            payload=row.get("payload") or {},
            created_at=row["created_at"],
        )

    @staticmethod
    def _job(row: dict[str, Any]) -> JobRecord:
        return JobRecord(
            job_id=str(row["id"]),
            capability=row["capability"],
            payload=row.get("payload") or {},
            requirements=requirements_from_dict(row.get("requirements")),
            priority=int(row["priority"]),
            sequence=int(row["sequence"]),
            status=JobStatus(row["status"]),
            attempts=int(row["attempts"]),
            max_attempts=int(row["max_attempts"]),
            idempotency_key=row.get("idempotency_key"),
            assigned_worker_id=row.get("assigned_worker_id"),
            lease_token=row.get("lease_token"),
            result=job_result_from_dict(row.get("result")),
            error=row.get("error"),
            created_at=row["created_at"],
            available_at=row["available_at"],
            started_at=row.get("started_at"),
            finished_at=row.get("finished_at"),
            lease_expires_at=row.get("lease_expires_at"),
            deadline_at=row.get("deadline_at"),
            serving=(
                None
                if row.get("serving") is None
                else ServingJobBinding.from_dict(row["serving"])
            ),
            claimed_deployment_revision=row.get("claimed_deployment_revision"),
            claimed_serving_contract_revision=row.get(
                "claimed_serving_contract_revision"
            ),
            claimed_runtime_instance_epoch=row.get(
                "claimed_runtime_instance_epoch"
            ),
            updated_at=row["updated_at"],
        )

    def _lock_worker_ownership(
        self,
        connection: Any,
        worker_id: str,
        requested_gpu_uuids: tuple[str, ...] = (),
    ) -> dict[str, Any] | None:
        """Serialize acquisition, including a Worker/GPU with no row yet.

        Enrollment/state transitions take identity -> sorted GPU lock keys ->
        own Worker row. They never lock peer Worker rows or job rows. Job
        transactions retain job -> Worker order and do not take advisory locks.
        Release-only updates need no advisory lock: they can remove, but cannot
        introduce, an owner. Reacquisition must pass through this method.
        """
        connection.execute(
            "SELECT pg_advisory_xact_lock(%s::integer, %s::integer)",
            (_WORKER_OWNERSHIP_LOCK, _ownership_lock_key(worker_id)),
        )
        current = connection.execute(
            "SELECT gpu_uuids FROM workers WHERE id = %s", (worker_id,)
        ).fetchone()
        # The identity lock prevents concurrent enrollment from changing this
        # topology while GPU locks are acquired. Include old and desired GPUs
        # so topology replacement and resource handoff use one protocol.
        gpu_uuids = set(requested_gpu_uuids)
        if current is not None:
            gpu_uuids.update(current.get("gpu_uuids") or ())
        for key in sorted({_ownership_lock_key(uuid) for uuid in gpu_uuids}):
            connection.execute(
                "SELECT pg_advisory_xact_lock(%s::integer, %s::integer)",
                (_GPU_OWNERSHIP_LOCK, key),
            )
        # Liveness and active-job counts may have changed during a lock wait.
        # Read/lock the current row only after acquiring the entire GPU set.
        return connection.execute(
            "SELECT * FROM workers WHERE id = %s FOR UPDATE", (worker_id,)
        ).fetchone()

    def _gpu_overlap(
        self,
        connection: Any,
        registration: WorkerRegistration,
    ) -> str | None:
        gpu_uuids = list(registration.spec.gpu_uuids)
        if not gpu_uuids:
            return None
        row = connection.execute(
            """
            SELECT id
            FROM workers
            WHERE id <> %s
              AND (state <> 'offline' OR active_jobs > 0)
              AND EXISTS (
                  SELECT 1
                  FROM jsonb_array_elements_text(%s::jsonb) AS requested(uuid)
                  WHERE gpu_uuids ? requested.uuid
              )
            ORDER BY id
            LIMIT 1
            """,
            (registration.spec.worker_id, _json(gpu_uuids)),
        ).fetchone()
        return None if row is None else str(row["id"])

    def register_worker(
        self, registration: WorkerRegistration, *, now: datetime | None = None
    ) -> WorkerRecord:
        timestamp = _aware(now)
        spec = registration.spec
        with self._transaction() as connection:
            existing = self._lock_worker_ownership(
                connection, spec.worker_id, spec.gpu_uuids
            )
            if existing is not None:
                current = self._worker(existing)
                if current.active_jobs > 0:
                    if registration.spec != current.spec:
                        raise ConflictError(
                            "worker resource/topology cannot change while jobs are active"
                        )
                    if registration.max_concurrency < current.active_jobs:
                        raise ConflictError(
                            "max_concurrency cannot be lower than active job count"
                        )
                    if registration.serving != current.serving:
                        raise ConflictError(
                            "worker serving deployment cannot change while jobs are active"
                        )

            conflicting = self._gpu_overlap(connection, registration)
            if conflicting:
                raise ConflictError(
                    f"GPU identity overlaps with worker {conflicting}"
                )

            registered_at = existing["registered_at"] if existing else timestamp
            active_jobs = connection.execute(
                """
                SELECT count(*)::integer AS count
                FROM jobs
                WHERE status = 'running' AND assigned_worker_id = %s
                """,
                (spec.worker_id,),
            ).fetchone()["count"]

            row = connection.execute(
                """
                INSERT INTO workers (
                    id, worker_class, capabilities, labels, gpu_uuids,
                    accelerators, gpu_count, total_vram_mb, max_single_gpu_vram_mb,
                    max_concurrency, state, metadata, serving, registered_at,
                    last_seen_at, active_jobs, updated_at
                ) VALUES (
                    %s, %s, %s, %s, %s,
                    %s, %s, %s, %s,
                    %s, 'online', %s, %s, %s,
                    %s, %s, %s
                )
                ON CONFLICT (id) DO UPDATE SET
                    worker_class = EXCLUDED.worker_class,
                    capabilities = EXCLUDED.capabilities,
                    labels = EXCLUDED.labels,
                    gpu_uuids = EXCLUDED.gpu_uuids,
                    accelerators = EXCLUDED.accelerators,
                    gpu_count = EXCLUDED.gpu_count,
                    total_vram_mb = EXCLUDED.total_vram_mb,
                    max_single_gpu_vram_mb = EXCLUDED.max_single_gpu_vram_mb,
                    max_concurrency = EXCLUDED.max_concurrency,
                    state = 'online',
                    metadata = EXCLUDED.metadata,
                    serving = EXCLUDED.serving,
                    last_seen_at = EXCLUDED.last_seen_at,
                    active_jobs = EXCLUDED.active_jobs,
                    updated_at = EXCLUDED.updated_at
                RETURNING *
                """,
                (
                    spec.worker_id,
                    spec.worker_class,
                    _json(sorted(spec.capabilities)),
                    _json(dict(spec.labels)),
                    _json(list(spec.gpu_uuids)),
                    _json(
                        [
                            {
                                "uuid": device.uuid,
                                "memory_mb": device.memory_mb,
                                "compute_capability": device.compute_capability,
                                "device_class": device.device_class,
                            }
                            for device in spec.accelerators
                        ]
                    ),
                    spec.resources.gpu_count,
                    spec.resources.total_vram_mb,
                    spec.resources.max_single_gpu_vram_mb,
                    registration.max_concurrency,
                    _json(dict(registration.metadata)),
                    _json_optional(
                        None
                        if registration.serving is None
                        else registration.serving.to_dict()
                    ),
                    registered_at,
                    timestamp,
                    active_jobs,
                    timestamp,
                ),
            ).fetchone()
            return self._worker(row)

    def get_worker(self, worker_id: str) -> WorkerRecord:
        with self._connection() as connection:
            row = connection.execute(
                "SELECT * FROM workers WHERE id = %s", (worker_id,)
            ).fetchone()
        if row is None:
            raise NotFoundError(f"worker not found: {worker_id}")
        return self._worker(row)

    def set_worker_state(
        self,
        worker_id: str,
        state: WorkerState,
        *,
        runtime_instance_epoch: str | None = None,
        now: datetime | None = None,
    ) -> WorkerRecord:
        timestamp = _aware(now)
        with self._transaction() as connection:
            current_row = self._lock_worker_ownership(connection, worker_id)
            if current_row is None:
                raise NotFoundError(f"worker not found: {worker_id}")
            current = self._worker(current_row)
            _assert_worker_epoch(current, runtime_instance_epoch)
            if state is not WorkerState.OFFLINE:
                conflict = self._gpu_overlap(
                    connection,
                    WorkerRegistration(
                        spec=current.spec,
                        max_concurrency=current.max_concurrency,
                        metadata=current.metadata,
                        serving=current.serving,
                    ),
                )
                if conflict:
                    raise ConflictError(
                        f"GPU identity overlaps with worker {conflict}"
                    )
            row = connection.execute(
                """
                UPDATE workers
                SET state = %s, last_seen_at = %s, updated_at = %s
                WHERE id = %s
                RETURNING *
                """,
                (state.value, timestamp, timestamp, worker_id),
            ).fetchone()
            return self._worker(row)

    def heartbeat_worker(
        self,
        worker_id: str,
        heartbeat: WorkerHeartbeat | None = None,
        *,
        now: datetime | None = None,
    ) -> WorkerRecord:
        timestamp = _aware(now)
        heartbeat = heartbeat or WorkerHeartbeat()
        with self._transaction() as connection:
            # Keep the global lock order job -> worker whenever a job is
            # involved. Claim/completion/recovery use the same order.
            if heartbeat.active_job_id is not None or heartbeat.lease_token is not None:
                if not heartbeat.active_job_id or not heartbeat.lease_token:
                    raise ConflictError(
                        "active_job_id and lease_token must be supplied together"
                    )
                job_row = connection.execute(
                    "SELECT * FROM jobs WHERE id::text = %s FOR UPDATE",
                    (heartbeat.active_job_id,),
                ).fetchone()
                if job_row is None:
                    raise NotFoundError(
                        f"job not found: {heartbeat.active_job_id}"
                    )
                self._assert_running_row(
                    job_row,
                    worker_id=worker_id,
                    lease_token=heartbeat.lease_token,
                    runtime_instance_epoch=heartbeat.runtime_instance_epoch,
                    now=timestamp,
                )
                connection.execute(
                    """
                    UPDATE jobs
                    SET lease_expires_at = %s, updated_at = %s
                    WHERE id = %s
                    """,
                    (
                        _lease_expiry(
                            timestamp,
                            self.lease_seconds,
                            job_row.get("deadline_at"),
                        ),
                        timestamp,
                        job_row["id"],
                    ),
                )

            worker_row = connection.execute(
                "SELECT * FROM workers WHERE id = %s FOR UPDATE", (worker_id,)
            ).fetchone()
            if worker_row is None:
                raise NotFoundError(f"worker not found: {worker_id}")
            current = self._worker(worker_row)
            _assert_worker_epoch(current, heartbeat.runtime_instance_epoch)
            if current.state is WorkerState.OFFLINE and heartbeat.state in {
                WorkerState.ONLINE, WorkerState.DRAINING,
            }:
                raise ConflictError("offline worker must explicitly reacquire GPU ownership")

            active_jobs = connection.execute(
                """
                SELECT count(*)::integer AS count
                FROM jobs
                WHERE status = 'running' AND assigned_worker_id = %s
                """,
                (worker_id,),
            ).fetchone()["count"]
            state = (heartbeat.state or current.state).value
            metadata = {**dict(current.metadata), **dict(heartbeat.metadata)}
            row = connection.execute(
                """
                UPDATE workers
                SET state = %s, last_seen_at = %s, active_jobs = %s,
                    metadata = %s, updated_at = %s
                WHERE id = %s
                RETURNING *
                """,
                (
                    state,
                    timestamp,
                    active_jobs,
                    _json(metadata),
                    timestamp,
                    worker_id,
                ),
            ).fetchone()
            return self._worker(row)

    def expire_stale_workers(
        self, *, now: datetime | None = None
    ) -> list[WorkerRecord]:
        timestamp = _aware(now)
        cutoff = timestamp - timedelta(seconds=self.worker_ttl_seconds)
        with self._transaction() as connection:
            rows = connection.execute(
                """
                UPDATE workers
                SET state = 'offline', updated_at = %s
                WHERE state <> 'offline' AND last_seen_at < %s
                RETURNING *
                """,
                (timestamp, cutoff),
            ).fetchall()
        return [self._worker(row) for row in rows]

    def expire_deadline_jobs(
        self, *, now: datetime | None = None
    ) -> list[JobRecord]:
        timestamp = _aware(now)
        expired: list[JobRecord] = []
        while True:
            with self._transaction() as connection:
                row = connection.execute(
                    """
                    SELECT *
                    FROM jobs
                    WHERE status IN ('queued', 'running')
                      AND deadline_at IS NOT NULL
                      AND deadline_at <= %s
                    ORDER BY sequence ASC
                    FOR UPDATE SKIP LOCKED
                    LIMIT 1
                    """,
                    (timestamp,),
                ).fetchone()
                if row is None:
                    return expired
                was_running = row["status"] == JobStatus.RUNNING.value
                updated = connection.execute(
                    """
                    UPDATE jobs
                    SET status = 'failed',
                        error = %s,
                        assigned_worker_id = NULL,
                        lease_token = NULL,
                        lease_expires_at = NULL,
                        finished_at = %s,
                        updated_at = %s
                    WHERE id = %s
                    RETURNING *
                    """,
                    (
                        _json(
                            {
                                "type": "deadline_expired",
                                "message": "job deadline expired",
                                "retryable": False,
                            }
                        ),
                        timestamp,
                        timestamp,
                        row["id"],
                    ),
                ).fetchone()
                if was_running:
                    self._decrement_worker(
                        connection, row.get("assigned_worker_id"), timestamp
                    )
                expired.append(self._job(updated))

    def submit_job(
        self, submission: JobSubmission, *, now: datetime | None = None
    ) -> JobRecord:
        timestamp = _aware(now)
        available_at = (
            _aware(submission.available_at)
            if submission.available_at is not None
            else timestamp
        )
        job_id = str(uuid4())
        requirements = requirements_to_dict(submission.requirements)

        with self._transaction() as connection:
            # Resolve durable idempotency before transient admission state.
            if submission.idempotency_key:
                existing = connection.execute(
                    """
                    SELECT * FROM jobs
                    WHERE idempotency_key = %s
                    FOR UPDATE
                    """,
                    (submission.idempotency_key,),
                ).fetchone()
                if existing is not None:
                    record = self._job(existing)
                    if not _submission_matches(record, submission):
                        raise ConflictError(
                            "idempotency key already belongs to a different job request"
                        )
                    return record

            if (
                submission.deadline_at is not None
                and _aware(submission.deadline_at) <= timestamp
            ):
                raise DeadlineExceededError("job deadline has expired")

            if submission.serving is not None:
                cutoff = timestamp - timedelta(seconds=self.worker_ttl_seconds)
                candidate_rows = connection.execute(
                    """
                    SELECT * FROM workers
                    WHERE state = 'online'
                      AND last_seen_at >= %s
                      AND capabilities ? %s
                    """,
                    (cutoff, submission.capability),
                ).fetchall()
                compatible = [
                    worker
                    for worker in (self._worker(row) for row in candidate_rows)
                    if worker_matches(worker.spec, submission.requirements)
                    and worker_serving_accepts_job(
                        worker.serving, submission.capability, submission.serving
                    )
                ]
                if not compatible:
                    raise NoCompatibleDeployment(
                        "no compatible serving deployment is available"
                    )
                if all(
                    worker.active_jobs >= worker.max_concurrency
                    for worker in compatible
                ):
                    raise OverloadedError(
                        "all compatible serving deployments are at capacity"
                    )

            row = connection.execute(
                """
                INSERT INTO jobs (
                    id, capability, payload, requirements, priority,
                    attempts, max_attempts, idempotency_key,
                    created_at, available_at, deadline_at, serving, updated_at
                ) VALUES (
                    %s, %s, %s, %s, %s,
                    0, %s, %s,
                    %s, %s, %s, %s, %s
                )
                ON CONFLICT (idempotency_key) DO NOTHING
                RETURNING *
                """,
                (
                    job_id,
                    submission.capability,
                    _json(dict(submission.payload)),
                    _json(requirements),
                    submission.priority,
                    submission.max_attempts,
                    submission.idempotency_key,
                    timestamp,
                    available_at,
                    None if submission.deadline_at is None else _aware(submission.deadline_at),
                    _json_optional(
                        None
                        if submission.serving is None
                        else submission.serving.to_dict()
                    ),
                    timestamp,
                ),
            ).fetchone()
            if row is not None:
                return self._job(row)

            existing = connection.execute(
                """
                SELECT * FROM jobs
                WHERE idempotency_key = %s
                FOR UPDATE
                """,
                (submission.idempotency_key,),
            ).fetchone()
            if existing is None:
                raise StorageUnavailable("idempotent job insert did not persist")
            record = self._job(existing)
            if not _submission_matches(record, submission):
                raise ConflictError(
                    "idempotency key already belongs to a different job request"
                )
            return record

    def get_job(self, job_id: str) -> JobRecord:
        with self._connection() as connection:
            row = connection.execute(
                "SELECT * FROM jobs WHERE id::text = %s", (job_id,)
            ).fetchone()
        if row is None:
            raise NotFoundError(f"job not found: {job_id}")
        return self._job(row)

    def append_job_event(
        self,
        job_id: str,
        *,
        worker_id: str,
        lease_token: str,
        runtime_instance_epoch: str | None,
        kind: str,
        payload: Mapping[str, object],
        now: datetime | None = None,
    ) -> JobEventRecord:
        timestamp = _aware(now)
        normalized_kind = str(kind).strip()
        if not normalized_kind:
            raise ValueError("event kind must not be blank")
        size = _event_size(normalized_kind, payload)
        if size > self.event_max_payload_bytes:
            raise EventBufferFull("job event payload exceeds the configured limit")

        with self._transaction() as connection:
            job_row = connection.execute(
                "SELECT * FROM jobs WHERE id::text = %s FOR UPDATE",
                (job_id,),
            ).fetchone()
            if job_row is None:
                raise NotFoundError(f"job not found: {job_id}")
            self._assert_running_row(
                job_row,
                worker_id=worker_id,
                lease_token=lease_token,
                runtime_instance_epoch=runtime_instance_epoch,
                now=timestamp,
            )
            claimed_epoch = job_row.get("claimed_runtime_instance_epoch")
            if runtime_instance_epoch != claimed_epoch:
                raise ConflictError(f"job {job_id} runtime instance is stale")

            aggregate = connection.execute(
                """
                SELECT
                    count(*)::integer AS event_count,
                    COALESCE(sum(payload_bytes), 0)::bigint AS total_bytes,
                    COALESCE(max(sequence), 0)::bigint AS last_sequence
                FROM job_events
                WHERE job_id = %s
                """,
                (job_row["id"],),
            ).fetchone()
            if int(aggregate["event_count"]) >= self.event_max_count:
                raise EventBufferFull("job event count exceeds the configured limit")
            if int(aggregate["total_bytes"]) + size > self.event_max_total_bytes:
                raise EventBufferFull("job event buffer exceeds the configured byte limit")
            sequence = int(aggregate["last_sequence"]) + 1

            row = connection.execute(
                """
                INSERT INTO job_events (
                    job_id, sequence, attempt, worker_id,
                    runtime_instance_epoch, kind, payload,
                    payload_bytes, created_at
                ) VALUES (
                    %s, %s, %s, %s,
                    %s, %s, %s,
                    %s, %s
                )
                RETURNING *
                """,
                (
                    job_row["id"],
                    sequence,
                    int(job_row["attempts"]),
                    worker_id,
                    claimed_epoch,
                    normalized_kind,
                    _json(dict(payload)),
                    size,
                    timestamp,
                ),
            ).fetchone()
            return self._event(row)

    def list_job_events(
        self,
        job_id: str,
        *,
        after_sequence: int = 0,
        limit: int = 128,
    ) -> list[JobEventRecord]:
        if type(after_sequence) is not int or after_sequence < 0:
            raise ValueError("after_sequence must be a non-negative integer")
        if type(limit) is not int or not 1 <= limit <= self.event_max_read:
            raise ValueError("event read limit is outside the configured bound")
        with self._connection() as connection:
            exists = connection.execute(
                "SELECT 1 FROM jobs WHERE id::text = %s",
                (job_id,),
            ).fetchone()
            if exists is None:
                raise NotFoundError(f"job not found: {job_id}")
            rows = connection.execute(
                """
                SELECT *
                FROM job_events
                WHERE job_id::text = %s
                  AND sequence > %s
                ORDER BY sequence ASC
                LIMIT %s
                """,
                (job_id, after_sequence, limit),
            ).fetchall()
        return [self._event(row) for row in rows]

    def claim_next_job(
        self,
        worker_id: str,
        *,
        runtime_instance_epoch: str | None = None,
        now: datetime | None = None,
    ) -> JobRecord | None:
        timestamp = _aware(now)
        cutoff = timestamp - timedelta(seconds=self.worker_ttl_seconds)
        with self._transaction() as connection:
            worker_row = connection.execute(
                "SELECT * FROM workers WHERE id = %s", (worker_id,)
            ).fetchone()
            if worker_row is None:
                raise NotFoundError(f"worker not found: {worker_id}")
            worker = self._worker(worker_row)
            _assert_worker_epoch(worker, runtime_instance_epoch)
            if worker.last_seen_at < cutoff:
                connection.execute(
                    """
                    UPDATE workers
                    SET state = 'offline', updated_at = %s
                    WHERE id = %s
                    """,
                    (timestamp, worker_id),
                )
                return None
            if worker.state is not WorkerState.ONLINE:
                return None

            row = connection.execute(
                """
                SELECT j.*
                FROM jobs AS j
                WHERE j.status = 'queued'
                  AND j.available_at <= %s
                  AND (j.deadline_at IS NULL OR j.deadline_at > %s)
                  AND j.attempts < j.max_attempts
                  AND %s::jsonb ? j.capability
                  AND (
                      j.requirements->>'worker_class' IS NULL
                      OR j.requirements->>'worker_class' = %s
                  )
                  AND NOT EXISTS (
                      SELECT 1
                      FROM jsonb_array_elements_text(
                          COALESCE(j.requirements->'required_capabilities', '[]'::jsonb)
                      ) AS required(capability)
                      WHERE NOT (%s::jsonb ? required.capability)
                  )
                  AND COALESCE(j.requirements->'required_labels', '{}'::jsonb) <@ %s::jsonb
                  AND NOT EXISTS (
                      SELECT 1
                      FROM jsonb_array_elements_text(
                          COALESCE(j.requirements->'required_gpu_uuids', '[]'::jsonb)
                      ) AS required(uuid)
                      WHERE NOT (%s::jsonb ? required.uuid)
                  )
                  AND %s >= COALESCE(
                      (j.requirements->>'min_gpu_count')::integer, 0
                  )
                  AND %s >= COALESCE(
                      (j.requirements->>'min_total_vram_mb')::integer, 0
                  )
                  AND %s >= COALESCE(
                      (j.requirements->>'min_single_gpu_vram_mb')::integer, 0
                  )
                  AND (
                      (
                          j.serving IS NULL
                          AND NOT EXISTS (
                              SELECT 1
                              FROM jsonb_array_elements(
                                  COALESCE(%s::jsonb->'contracts', '[]'::jsonb)
                              ) AS covered(item)
                              WHERE covered.item->'contract'->>'capability'
                                    = j.capability
                          )
                      )
                      OR (
                          %s::jsonb IS NOT NULL
                          AND %s::jsonb->>'deployment_revision'
                              = j.serving->>'deployment_revision'
                          AND EXISTS (
                              SELECT 1
                              FROM jsonb_array_elements(
                                  COALESCE(%s::jsonb->'contracts', '[]'::jsonb)
                              ) AS advertised(item)
                              WHERE advertised.item->>'serving_contract_revision'
                                    = j.serving->>'serving_contract_revision'
                                AND advertised.item->'contract'->>'capability'
                                    = j.serving->>'capability'
                                AND advertised.item->'contract'->>'operation_schema'
                                    = j.serving->>'operation_schema'
                          )
                      )
                  )
                  AND (
                      SELECT w.active_jobs < w.max_concurrency
                      FROM workers AS w
                      WHERE w.id = %s
                  )
                ORDER BY j.priority DESC, j.sequence ASC
                FOR UPDATE SKIP LOCKED
                LIMIT 1
                """,
                (
                    timestamp,
                    timestamp,
                    _json(sorted(worker.spec.capabilities)),
                    worker.spec.worker_class,
                    _json(sorted(worker.spec.capabilities)),
                    _json(dict(worker.spec.labels)),
                    _json(list(worker.spec.gpu_uuids)),
                    worker.spec.resources.gpu_count,
                    worker.spec.resources.total_vram_mb,
                    worker.spec.resources.max_single_gpu_vram_mb,
                    _json_optional(
                        None if worker.serving is None else worker.serving.to_dict()
                    ),
                    _json_optional(
                        None if worker.serving is None else worker.serving.to_dict()
                    ),
                    _json_optional(
                        None if worker.serving is None else worker.serving.to_dict()
                    ),
                    _json_optional(
                        None if worker.serving is None else worker.serving.to_dict()
                    ),
                    worker_id,
                ),
            ).fetchone()
            if row is None:
                return None

            locked_worker_row = connection.execute(
                "SELECT * FROM workers WHERE id = %s FOR UPDATE", (worker_id,)
            ).fetchone()
            if locked_worker_row is None:
                raise NotFoundError(f"worker not found: {worker_id}")
            locked_worker = self._worker(locked_worker_row)
            _assert_worker_epoch(locked_worker, runtime_instance_epoch)
            if (
                locked_worker.last_seen_at < cutoff
                or locked_worker.state is not WorkerState.ONLINE
                or locked_worker.active_jobs >= locked_worker.max_concurrency
            ):
                return None

            selected = self._job(row)
            if (
                selected.capability not in locked_worker.spec.capabilities
                or not worker_matches(locked_worker.spec, selected.requirements)
                or not worker_serving_accepts_job(locked_worker.serving, selected.capability, selected.serving)
            ):
                return None

            lease_token = str(uuid4())
            claimed_deployment_revision = (
                None
                if selected.serving is None
                else locked_worker.serving.deployment_revision
            )
            claimed_serving_contract_revision = (
                None
                if selected.serving is None
                else selected.serving.serving_contract_revision
            )
            claimed_runtime_instance_epoch = (
                None
                if selected.serving is None
                else locked_worker.serving.runtime_instance.epoch
            )
            claimed_row = connection.execute(
                """
                UPDATE jobs
                SET status = 'running',
                    attempts = attempts + 1,
                    assigned_worker_id = %s,
                    lease_token = %s,
                    lease_expires_at = %s,
                    claimed_deployment_revision = %s,
                    claimed_serving_contract_revision = %s,
                    claimed_runtime_instance_epoch = %s,
                    started_at = %s,
                    finished_at = NULL,
                    error = NULL,
                    updated_at = %s
                WHERE id = %s
                RETURNING *
                """,
                (
                    worker_id,
                    lease_token,
                    _lease_expiry(
                        timestamp,
                        self.lease_seconds,
                        selected.deadline_at,
                    ),
                    claimed_deployment_revision,
                    claimed_serving_contract_revision,
                    claimed_runtime_instance_epoch,
                    timestamp,
                    timestamp,
                    row["id"],
                ),
            ).fetchone()
            connection.execute(
                """
                UPDATE workers
                SET active_jobs = active_jobs + 1, updated_at = %s
                WHERE id = %s
                """,
                (timestamp, worker_id),
            )
            return self._job(claimed_row)

    @staticmethod
    def _assert_running_row(
        row: dict[str, Any],
        *,
        worker_id: str,
        lease_token: str,
        runtime_instance_epoch: str | None,
        now: datetime,
    ) -> None:
        if row["status"] != JobStatus.RUNNING.value:
            raise ConflictError(f"job {row['id']} is not running")
        if row.get("assigned_worker_id") != worker_id:
            raise ConflictError(f"job {row['id']} is assigned to another worker")
        if not lease_token or row.get("lease_token") != lease_token:
            raise ConflictError(f"job {row['id']} lease token is stale")
        expires_at = row.get("lease_expires_at")
        if expires_at is None or expires_at <= now:
            raise ConflictError(f"job {row['id']} lease has expired")
        deadline_at = row.get("deadline_at")
        if deadline_at is not None and deadline_at <= now:
            raise ConflictError(f"job {row['id']} deadline has expired")
        claimed_epoch = row.get("claimed_runtime_instance_epoch")
        if claimed_epoch is not None and runtime_instance_epoch != claimed_epoch:
            raise ConflictError(f"job {row['id']} runtime instance is stale")

    @staticmethod
    def _decrement_worker(
        connection: Any, worker_id: str | None, timestamp: datetime
    ) -> None:
        if worker_id is None:
            return
        connection.execute(
            """
            UPDATE workers
            SET active_jobs = GREATEST(active_jobs - 1, 0), updated_at = %s
            WHERE id = %s
            """,
            (timestamp, worker_id),
        )

    def complete_job(
        self,
        job_id: str,
        result: JobResult,
        *,
        worker_id: str,
        lease_token: str,
        runtime_instance_epoch: str | None = None,
        now: datetime | None = None,
    ) -> JobRecord:
        if not isinstance(result, JobResult):
            raise TypeError("result must be JobResult")
        timestamp = _aware(now)
        with self._transaction() as connection:
            row = connection.execute(
                "SELECT * FROM jobs WHERE id::text = %s FOR UPDATE", (job_id,)
            ).fetchone()
            if row is None:
                raise NotFoundError(f"job not found: {job_id}")
            self._assert_running_row(
                row,
                worker_id=worker_id,
                lease_token=lease_token,
                runtime_instance_epoch=runtime_instance_epoch,
                now=timestamp,
            )
            updated = connection.execute(
                """
                UPDATE jobs
                SET status = 'succeeded',
                    result = %s,
                    error = NULL,
                    assigned_worker_id = NULL,
                    lease_token = NULL,
                    lease_expires_at = NULL,
                    finished_at = %s,
                    updated_at = %s
                WHERE id = %s
                RETURNING *
                """,
                (
                    _json(job_result_to_dict(result)),
                    timestamp,
                    timestamp,
                    row["id"],
                ),
            ).fetchone()
            self._decrement_worker(connection, worker_id, timestamp)
            return self._job(updated)

    def fail_job(
        self,
        job_id: str,
        error: str | dict[str, object],
        *,
        retryable: bool,
        worker_id: str,
        lease_token: str,
        runtime_instance_epoch: str | None = None,
        now: datetime | None = None,
    ) -> JobRecord:
        timestamp = _aware(now)
        with self._transaction() as connection:
            row = connection.execute(
                "SELECT * FROM jobs WHERE id::text = %s FOR UPDATE", (job_id,)
            ).fetchone()
            if row is None:
                raise NotFoundError(f"job not found: {job_id}")
            self._assert_running_row(
                row,
                worker_id=worker_id,
                lease_token=lease_token,
                runtime_instance_epoch=runtime_instance_epoch,
                now=timestamp,
            )
            should_retry = (
                retryable
                and int(row["attempts"]) < int(row["max_attempts"])
                and (row.get("deadline_at") is None or row["deadline_at"] > timestamp)
            )
            status = JobStatus.QUEUED if should_retry else JobStatus.FAILED
            updated = connection.execute(
                """
                UPDATE jobs
                SET status = %s,
                    error = %s,
                    assigned_worker_id = NULL,
                    lease_token = NULL,
                    lease_expires_at = NULL,
                    started_at = CASE WHEN %s THEN NULL ELSE started_at END,
                    finished_at = CASE WHEN %s THEN NULL ELSE %s END,
                    available_at = CASE WHEN %s THEN %s ELSE available_at END,
                    claimed_deployment_revision = CASE
                        WHEN %s THEN NULL ELSE claimed_deployment_revision END,
                    claimed_serving_contract_revision = CASE
                        WHEN %s THEN NULL ELSE claimed_serving_contract_revision END,
                    claimed_runtime_instance_epoch = CASE
                        WHEN %s THEN NULL ELSE claimed_runtime_instance_epoch END,
                    updated_at = %s
                WHERE id = %s
                RETURNING *
                """,
                (
                    status.value,
                    _json(_failure_payload(error, retryable=should_retry)),
                    should_retry,
                    should_retry,
                    timestamp,
                    should_retry,
                    timestamp,
                    should_retry,
                    should_retry,
                    should_retry,
                    timestamp,
                    row["id"],
                ),
            ).fetchone()
            self._decrement_worker(connection, worker_id, timestamp)
            return self._job(updated)

    def cancel_job(
        self, job_id: str, *, now: datetime | None = None
    ) -> JobRecord:
        timestamp = _aware(now)
        with self._transaction() as connection:
            row = connection.execute(
                "SELECT * FROM jobs WHERE id::text = %s FOR UPDATE", (job_id,)
            ).fetchone()
            if row is None:
                raise NotFoundError(f"job not found: {job_id}")
            job = self._job(row)
            if job.status in {
                JobStatus.SUCCEEDED,
                JobStatus.FAILED,
                JobStatus.CANCELLED,
            }:
                return job
            updated = connection.execute(
                """
                UPDATE jobs
                SET status = 'cancelled',
                    assigned_worker_id = NULL,
                    lease_token = NULL,
                    lease_expires_at = NULL,
                    finished_at = %s,
                    updated_at = %s
                WHERE id = %s
                RETURNING *
                """,
                (timestamp, timestamp, row["id"]),
            ).fetchone()
            if job.status is JobStatus.RUNNING:
                self._decrement_worker(
                    connection, job.assigned_worker_id, timestamp
                )
            return self._job(updated)

    def recover_expired_jobs(
        self, *, now: datetime | None = None
    ) -> list[JobRecord]:
        timestamp = _aware(now)
        recovered: list[JobRecord] = []
        while True:
            with self._transaction() as connection:
                row = connection.execute(
                    """
                    SELECT *
                    FROM jobs
                    WHERE status = 'running'
                      AND lease_expires_at <= %s
                    ORDER BY sequence ASC
                    FOR UPDATE SKIP LOCKED
                    LIMIT 1
                    """,
                    (timestamp,),
                ).fetchone()
                if row is None:
                    return recovered

                deadline_expired = (
                    row.get("deadline_at") is not None
                    and row["deadline_at"] <= timestamp
                )
                should_retry = (
                    not deadline_expired
                    and int(row["attempts"]) < int(row["max_attempts"])
                )
                status = JobStatus.QUEUED if should_retry else JobStatus.FAILED
                updated = connection.execute(
                    """
                    UPDATE jobs
                    SET status = %s,
                        error = %s,
                        assigned_worker_id = NULL,
                        lease_token = NULL,
                        lease_expires_at = NULL,
                        started_at = CASE WHEN %s THEN NULL ELSE started_at END,
                        finished_at = CASE WHEN %s THEN NULL ELSE %s END,
                        available_at = CASE WHEN %s THEN %s ELSE available_at END,
                        claimed_deployment_revision = CASE
                            WHEN %s THEN NULL ELSE claimed_deployment_revision END,
                        claimed_serving_contract_revision = CASE
                            WHEN %s THEN NULL ELSE claimed_serving_contract_revision END,
                        claimed_runtime_instance_epoch = CASE
                            WHEN %s THEN NULL ELSE claimed_runtime_instance_epoch END,
                        updated_at = %s
                    WHERE id = %s
                    RETURNING *
                    """,
                    (
                        status.value,
                        _json(
                            (
                                {
                                    "type": "deadline_expired",
                                    "message": "job deadline expired",
                                    "retryable": False,
                                }
                                if deadline_expired
                                else {
                                    "message": "worker lease expired",
                                    "retryable": should_retry,
                                }
                            )
                        ),
                        should_retry,
                        should_retry,
                        timestamp,
                        should_retry,
                        timestamp,
                        should_retry,
                        should_retry,
                        should_retry,
                        timestamp,
                        row["id"],
                    ),
                ).fetchone()
                self._decrement_worker(
                    connection, row.get("assigned_worker_id"), timestamp
                )
                recovered.append(self._job(updated))


__all__ = ["PostgresControlRepository"]
