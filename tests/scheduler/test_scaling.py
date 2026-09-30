import os
import signal
import sys
import time
import unittest
from multiprocessing import Process
from typing import Dict, Optional

from scaler import Client
from scaler.cluster.object_storage_server import ObjectStorageServerProcess
from scaler.cluster.scheduler import SchedulerProcess
from scaler.config.common.logging import LoggingConfig
from scaler.config.common.worker import WorkerConfig
from scaler.config.common.worker_manager import WorkerManagerConfig
from scaler.config.defaults import (
    DEFAULT_CLIENT_TIMEOUT_SECONDS,
    DEFAULT_GARBAGE_COLLECT_INTERVAL_SECONDS,
    DEFAULT_HARD_PROCESSOR_SUSPEND,
    DEFAULT_HEARTBEAT_INTERVAL_SECONDS,
    DEFAULT_IO_THREADS,
    DEFAULT_LOAD_BALANCE_SECONDS,
    DEFAULT_LOAD_BALANCE_TRIGGER_TIMES,
    DEFAULT_MAX_NUMBER_OF_TASKS_WAITING,
    DEFAULT_OBJECT_RETENTION_SECONDS,
    DEFAULT_TASK_TIMEOUT_SECONDS,
    DEFAULT_TRIM_MEMORY_THRESHOLD_BYTES,
    DEFAULT_WORKER_DEATH_TIMEOUT,
    DEFAULT_WORKER_TIMEOUT_SECONDS,
)
from scaler.config.section.native_worker_manager import NativeWorkerManagerConfig
from scaler.config.section.scheduler import PolicyConfig
from scaler.config.types.address import AddressConfig
from scaler.config.types.worker import WorkerCapabilities
from scaler.io.utility import deserialize, serialize
from scaler.protocol.capnp import Resource, Task, WorkerHeartbeat, WorkerManagerHeartbeat
from scaler.protocol.helpers import dict_to_capabilities
from scaler.scheduler.controllers.policies.simple_policy.scaling.capability_scaling import CapabilityScalingPolicy
from scaler.scheduler.controllers.policies.simple_policy.scaling.static import StaticScalingPolicy
from scaler.scheduler.controllers.policies.simple_policy.scaling.types import WorkerManagerBounds
from scaler.scheduler.controllers.policies.simple_policy.scaling.utility import create_scaling_policy
from scaler.scheduler.controllers.policies.simple_policy.scaling.vanilla import VanillaScalingPolicy
from scaler.utility.identifiers import ClientID, ObjectID, TaskID, WorkerID
from scaler.utility.logging.utility import setup_logger
from scaler.utility.network_util import get_available_tcp_port
from scaler.utility.snapshot import InformationSnapshot
from tests.utility.utility import logging_test_name


class TestScaling(unittest.TestCase):
    def setUp(self) -> None:
        setup_logger()
        logging_test_name(self)

        self.scheduler_address = f"tcp://127.0.0.1:{get_available_tcp_port()}"
        self.object_storage_address = AddressConfig.from_string(f"tcp://127.0.0.1:{get_available_tcp_port()}")

    @unittest.skipIf(
        sys.platform == "win32",
        "Declarative scale-down destroys workers mid-test with Process.terminate(), which on POSIX sends "
        "SIGTERM so the worker sends WorkerDisconnectNotification on shutdown. On Windows terminate() is "
        "TerminateProcess, so any scaled-down worker is killed without notice and the scheduler waits ~60s "
        "for heartbeat timeout. The scaling policy logic itself is covered by test_vanilla_scaling.py.",
    )
    def test_scaling_basic(self):
        object_storage = ObjectStorageServerProcess(
            bind_address=self.object_storage_address,
            identity="ObjectStorageServer",
            logging_paths=("/dev/stdout",),
            logging_config_file=None,
            logging_level="INFO",
        )
        object_storage.start()
        object_storage.wait_until_ready()

        scheduler = SchedulerProcess(
            bind_address=AddressConfig.from_string(self.scheduler_address),
            object_storage_address=self.object_storage_address,
            advertised_object_storage_address=None,
            monitor_address=None,
            policy=PolicyConfig(policy_content="allocate=even_load; scaling=vanilla"),
            io_threads=DEFAULT_IO_THREADS,
            max_number_of_tasks_waiting=DEFAULT_MAX_NUMBER_OF_TASKS_WAITING,
            client_timeout_seconds=DEFAULT_CLIENT_TIMEOUT_SECONDS,
            worker_timeout_seconds=DEFAULT_WORKER_TIMEOUT_SECONDS,
            object_retention_seconds=DEFAULT_OBJECT_RETENTION_SECONDS,
            load_balance_seconds=DEFAULT_LOAD_BALANCE_SECONDS,
            load_balance_trigger_times=DEFAULT_LOAD_BALANCE_TRIGGER_TIMES,
            protected=False,
            event_loop="builtin",
            logging_paths=("/dev/stdout",),
            logging_config_file=None,
            logging_level="INFO",
        )
        scheduler.start()

        manager_process = Process(target=_run_native_worker_manager, args=(self.scheduler_address,))
        manager_process.start()

        with Client(self.scheduler_address) as client:
            client.map(time.sleep, [0.1] * 100)

        os.kill(scheduler.pid, signal.SIGINT)
        scheduler.join()

        object_storage.kill()
        object_storage.join()

        manager_process.terminate()
        manager_process.join()

    @unittest.skipIf(
        sys.platform == "win32",
        "See test_scaling_basic: declarative scale-down has no graceful path on Windows. "
        "Capability policy logic is covered by test_capability_scaling.py.",
    )
    def test_capability_scaling_basic(self):
        """Test that capability scaling starts workers with the correct capabilities."""
        object_storage = ObjectStorageServerProcess(
            bind_address=self.object_storage_address,
            identity="ObjectStorageServer",
            logging_paths=("/dev/stdout",),
            logging_config_file=None,
            logging_level="INFO",
        )
        object_storage.start()
        object_storage.wait_until_ready()

        scheduler = SchedulerProcess(
            bind_address=AddressConfig.from_string(self.scheduler_address),
            object_storage_address=self.object_storage_address,
            advertised_object_storage_address=None,
            monitor_address=None,
            io_threads=DEFAULT_IO_THREADS,
            max_number_of_tasks_waiting=DEFAULT_MAX_NUMBER_OF_TASKS_WAITING,
            client_timeout_seconds=DEFAULT_CLIENT_TIMEOUT_SECONDS,
            worker_timeout_seconds=DEFAULT_WORKER_TIMEOUT_SECONDS,
            object_retention_seconds=DEFAULT_OBJECT_RETENTION_SECONDS,
            load_balance_seconds=DEFAULT_LOAD_BALANCE_SECONDS,
            load_balance_trigger_times=DEFAULT_LOAD_BALANCE_TRIGGER_TIMES,
            protected=False,
            policy=PolicyConfig(policy_content="allocate=even_load; scaling=capability"),
            event_loop="builtin",
            logging_paths=("/dev/stdout",),
            logging_config_file=None,
            logging_level="INFO",
        )
        scheduler.start()

        manager_process = Process(target=_run_native_worker_manager, args=(self.scheduler_address,))
        manager_process.start()

        with Client(self.scheduler_address) as client:
            # Submit tasks without capabilities (should work like vanilla)
            client.map(time.sleep, [0.1] * 50)

        os.kill(scheduler.pid, signal.SIGINT)
        scheduler.join()

        object_storage.kill()
        object_storage.join()

        manager_process.terminate()
        manager_process.join()


class TestScalingStringParsing(unittest.TestCase):
    def test_a_colon_without_an_argument_is_refused(self):
        """`name:` is a missing argument, not the bare name."""
        for scaling in ["static:", "vanilla:", "capability:"]:
            with self.subTest(scaling=scaling):
                with self.assertRaises(ValueError):
                    create_scaling_policy(scaling)

    def test_only_ascii_digits_are_counts(self):
        """Unicode digits are refused with the parser's message, not converted or crashed on in `int()`."""
        for scaling in ["static:\u00b2", "static:\u0663", "static[a:\u00b2]", "vanilla[a:\u0663]"]:
            with self.subTest(scaling=scaling):
                with self.assertRaisesRegex(ValueError, "is not a non-negative task concurrency"):
                    create_scaling_policy(scaling)

    def test_whitespace_around_separators_is_ignored(self):
        """Spaces around the name, the argument, and the entries parse the same as none."""
        static = create_scaling_policy(" static : 4 ")
        assert isinstance(static, StaticScalingPolicy)
        self.assertEqual(static._task_concurrency, 4)

        vanilla = create_scaling_policy("vanilla [native:8]")
        assert isinstance(vanilla, VanillaScalingPolicy)
        self.assertEqual(vanilla._bounds, {b"native": WorkerManagerBounds(8, 0)})

    def test_an_argument_with_entries_is_refused_as_such(self):
        with self.assertRaisesRegex(ValueError, "an argument or entries, not both"):
            create_scaling_policy("static:2[native:4]")

    def test_an_unknown_name_lists_the_known_ones(self):
        with self.assertRaisesRegex(ValueError, "expected one of static, vanilla, capability"):
            create_scaling_policy("nope")

    def test_unclosed_entries_report_the_expected_shape(self):
        """A missing `]` is a malformed string, whatever the policy takes."""
        for scaling in ["capability[x", "static[native:4"]:
            with self.subTest(scaling=scaling):
                with self.assertRaisesRegex(
                    ValueError, "scaling must be 'name', 'name:argument', or 'name\\[entries\\]'"
                ):
                    create_scaling_policy(scaling)

    def test_a_worker_manager_id_with_a_bracket_is_refused(self):
        for scaling in ["static[[native:4]", "vanilla[[native:8]", "static[nat]ive:4]"]:
            with self.subTest(scaling=scaling):
                with self.assertRaises(ValueError):
                    create_scaling_policy(scaling)


class TestAtCapacityEmission(unittest.TestCase):
    """Policies unconditionally emit setDesired even when the computed desired equals the
    manager's current connected worker count -- the worker manager always receives the
    authoritative desired count."""

    def setUp(self):
        setup_logger()

    def test_vanilla_at_cap_emits_current(self):
        """Vanilla: ratio asks for current+1, cap clamps to current -> emits setDesired(current)."""
        policy = VanillaScalingPolicy({})
        tasks = {TaskID.generate_task_id(): _create_mock_task(TaskID.generate_task_id(), {}) for _ in range(100)}
        managed = [WorkerID(f"w{i}".encode()) for i in range(10)]
        workers = {wid: _create_mock_worker_heartbeat({}, queued_tasks=10) for wid in managed}
        snapshot = InformationSnapshot(tasks=tasks, workers=workers)
        heartbeat = _create_worker_manager_heartbeat(b"mgr", max_task_concurrency=10)

        commands = policy.get_scaling_commands(snapshot, heartbeat, managed, {})

        self.assertEqual(len(commands), 1)
        requests = list(commands[0].setDesiredTaskConcurrencyRequests)
        self.assertEqual(requests[0].taskConcurrency, 10)

    def test_vanilla_changes_emit(self):
        """Vanilla: when ratio's desired differs from current connected, emit."""
        policy = VanillaScalingPolicy({})
        tasks = {TaskID.generate_task_id(): _create_mock_task(TaskID.generate_task_id(), {}) for _ in range(100)}
        managed = [WorkerID(b"w0")]
        workers = {wid: _create_mock_worker_heartbeat({}, queued_tasks=10) for wid in managed}
        snapshot = InformationSnapshot(tasks=tasks, workers=workers)
        heartbeat = _create_worker_manager_heartbeat(b"mgr", max_task_concurrency=10)

        commands = policy.get_scaling_commands(snapshot, heartbeat, managed, {})

        self.assertEqual(len(commands), 1)
        requests = list(commands[0].setDesiredTaskConcurrencyRequests)
        self.assertEqual(requests[0].taskConcurrency, 2)

    def test_capability_at_cap_emits_current(self):
        """Capability: ratio's per-capset desired equals current connected -> emits setDesired(current)."""
        policy = CapabilityScalingPolicy()
        # ceil(50/5) = 10 desired for gpu capset; clamp at cap=10; emits setDesired(10).
        tasks = {}
        for _ in range(50):
            tid = TaskID.generate_task_id()
            tasks[tid] = _create_mock_task(tid, {"gpu": 1})
        managed = [WorkerID(f"w{i}".encode()) for i in range(10)]
        snapshot = InformationSnapshot(tasks=tasks, workers={})
        heartbeat = _create_worker_manager_heartbeat(b"mgr", max_task_concurrency=10, capabilities={"gpu": -1})

        commands = policy.get_scaling_commands(snapshot, heartbeat, managed, {})

        self.assertEqual(len(commands), 1)
        requests = list(commands[0].setDesiredTaskConcurrencyRequests)
        self.assertEqual(len(requests), 1)
        self.assertEqual(requests[0].taskConcurrency, 10)

    def test_capability_unservable_capset_emits(self):
        """Capability: a request whose capabilities aren't a subset of the manager's caps
        is still forwarded -- the policy emits the capset command regardless of serviceability."""
        policy = CapabilityScalingPolicy()
        task_id = TaskID.generate_task_id()
        snapshot = InformationSnapshot(tasks={task_id: _create_mock_task(task_id, {"gpu": 1})}, workers={})
        heartbeat = _create_worker_manager_heartbeat(b"mgr", capabilities={})

        commands = policy.get_scaling_commands(snapshot, heartbeat, [], {})

        self.assertEqual(len(commands), 1)
        requests = list(commands[0].setDesiredTaskConcurrencyRequests)
        self.assertEqual(len(requests), 1)
        self.assertEqual(requests[0].taskConcurrency, 1)

    def test_waterfall_at_cap_emits_current(self):
        """Waterfall: when the manager is full per the priority chain, it still emits setDesired(current)."""
        from scaler.scheduler.controllers.policies.simple_policy.scaling.types import WorkerManagerSnapshot
        from scaler.scheduler.controllers.policies.waterfall_v1.scaling.types import WaterfallRule
        from scaler.scheduler.controllers.policies.waterfall_v1.scaling.waterfall import WaterfallScalingPolicy

        rules = [WaterfallRule(priority=1, worker_manager_id=b"mgr", max_task_concurrency=10)]
        policy = WaterfallScalingPolicy(rules)
        # ceil(100/10) = 10; cap=10; desired=10 -> emits setDesired(10).
        tasks = {TaskID.generate_task_id(): _create_mock_task(TaskID.generate_task_id(), {}) for _ in range(100)}
        managed = [WorkerID(f"w{i}".encode()) for i in range(10)]
        snapshot = InformationSnapshot(tasks=tasks, workers={})
        heartbeat = _create_worker_manager_heartbeat(b"mgr", max_task_concurrency=10)
        manager_snapshots = {
            b"mgr": WorkerManagerSnapshot(
                worker_manager_id=b"mgr", max_task_concurrency=10, worker_count=10, last_seen_at=0.0, capabilities={}
            )
        }

        commands = policy.get_scaling_commands(snapshot, heartbeat, managed, manager_snapshots)

        self.assertEqual(len(commands), 1)
        requests = list(commands[0].setDesiredTaskConcurrencyRequests)
        self.assertEqual(requests[0].taskConcurrency, 10)


class TestPendingWorkersStatus(unittest.IsolatedAsyncioTestCase):
    """Pending-worker reporting in WorkerManagerController.get_status."""

    def setUp(self):
        from unittest.mock import AsyncMock, MagicMock

        from scaler.scheduler.controllers.worker_manager_controller import WorkerManagerController

        setup_logger()
        config_controller = MagicMock()
        policy_controller = MagicMock()
        policy_controller.get_scaling_status.return_value = MagicMock(managed_workers={})

        self.controller = WorkerManagerController(config_controller, policy_controller)
        self.policy_controller = policy_controller

        binder = AsyncMock()
        task_controller = MagicMock()
        task_controller._task_id_to_task = {}
        self.worker_controller = MagicMock()
        self.worker_controller._worker_alive_since = {}

        self.controller.register(binder, task_controller, self.worker_controller)

    async def test_pending_equals_desired_minus_connected(self):
        """pendingWorkers = max(0, last_desired_total - connected_count)."""
        from scaler.scheduler.controllers.worker_manager_utilties import build_set_desired_command

        source = b"mgr-src"
        manager_id = b"mgr-id"
        heartbeat = _create_worker_manager_heartbeat(manager_id)

        # Policy returns a setDesired command totaling 5 workers for this manager (empty caps).
        self.policy_controller.get_scaling_commands.return_value = [build_set_desired_command([({}, 5)])]
        # 2 workers are currently connected to this manager.
        self.worker_controller.get_workers_by_manager_id.return_value = [WorkerID(b"w0"), WorkerID(b"w1")]

        await self.controller.on_heartbeat(source, heartbeat)
        status = self.controller.get_status()

        detail = next(d for d in status.workerManagerDetails if d.workerManagerID == manager_id)
        self.assertEqual(detail.pendingWorkers, 3)  # 5 desired - 2 connected

    async def test_pending_clamped_at_zero(self):
        """If more workers are connected than desired, pendingWorkers is 0 (never negative)."""
        from scaler.scheduler.controllers.worker_manager_utilties import build_set_desired_command

        source = b"mgr-src"
        manager_id = b"mgr-id"
        heartbeat = _create_worker_manager_heartbeat(manager_id)

        self.policy_controller.get_scaling_commands.return_value = [build_set_desired_command([({}, 1)])]
        self.worker_controller.get_workers_by_manager_id.return_value = [WorkerID(b"w0"), WorkerID(b"w1")]

        await self.controller.on_heartbeat(source, heartbeat)
        status = self.controller.get_status()

        detail = next(d for d in status.workerManagerDetails if d.workerManagerID == manager_id)
        self.assertEqual(detail.pendingWorkers, 0)

    async def test_pending_only_counts_capsets_this_manager_can_serve(self):
        """A capset whose capabilities are not a subset of the manager's capabilities is excluded."""
        from scaler.scheduler.controllers.worker_manager_utilties import build_set_desired_command

        source = b"mgr-src"
        manager_id = b"mgr-id"
        # Manager advertises only "cpu" capability.
        heartbeat = _create_worker_manager_heartbeat(manager_id, max_task_concurrency=10, capabilities={"cpu": -1})

        # Generic (empty caps, wildcard) -> 2; gpu-only -> 4 (not servable); cpu-only -> 3 (servable).
        self.policy_controller.get_scaling_commands.return_value = [
            build_set_desired_command([({}, 2), ({"gpu": -1}, 4), ({"cpu": -1}, 3)])
        ]
        self.worker_controller.get_workers_by_manager_id.return_value = []

        await self.controller.on_heartbeat(source, heartbeat)
        status = self.controller.get_status()

        detail = next(d for d in status.workerManagerDetails if d.workerManagerID == manager_id)
        # 2 (empty wildcard) + 3 (cpu subset) - 0 connected = 5; gpu (4) is excluded.
        self.assertEqual(detail.pendingWorkers, 5)


def _create_mock_task(task_id: TaskID, capabilities: dict) -> Task:
    client_id = ClientID.generate_client_id()
    return Task(
        taskId=task_id,
        source=client_id,
        metadata=b"",
        funcObjectId=ObjectID.generate_object_id(client_id),
        functionArgs=[],
        capabilities=capabilities,
    )


def _create_mock_worker_heartbeat(capabilities: dict, queued_tasks: int = 0) -> WorkerHeartbeat:
    return WorkerHeartbeat(
        agent=Resource(cpu=1, rss=1000000),
        rssFree=500000,
        queueSize=10,
        queuedTasks=queued_tasks,
        latencyMicroseconds=100,
        taskLock=False,
        processors=[],
        capabilities=capabilities,
        workerManagerID=b"test",
    )


def _create_worker_manager_heartbeat(
    worker_manager_id: bytes, max_task_concurrency: int = 10, capabilities: Optional[Dict[str, int]] = None
) -> WorkerManagerHeartbeat:
    """A heartbeat as the binder delivers it: decoded from the wire, not built in memory."""
    heartbeat = deserialize(
        serialize(
            WorkerManagerHeartbeat(
                maxTaskConcurrency=max_task_concurrency,
                capabilities=dict_to_capabilities(capabilities or {}),
                workerManagerID=worker_manager_id,
            )
        )
    )
    assert isinstance(heartbeat, WorkerManagerHeartbeat)
    return heartbeat


def _run_native_worker_manager(
    scheduler_address: str, max_task_concurrency: int = 4, worker_manager_id: str = "test_manager"
) -> None:
    from scaler.worker_manager.native.worker_manager import NativeWorkerManager

    manager = NativeWorkerManager(
        NativeWorkerManagerConfig(
            worker_manager_config=WorkerManagerConfig(
                scheduler_address=AddressConfig.from_string(scheduler_address),
                worker_manager_id=worker_manager_id,
                object_storage_address=None,
                max_task_concurrency=max_task_concurrency,
            ),
            worker_config=WorkerConfig(
                per_worker_capabilities=WorkerCapabilities({}),
                per_worker_task_queue_size=10,
                heartbeat_interval_seconds=DEFAULT_HEARTBEAT_INTERVAL_SECONDS,
                task_timeout_seconds=DEFAULT_TASK_TIMEOUT_SECONDS,
                death_timeout_seconds=DEFAULT_WORKER_DEATH_TIMEOUT,
                garbage_collect_interval_seconds=DEFAULT_GARBAGE_COLLECT_INTERVAL_SECONDS,
                trim_memory_threshold_bytes=DEFAULT_TRIM_MEMORY_THRESHOLD_BYTES,
                hard_processor_suspend=DEFAULT_HARD_PROCESSOR_SUSPEND,
                io_threads=DEFAULT_IO_THREADS,
                event_loop="builtin",
            ),
            logging_config=LoggingConfig(paths=("/dev/stdout",), level="INFO", config_file=None),
        )
    )

    manager.run()
