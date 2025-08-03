"""GPU compute orchestration with unified cloud provider abstraction.

Flow SDK provides a high-level interface for GPU workload submission across
heterogeneous cloud infrastructure. The design philosophy emphasizes explicit
behavior, progressive disclosure, and fail-fast validation.

Architectural Principles:
    - Single source of truth: TaskConfig defines complete job specification
    - Provider agnostic: Uniform API abstracts cloud-specific complexity
    - Resource lifecycle: Explicit management of compute and storage resources
    - Observability first: Comprehensive logging, monitoring, and debugging

Typical Workflow:
    1. Initialize Flow with authentication credentials
    2. Create TaskConfig with compute requirements and workload
    3. Submit task to available GPU infrastructure
    4. Monitor execution via logs, status, and SSH access
    5. Manage persistent volumes for data and model storage

Examples:
    Basic GPU job submission:
        >>> flow = Flow()
        >>> task = flow.run("python train.py", instance_type="a100")
        >>> task.wait()
        >>> print(task.logs())

    Full configuration with volumes and monitoring:
        >>> config = TaskConfig(
        ...     name="distributed-training",
        ...     instance_type="8xh100",
        ...     command=["python", "train.py", "--epochs", "100"],
        ...     volumes=[VolumeSpec(size_gb=100, mount_path="/data")],
        ...     max_price_per_hour=50.0,
        ...     max_run_time_hours=24.0
        ... )
        >>> task = flow.run(config)
        >>> for line in task.logs(follow=True):
        ...     process_training_metrics(line)

    Capability-based GPU selection:
        >>> task = flow.run(
        ...     TaskConfig(
        ...         name="inference",
        ...         min_gpu_memory_gb=24,
        ...         command="python infer.py",
        ...         max_price_per_hour=10.0
        ...     )
        ... )
"""

import logging
import os
import time
from pathlib import Path
from typing import Any, Dict, Iterator, List, Literal, Optional, TypedDict, Union

from flow._internal.config import Config
from flow._internal.data import URLResolver, VolumeLoader
from flow._internal.data.resolver import DataError
from flow.api.models import AvailableInstance, MountSpec, Task, TaskConfig, TaskStatus, Volume, VolumeSpec
from flow.core.provider_interfaces import IProvider
from flow.providers.interfaces import IProviderInit
from flow.core.resources import GPUParser, InstanceMatcher
from flow.errors import (
    FlowError,
    NetworkError,
    ResourceNotAvailableError,
    ValidationError,
    VolumeError,
)
from flow.providers.factory import create_provider

logger = logging.getLogger(__name__)


# ================== Type Definitions ==================

class GPUInstanceDict(TypedDict):
    """GPU instance dictionary returned by _find_gpus_by_memory()."""
    name: str
    gpu_memory_gb: int
    price_per_hour: float
    gpu_model: str


class TaskDict(TypedDict):
    """Task dictionary returned by list() method."""
    id: str
    name: str
    status: str
    instance_type: str
    created: Optional[str]


class InstanceRequirements(TypedDict, total=False):
    """Instance requirements dictionary for find_instances()."""
    instance_type: str
    min_gpu_count: int
    max_price: float
    region: str
    gpu_memory_gb: int
    gpu_type: str



class CatalogEntry(TypedDict):
    """Instance catalog entry dictionary."""
    name: str
    gpu_type: str
    gpu_count: int
    price_per_hour: float
    available: bool
    gpu: Dict[str, Any]  # Nested GPU info with model and memory_gb


class Flow:
    """Primary orchestration interface for GPU compute infrastructure.

    Flow implements a facade pattern over cloud provider APIs, providing
    unified task submission, monitoring, and resource management. The class
    maintains provider connections with lazy initialization and connection
    pooling for optimal performance.

    Architecture:
        - Lazy provider initialization reduces startup overhead
        - Instance catalog cached with TTL for price freshness
        - Async task submission with polling-based monitoring
        - SSH tunnel establishment for interactive debugging

    Core Capabilities:
        - Multi-format task submission (YAML, Python API, CLI)
        - Automatic GPU instance selection by requirements
        - Persistent volume management across task lifecycles
        - Real-time log streaming with backpressure control
        - Direct SSH access to running instances

    Performance Characteristics:
        - Instance catalog: 200-500ms cold, <1ms warm (5min TTL)
        - Task submission: 2-5s typical (provider API + provisioning)
        - Log streaming: 50-100ms per chunk, 1MB/s sustained
        - Status queries: 100-200ms (cached for 10s)

    Resource Management:
        - Automatic cleanup on context exit
        - Graceful shutdown of streaming connections
        - Provider connection reuse across operations

    Thread Safety:
        - NOT thread-safe: use one Flow instance per thread
        - Provider maintains internal connection pooling
        - Catalog cache is instance-local (no locks)

    Error Handling:
        - Fail-fast validation at submission time
        - Detailed error messages with recovery suggestions
        - Automatic retry for transient network failures
    """

    def __init__(self, config: Optional[Config] = None, auto_init: bool = False):
        """Initialize Flow with automatic configuration discovery.

        Configuration resolution follows a clear precedence order, enabling
        both programmatic control and environment-based deployment.

        Args:
            config: Explicit configuration object. When provided, bypasses
                all discovery mechanisms. Useful for testing and programmatic
                control with dependency injection.
            auto_init: Enable interactive setup for missing configuration.
                Only activates in CLI contexts to avoid blocking library usage.
                When True and config is missing, launches guided setup flow.

        Raises:
            ValueError: Missing required configuration (API key, project) when
                auto_init=False. Includes specific guidance on resolution.

        Configuration Discovery Order:
            1. Explicit config parameter (highest precedence)
            2. FLOW_API_KEY environment variable
            3. ~/.flow/config.json file (user-specific)
            4. Interactive setup (if auto_init=True)

        Example:
            >>> # Explicit configuration
            >>> config = Config(api_key="fcp-...", project="ml-research")
            >>> flow = Flow(config=config)

            >>> # Environment-based discovery
            >>> os.environ['FLOW_API_KEY'] = "fcp-..."
            >>> flow = Flow()  # Auto-discovers from environment
        """
        if config:
            self.config = config
        else:
            try:
                self.config = Config.from_env(require_auth=True)
            except ValueError as e:
                if auto_init:
                    # Only launch interactive setup from CLI
                    from flow._internal.auth import ensure_initialized

                    if not ensure_initialized():
                        raise ValueError(str(e)) from e
                    # Retry after setup
                    self.config = Config.from_env(require_auth=True)
                else:
                    # In SDK usage, just raise the error
                    raise

        self._provider: Optional[IProvider] = None
        self._dev = None

    @property
    def dev(self):
        """Access development environment functionality.
        
        Provides programmatic access to Flow's persistent development
        environment, enabling fast container-based command execution
        on a long-running VM.
        
        Returns:
            DevEnvironment: Development environment manager
            
        Example:
            >>> flow = Flow()
            >>> # Start dev VM
            >>> vm = flow.dev.start()
            >>> 
            >>> # Execute commands
            >>> flow.dev.exec("python train.py")
            >>> 
            >>> # Check status
            >>> status = flow.dev.status()
            >>> print(f"Active containers: {status['active_containers']}")
            >>> 
            >>> # Use as context manager with auto-stop
            >>> with flow.dev_context(auto_stop=True) as dev:
            ...     dev.exec("python train.py")
        """
        if self._dev is None:
            from flow.api.dev import DevEnvironment
            self._dev = DevEnvironment(self)
        return self._dev
    
    def dev_context(self, auto_stop: bool = False):
        """Create a dev environment context manager.
        
        Args:
            auto_stop: Automatically stop VM on exit (default: False)
            
        Returns:
            DevEnvironment: Context manager for dev environment
            
        Example:
            >>> # Auto-stop VM when done
            >>> with flow.dev_context(auto_stop=True) as dev:
            ...     dev.exec("python train.py")
            ...     dev.exec("python test.py")
            ... # VM stopped automatically
            >>> 
            >>> # Keep VM running (default)
            >>> with flow.dev_context() as dev:
            ...     dev.exec("make build")
            ... # VM continues running
        """
        from flow.api.dev import DevEnvironment
        return DevEnvironment(self, auto_stop=auto_stop)

    def _find_gpus_by_memory(
        self, min_memory_gb: int, max_price: Optional[float] = None
    ) -> List[GPUInstanceDict]:
        """Find GPU instances matching memory and price constraints.

        Implements capability-based instance discovery by scanning the
        cached catalog for suitable GPU configurations. Results are
        deterministically sorted by price for cost optimization.

        Args:
            min_memory_gb: Minimum GPU memory in gigabytes. Common values:
                - 16: Consumer GPUs (V100-16GB)
                - 24: Mid-range (RTX 3090, RTX 4090)
                - 40: A100-40GB, high-end consumer
                - 80: A100-80GB, H100-80GB datacenter
            max_price: Maximum hourly spot price in USD. None allows any price.
                Typical ranges: A100=$2-10/hr, H100=$10-50/hr

        Returns:
            List of matching instances sorted by price (cheapest first).
            Each instance dict contains:
                - name: Provider instance type ID
                - gpu_memory_gb: Available VRAM per GPU
                - price_per_hour: Current spot price
                - gpu_model: Human-readable GPU identifier

        Performance:
            - O(n) catalog scan, n ≈ 100 instance types
            - Operates on cached data (no API calls)
            - Sort is O(n log n) but n is small

        Algorithm:
            1. Filter instances with GPU memory ≥ min_memory_gb
            2. Filter instances with price ≤ max_price (if set)
            3. Sort by price ascending for cost optimization
            4. Return all matches (caller selects first)
        """
        catalog = self._load_instance_catalog()
        suitable = []

        for instance in catalog:
            # Skip if no GPU info
            gpu_info = instance.get("gpu", {})
            if not gpu_info:
                continue

            # Check memory requirement
            memory_gb = gpu_info.get("memory_gb", 0)
            if memory_gb < min_memory_gb:
                continue

            # Check price requirement
            price = instance.get("price_per_hour")
            if price is None:
                continue
            if max_price and price > max_price:
                continue

            suitable.append(
                {
                    "name": instance["name"],
                    "gpu_memory_gb": memory_gb,
                    "price_per_hour": price,
                    "gpu_model": gpu_info.get("model", "unknown"),
                }
            )

        # Sort by price (cheapest first)
        suitable.sort(key=lambda x: x["price_per_hour"])

        return suitable

    def get_remote_operations(self):
        """Get remote operations interface from provider.
        
        Provides access to SSH-based remote operations for executing
        commands and opening shells on running instances. This is the
        clean interface for accessing provider remote capabilities.
        
        Returns:
            Remote operations interface with execute_command and open_shell methods
            
        Raises:
            NotImplementedError: If provider doesn't support remote operations
            AttributeError: If provider is missing the interface
            
        Example:
            >>> remote_ops = flow.get_remote_operations()
            >>> output = remote_ops.execute_command(task_id, "ls -la")
            >>> remote_ops.open_shell(task_id)
        """
        provider = self._ensure_provider()
        
        if not hasattr(provider, 'get_remote_operations'):
            raise NotImplementedError(
                f"Provider {provider.__class__.__name__} doesn't support remote operations"
            )
        
        return provider.get_remote_operations()

    def _ensure_provider(self) -> IProvider:
        """Ensure provider instance exists with lazy initialization.

        Implements singleton pattern for provider lifecycle management.
        Provider instances maintain connection pools and are expensive
        to create, so we initialize once and reuse.

        Returns:
            IProvider: Cached provider instance for current configuration.
                Same instance returned on subsequent calls.

        Thread Safety:
            NOT thread-safe. Concurrent calls may create multiple providers.
            Use external synchronization if sharing Flow across threads.

        Implementation Notes:
            - First call: 100-500ms (API connection establishment)
            - Subsequent calls: <1μs (attribute access)
            - Provider selection based on Config.api_url domain
        """
        if self._provider is None:
            self._provider = create_provider(self.config)
        return self._provider

    @property
    def provider(self) -> IProvider:
        """Get the compute provider instance.

        Returns:
            The provider instance, creating it if necessary.
            
        Example:
            >>> flow = Flow()
            >>> provider = flow.provider
            >>> # Use provider-specific methods
            >>> instance_type, count, msg = provider.normalize_instance_request(1, "h100")
        """
        return self._ensure_provider()

    def run(
        self,
        task: Union[TaskConfig, str, Path],
        wait: bool = False,
        mounts: Optional[Union[str, Dict[str, str]]] = None,
    ) -> Task:
        """Submit computational task to GPU infrastructure.

        Primary API for workload submission. Handles the complete lifecycle:
        validation, instance discovery, resource allocation, and execution.
        Designed for both interactive and automated workflows.

        Args:
            task: Task specification in one of three formats:
                - TaskConfig: Programmatic configuration object
                - str/Path: File path to YAML configuration
                - Dict: Direct configuration dictionary (internal use)
            wait: Block until task reaches running state. When True, returns
                only after instance is provisioned and startup complete.
                Default False for async operation.
            mounts: Storage sources to mount (overrides config.data_mounts).
                - str: Single source auto-mounted to appropriate path:
                    - s3://bucket/path → /data
                    - volume://name → /mnt
                    - /local/path → /data
                - Dict[str, str]: Multiple mounts as {mount_path: source_url}
                    Example: {"/data": "s3://bucket/dataset", "/models": "volume://pretrained"}
                Supported protocols:
                    - s3://bucket/path: S3 buckets (requires AWS credentials in environment)
                    - volume://name: Persistent volumes (must exist in same region)

        Returns:
            Task: Handle for lifecycle management. Primary methods:
                - status: Current execution state (property)
                - logs(follow=True): Stream output in real-time
                - ssh(): Open interactive shell session
                - wait(timeout=None): Block until running/complete
                - cancel(): Request graceful termination
                - get_user(): Retrieve task creator information
                - get_instances(): Get detailed instance metadata

        Raises:
            FlowError: Infrastructure or availability issues:
                - No instances match requirements
                - Insufficient capacity in region
                - API communication failure
            ValidationError: Configuration issues:
                - Missing required fields (command/instance_type)
                - Invalid field values or combinations
                - Constraint violations (price, runtime)
            FileNotFoundError: YAML path does not exist
            yaml.YAMLError: Invalid YAML syntax

        Instance Resolution Algorithm:
            1. If instance_type provided: Direct lookup
               - Supports shortcuts: "a100", "4xa100", "h100"
               - Full spec: "a100-80gb.sxm.4x"
               - Provider FID: "it_fK7Cx6TVhOK5ZfXT"

            2. If min_gpu_memory_gb provided: Capability search
               - Finds all instances with sufficient VRAM
               - Filters by max_price_per_hour if set
               - Selects cheapest option automatically

            3. If neither: Error with specific suggestions

        Performance Profile:
            - Config parsing: <1ms
            - Validation: <10ms (Pydantic)
            - Instance catalog: 200-500ms cold, <1ms warm
            - API submission: 2-5s typical, 10s worst case
            - Wait polling: 1s intervals, 10-60s typical

        Best Practices:
            - Always set max_price_per_hour to control costs
            - Use wait=True for dependent workflows
            - Prefer instance_type for reproducibility
            - Use min_gpu_memory_gb for flexibility

        Examples:
            Basic single-GPU job:
                >>> task = flow.run("python train.py", instance_type="a100")
                >>> print(f"Submitted: {task.task_id}")

            Full configuration with constraints:
                >>> config = TaskConfig(
                ...     name="distributed-training",
                ...     instance_type="8xa100",  # 8x A100 GPUs
                ...     command=["python", "-m", "torch.distributed.launch",
                ...              "--nproc_per_node=8", "train.py"],
                ...     max_price_per_hour=25.0,  # Cost control
                ...     max_run_time_hours=24.0,  # Time limit
                ...     volumes=[VolumeSpec(size_gb=1000, mount_path="/data")],
                ...     env={"BATCH_SIZE": "512", "EPOCHS": "100"}
                ... )
                >>> task = flow.run(config, wait=True)
                >>> print(f"Running on {task.ssh_host}")

            Capability-based GPU selection:
                >>> task = flow.run(
                ...     TaskConfig(
                ...         name="llm-inference",
                ...         min_gpu_memory_gb=40,  # A100-40GB or better
                ...         command="python serve_model.py",
                ...         max_price_per_hour=10.0
                ...     )
                ... )
        """
        # Load from YAML if needed
        if isinstance(task, (str, Path)):
            task = TaskConfig.from_yaml(str(task))

        # Let provider prepare the task configuration with defaults
        provider = self._ensure_provider()
        task = provider.prepare_task_config(task)

        # Handle mounts parameter - convert to data_mounts
        if mounts:
            mount_specs = self._resolve_data_mounts(mounts)
            # Override any existing data_mounts with the provided mounts
            task = task.model_copy(update={"data_mounts": mount_specs})

        # Validate that either instance_type or min_gpu_memory_gb is specified
        if not task.instance_type and not task.min_gpu_memory_gb:
            raise ValidationError(
                "Must specify either 'instance_type' or 'min_gpu_memory_gb'",
                suggestions=[
                    "Add instance_type='a100' for a specific GPU",
                    "Add min_gpu_memory_gb=24 for capability-based selection",
                    "Run 'flow catalog' to see available instance types",
                ],
            )

        # Handle capability-based GPU selection if needed
        if task.min_gpu_memory_gb and not task.instance_type:
            # Find GPUs with sufficient memory, sorted by price
            suitable_types = self._find_gpus_by_memory(
                min_memory_gb=task.min_gpu_memory_gb, max_price=task.max_price_per_hour
            )

            if suitable_types:
                # Use the cheapest suitable type
                selected = suitable_types[0]
                task.instance_type = selected["name"]
                logger.info(
                    f"Auto-selected {task.instance_type} with {selected['gpu_memory_gb']}GB "
                    f"GPU memory (${selected['price_per_hour']}/hour)"
                )
            else:
                raise ResourceNotAvailableError(
                    f"No GPU instances found with at least {task.min_gpu_memory_gb}GB memory"
                    + (
                        f" under ${task.max_price_per_hour}/hour" if task.max_price_per_hour else ""
                    ),
                    suggestions=[
                        "Try reducing the minimum GPU memory requirement",
                        "Increase your max_price_per_hour limit",
                        "Use 'flow catalog' to see available instances",
                        "Try a different region with --region",
                        "Consider using a specific instance_type instead",
                    ],
                    error_code="RESOURCE_001",
                )

        # At this point we have an instance_type
        logger.debug(f"Submitting task with instance type: {task.instance_type}")

        # Handle volumes - create new ones if needed
        volume_ids = []
        for vol_spec in task.volumes:
            if vol_spec.volume_id:
                # Use existing volume
                volume_ids.append(vol_spec.volume_id)
            else:
                # Create new volume with name
                logger.info(f"Creating volume '{vol_spec.name}' ({vol_spec.size_gb}GB)")
                volume = provider.create_volume(size_gb=vol_spec.size_gb, name=vol_spec.name)
                volume_ids.append(volume.volume_id)

        # Submit task to provider - the provider handles all instance resolution,
        # region selection, and availability checking internally
        task_obj = provider.submit_task(
            instance_type=task.instance_type,
            config=task,
            volume_ids=volume_ids,
        )

        logger.info(f"Task submitted successfully: {task_obj.task_id}")

        # Wait for task to start if requested
        if wait:
            task_obj.wait()

        return task_obj

    def status(self, task_id: str) -> str:
        """Query current task execution status.

        Provides lightweight status polling without full task metadata.
        Results may be cached briefly by providers to reduce API load.

        Args:
            task_id: Unique task identifier returned by run().
                Format is provider-specific (e.g., "task-abc123").

        Returns:
            str: Lowercase status string. One of:
                - "pending": Queued, waiting for resources
                - "running": Actively executing on GPU
                - "completed": Finished successfully (exit 0)
                - "failed": Terminated with error (non-zero exit)
                - "cancelled": User-requested termination

        Raises:
            FlowError: Task not found or access denied

        Performance:
            - Typical: 100-200ms (single API call)
            - Worst case: 500ms (network latency)
            - May use 10s cache to prevent API hammering

        Note:
            For detailed task information including SSH access,
            timestamps, and logs, use get_task() instead.
        """
        provider = self._ensure_provider()
        status = provider.get_task_status(task_id)
        return status.value.lower()

    def cancel(self, task_id: str) -> None:
        """Request graceful task termination.

        Initiates cancellation workflow: SIGTERM → wait → SIGKILL.
        Providers implement graceful shutdown with configurable timeouts.

        Args:
            task_id: Task identifier to cancel. Must be active (pending/running).

        Raises:
            FlowError: Cancellation failed. Common causes:
                - Task already completed/failed
                - Insufficient permissions
                - Provider rejection (e.g., critical system task)

        Cancellation Workflow:
            1. Send cancellation request to provider
            2. Provider sends SIGTERM to process group
            3. Wait up to 30s for graceful shutdown
            4. Force-terminate with SIGKILL if needed
            5. Clean up resources (volumes unmounted, logs flushed)

        Note:
            Cancellation is asynchronous and eventually consistent.
            Task status may remain "running" for 10-30s during shutdown.
            Use task.wait() after cancel to ensure termination.
        """
        provider = self._ensure_provider()
        success = provider.cancel_task(task_id)
        if not success:
            raise FlowError(f"Failed to cancel task {task_id}")
        logger.info(f"Task {task_id} cancelled successfully")

    def logs(
        self, task_id: str, follow: bool = False, tail: int = 100, stderr: bool = False
    ) -> Union[str, Iterator[str]]:
        """Retrieve or stream task output logs.

        Provides both historical log retrieval and real-time streaming.
        Streaming includes automatic reconnection and backpressure handling.

        Args:
            task_id: Task identifier for log retrieval
            follow: Enable real-time streaming mode. When True, returns
                iterator yielding new lines as they arrive. When False,
                returns historical logs as single string.
            tail: Number of most recent lines to retrieve (follow=False only).
                Default 100 provides last few screens of output.
            stderr: Retrieve stderr instead of stdout. Note that many
                providers merge streams, making this a no-op.

        Returns:
            Union[str, Iterator[str]]:
                - follow=False: String containing last 'tail' lines
                - follow=True: Iterator yielding lines in real-time

        Performance:
            - Initial fetch: 200-500ms (metadata + first chunk)
            - Streaming latency: 50-100ms per chunk
            - Throughput: 1MB/s sustained, 10MB/s burst

        Example:
            >>> # Get last 100 lines
            >>> print(flow.logs(task_id))

            >>> # Stream until task completes
            >>> for line in flow.logs(task_id, follow=True):
            ...     if "ERROR" in line:
            ...         send_alert(line)
        """
        task = self.get_task(task_id)
        return task.logs(follow=follow, tail=tail, stderr=stderr)

    def shell(self, task_id: str, command: Optional[str] = None, node: Optional[int] = None, progress_context=None) -> None:
        """Open shell connection to task instance.

        Opens shell access for debugging, monitoring, or interactive
        development. Uses provider-specific remote operations.

        Args:
            task_id: Task to connect to. Must be in "running" state.
            command: Remote command to execute. If provided, runs
                command and exits. If None, starts interactive shell.
            node: Node index for multi-instance tasks (default: None).
            progress_context: Optional context manager for progress display
                during connection setup.

        Raises:
            FlowError: Connection failed. Common causes:
                - Task not in "running" state
                - Provider doesn't support remote operations
                - Network connectivity issues

        Example:
            >>> # Interactive debugging
            >>> flow.shell(task_id)

            >>> # Run command
            >>> flow.shell(task_id, "nvidia-smi")
            >>> flow.shell(task_id, "ps aux | grep python")
            
            >>> # Multi-instance task
            >>> flow.shell(task_id, node=1)
        """
        task = self.get_task(task_id)
        task.shell(command, node=node, progress_context=progress_context)

    def list(self, status: Optional[str] = None) -> List[TaskDict]:
        """List tasks with optional status filter (deprecated).

        Maintained for backward compatibility. New code should use
        list_tasks() which returns full Task objects.

        Args:
            status: Filter by status string ("pending", "running", etc.)

        Returns:
            List[Dict]: Simplified task summaries containing:
                - id: Task identifier
                - name: Human-readable name
                - status: Current status
                - instance_type: GPU instance type
                - created: ISO timestamp

        Deprecated:
            Use list_tasks() for new code. This method will be
            removed in v2.0.0.
        """
        tasks = self.list_tasks(status=TaskStatus(status) if status else None)

        # Simplify output for backward compatibility
        return [
            {
                "id": task.task_id,
                "name": task.name,
                "status": task.status.value,
                "instance_type": task.instance_type,
                "created": task.created_at.isoformat() if task.created_at else None,
            }
            for task in tasks
        ]

    def list_tasks(
        self, status: Optional[TaskStatus] = None, limit: int = 10, force_refresh: bool = False
    ) -> List[Task]:
        """Query recent tasks with optional filtering.

        Retrieves task history for current project with support for
        status filtering and pagination. Results include full task
        metadata for detailed inspection.

        Sort Behavior:
            Tasks are returned in newest-first order (by creation time).
            The FCP provider requests sort=created_at:desc from the API
            and applies additional client-side sorting to ensure consistent
            ordering across all scenarios.

        Args:
            status: Filter by TaskStatus enum value. None returns all.
                Common filters:
                - TaskStatus.RUNNING: Active tasks only
                - TaskStatus.FAILED: Debugging failures
                - TaskStatus.COMPLETED: Successful runs
            limit: Maximum tasks to return. Range [1, 100], default 10.
                Provider may return fewer if insufficient history.
            force_refresh: Bypass caching for real-time status data.

        Returns:
            List[Task]: Task objects with complete metadata, ordered
                by creation time (newest first). Empty list if no matches.

        Performance:
            - Single page: 200-500ms (includes metadata hydration)
            - Pagination: Linear in limit (no cursor support yet)

        Example:
            >>> # Get all running tasks
            >>> running = flow.list_tasks(status=TaskStatus.RUNNING)
            >>> for task in running:
            ...     print(f"{task.name}: {task.ssh_command}")
        """
        provider = self._ensure_provider()
        return provider.list_tasks(status=status, limit=limit, force_refresh=force_refresh)

    # Storage operations

    def create_volume(
        self,
        size_gb: int,
        name: Optional[str] = None,
        interface: Literal["block", "file"] = "block",
    ) -> Volume:
        """Create persistent storage volume.

        Provisions durable network-attached storage for data persistence
        across task lifecycles. Volumes are project-scoped and region-specific.

        Args:
            size_gb: Volume capacity in gigabytes.
                - Minimum: 1 GB (testing/config)
                - Maximum: 16,384 GB (16 TB)
                - Common sizes: 100 (datasets), 500 (models), 1000 (checkpoints)
                Cost scales linearly with size (~$0.10/GB/month).
            name: Human-readable identifier for volume management.
                - Optional: Auto-generated if None (vol-{timestamp})
                - Constraints: Alphanumeric, dash, underscore, max 63 chars
                - Must be unique within project
                - Used in volume:// URLs for easy reference
            interface: Storage type - "block" (default) or "file".
                - block: High-performance exclusive access (like AWS EBS)
                - file: Shared access across instances (like AWS EFS/NFS)

        Returns:
            Volume: Persistent volume object with metadata:
                - volume_id: Unique identifier for API operations
                - name: Human-readable name (as provided or generated)
                - size_gb: Allocated capacity
                - region: Deployment region (from config)
                - status: Current state ("available", "attached")
                - created_at: Creation timestamp

        Raises:
            FlowError: Infrastructure or quota issues:
                - Storage quota exceeded for project
                - Region capacity exhausted
                - Provisioning timeout (rare)
            ValidationError: Invalid parameters:
                - size_gb outside valid range
                - name already exists in project
                - name contains invalid characters
                - interface not "block" or "file"
            ResourceNotAvailableError: If file interface not available in region

        Performance:
            - API call: 200-500ms
            - Provisioning: 2-5s (background)
            - Available for use immediately after return

        Storage Characteristics:
            - Type: Network-attached block storage (EBS-like)
            - Durability: 99.999% (11 nines) annual
            - Performance: 3000 IOPS baseline, burstable to 10000
            - Filesystem: Ext4 formatted on first attach
            - Encryption: At-rest AES-256

        Best Practices:
            - Size for growth (expanding requires new volume)
            - Use descriptive names for team collaboration
            - Tag with data version in name (e.g., "dataset-v2")
            - Delete unused volumes to control costs

        Example:
            Simple volume creation and use:
                >>> # Create persistent storage
                >>> data_vol = flow.create_volume(500, "training-data")
                >>> model_vol = flow.create_volume(100, "model-checkpoints")
                >>>
                >>> # Use in task
                >>> task = flow.run(
                ...     TaskConfig(
                ...         name="distributed-training",
                ...         instance_type="8xa100",
                ...         command="python train.py",
                ...         volumes=[
                ...             VolumeSpec(volume_id=data_vol.volume_id,
                ...                       mount_path="/data"),
                ...             VolumeSpec(volume_id=model_vol.volume_id,
                ...                       mount_path="/checkpoints")
                ...         ]
                ...     )
                ... )

            Using volume:// URLs:
                >>> vol = flow.create_volume(100, "shared-data")
                >>> # Later, reference by name
                >>> task = flow.submit(
                ...     "python analyze.py",
                ...     gpu="a100",
                ...     data="volume://shared-data"  # Resolved by name
                ... )
        """
        # Validate interface parameter
        if interface not in ["block", "file"]:
            raise ValueError(f"Invalid interface: {interface}. Must be 'block' or 'file'")

        provider = self._ensure_provider()
        volume = provider.create_volume(size_gb, name, interface)
        logger.info(f"Created {interface} volume {volume.volume_id} ({size_gb}GB)")
        return volume

    def delete_volume(self, volume_id: str) -> None:
        """Permanently delete storage volume.

        Initiates immediate deletion of volume and all contained data.
        Operation is irreversible with no grace period or recovery.

        Args:
            volume_id: Unique volume identifier from create_volume().
                Format: "vol-{random}" (provider-specific).

        Raises:
            FlowError: Deletion failed. Common causes:
                - Volume currently attached to running task
                - Insufficient permissions
                - Volume already deleted
                - Provider-side protection enabled

        Warning:
            DATA LOSS: Deletion is immediate and permanent. No backups
            are retained. Ensure data is copied elsewhere if needed.

        Best Practices:
            - Verify volume contents before deletion
            - Detach from all tasks first
            - Consider using volume snapshots (future feature)
        """
        provider = self._ensure_provider()
        success = provider.delete_volume(volume_id)
        if not success:
            raise VolumeError(
                f"Failed to delete volume {volume_id}",
                suggestions=[
                    "Check if volume is currently attached to a running task",
                    "Verify volume exists with 'flow volume list'",
                    "Ensure you have permission to delete this volume",
                ],
                error_code="VOLUME_002",
            )
        logger.info(f"Volume {volume_id} deleted successfully")

    def list_volumes(self, limit: int = 100) -> List[Volume]:
        """List persistent volumes in current project.

        Enumerates all volumes accessible to current API key/project
        combination. Includes both attached and detached volumes.

        Args:
            limit: Maximum volumes to return. Range [1, 1000], default 100.
                Large limits may increase response time linearly.

        Returns:
            List[Volume]: Volume objects ordered by creation time
                (newest first). Each includes:
                - volume_id: Unique identifier
                - name: Human-readable name (if set)
                - size_gb: Capacity in gigabytes
                - status: Current state (available/attached)
                - created_at: Creation timestamp

        Performance:
            - O(limit) API response time
            - 100 volumes: ~200ms
            - 1000 volumes: ~2s

        Example:
            >>> volumes = flow.list_volumes()
            >>> for vol in volumes:
            ...     print(f"{vol.name}: {vol.size_gb}GB - {vol.status}")
        """
        provider = self._ensure_provider()
        return provider.list_volumes(limit=limit)

    def mount_volume(self, volume_id: str, task_id: str, mount_point: Optional[str] = None) -> None:
        """Mount a volume to a running task.

        Attaches and mounts a volume to an already running task without
        requiring task restart. The volume becomes available at
        /mnt/{volume_name} immediately after successful mounting.

        Args:
            volume_id: Volume identifier - either the ID (vol_xxx) or name
            task_id: Task identifier to mount the volume to
            mount_point: Optional custom mount path (default: /mnt/{volume_name})

        Raises:
            ResourceNotFoundError: Task or volume not found
            ValidationError: Region mismatch or volume already attached
            FlowError: Mount operation failed

        Example:
            >>> # Create and mount a volume to running task
            >>> volume = flow.create_volume(100, "shared-data")
            >>> task = flow.run(config)
            >>>
            >>> # Mount the volume to the running task
            >>> flow.mount_volume("shared-data", task.task_id)
            >>> # Volume now available at /mnt/shared-data in the task
            >>>
            >>> # Or use volume ID directly with custom mount point
            >>> flow.mount_volume(volume.volume_id, task.task_id, mount_point="/data/datasets")
        """
        provider = self._ensure_provider()
        provider.mount_volume(volume_id, task_id, mount_point=mount_point)
        logger.info(f"Successfully mounted volume {volume_id} to task {task_id}")

    def get_task(self, task_id: str) -> Task:
        """Retrieve task object for existing job.

        Reconstructs Task handle from ID, enabling operations on tasks
        started in previous sessions or by other processes.

        Args:
            task_id: Unique task identifier. Can be obtained from:
                - Return value of flow.run()
                - flow.list_tasks() results
                - Provider dashboard/CLI

        Returns:
            Task: Full task object with all methods available:
                - status: Current execution state
                - logs(): Output retrieval
                - ssh(): Shell access
                - wait(): Synchronous blocking
                - cancel(): Termination

        Raises:
            FlowError: Retrieval failed. Common causes:
                - Invalid task_id format
                - Task not found (may be expired)
                - Access denied (different project/user)
                - Provider API unavailable

        Example:
            >>> # Resume monitoring from previous session
            >>> task = flow.get_task("task-abc123")
            >>> print(task.status)
            >>> task.logs(follow=True)
        """
        provider = self._ensure_provider()
        return provider.get_task(task_id)

    def find_instances(
        self,
        requirements: InstanceRequirements,
        limit: int = 10,
    ) -> List[AvailableInstance]:
        """Find available GPU instances matching requirements.

        Searches provider inventory for instances satisfying specified
        constraints. Returns best matches sorted by price and capability.

        Args:
            requirements: Constraint dictionary with optional keys:
                - instance_type (str): Exact instance type (e.g., "a100", "8xh100")
                - min_gpu_count (int): Minimum number of GPUs (1-64)
                - max_price (float): Maximum hourly price in USD
                - region (str): Target region/zone
                - gpu_memory_gb (int): Minimum GPU memory per device (16, 24, 40, 80)
                - gpu_type (str): GPU model ("a100", "v100", "h100")
            limit: Maximum results to return (1-100)

        Returns:
            List[Dict[str, Any]]: Available instances with fields:
                - instance_type: Provider instance identifier
                - gpu_count: Number of GPUs
                - gpu_memory_gb: GPU memory per device
                - price_per_hour: Current spot/preemptible price
                - region: Deployment region
                - available_quantity: Current capacity

        Raises:
            ValidationError: Invalid requirements
            ProviderError: Provider API failure

        Example:
            >>> # Find cheapest A100 instances
            >>> instances = flow.find_instances({
            ...     "gpu_type": "a100",
            ...     "max_price": 10.0
            ... })
            >>> for inst in instances:
            ...     print(f"{inst['instance_type']}: ${inst['price_per_hour']}/hr")
        """
        provider = self._ensure_provider()
        return provider.find_instances(requirements, limit=limit)

    def submit(
        self,
        command: str,
        *,
        gpu: Optional[str] = None,
        mounts: Optional[Union[str, Dict[str, str]]] = None,
        instance_type: Optional[str] = None,
        wait: bool = False,
    ) -> Task:
        """Submit command with automatic configuration inference.

        Convenience method for rapid experimentation and simple workloads.
        Automatically handles GPU selection, data mounting, and sensible
        defaults while maintaining full configurability.

        Args:
            command: Shell command to execute. Will be run in bash -c.
                Complex commands with pipes, redirects, and multiple
                statements are supported.
            gpu: GPU specification syntax:
                - Type only: "a100", "h100" (single GPU)
                - With count: "a100:4", "h100:8" (multi-GPU)
                - Memory constraint: "gpu:24gb" (min 24GB VRAM)
                Parsed to appropriate instance_type automatically.
            mounts: Storage source specification. Accepts:
                - String: Single source with automatic mount path:
                    - "s3://bucket/data" → mounts to /data
                    - "volume://my-vol" → mounts to /mnt
                - Dict: Multiple mounts with explicit paths:
                    - {"/datasets": "s3://bucket/imagenet", "/checkpoints": "volume://models"}
                Supported protocols:
                - volume://name: Existing named volume (must be in same region)
                - s3://bucket/path: S3 object/prefix (requires AWS_ACCESS_KEY_ID and AWS_SECRET_ACCESS_KEY)
            instance_type: Explicit instance type override. When set,
                ignores gpu parameter. Use for precise control.
            wait: Block until task completes. Default False returns
                immediately after submission for async workflows.

        Returns:
            Task: Standard task handle with full lifecycle control.

        Environment:
            - Uses Ubuntu 22.04 base image (CUDA-capable)
            - Inherits AWS credentials if present in environment
            - Auto-generates unique task names with timestamps

        Data Mounting:
            S3 mounts use s3fs-fuse with these environment variables:
            - S3_MOUNT_0_BUCKET, S3_MOUNT_0_PATH, S3_MOUNT_0_TARGET
            - AWS_ACCESS_KEY_ID, AWS_SECRET_ACCESS_KEY (from env)
            Startup script handles mounting automatically.

        Performance:
            - GPU parsing: <1ms
            - Instance matching: <10ms (cached catalog)
            - Volume resolution: 100-200ms per volume
            - Total overhead: ~500ms above standard run()

        Examples:
            Quick single-GPU training:
                >>> task = flow.submit("python train.py --epochs 10", gpu="a100")
                >>> task.wait()
                >>> print(task.logs())

            Multi-GPU with storage mounts:
                >>> task = flow.submit(
                ...     "torchrun --nproc_per_node=4 train_ddp.py",
                ...     gpu="a100:4",
                ...     mounts={
                ...         "/data": "volume://training-data",
                ...         "/models": "s3://my-bucket/pretrained/",
                ...         "/output": "volume://results"
                ...     }
                ... )

            Memory-based GPU selection:
                >>> # Get any GPU with at least 40GB memory
                >>> task = flow.submit(
                ...     "python inference.py --model llama-70b",
                ...     gpu="gpu:40gb"
                ... )
        """
        # Build config dict first, then create TaskConfig
        config_dict = {
            "name": f"flow-submit-{int(time.time())}",
            "command": command,
            "image": "ubuntu:22.04",  # Sensible default
        }

        # Parse GPU specification and add to config dict
        if gpu and not instance_type:
            parsed_gpu = GPUParser().parse(gpu)

            # Match to instance type
            if not hasattr(self, "_instance_matcher"):
                # Load catalog (cached)
                catalog = self._load_instance_catalog()
                self._instance_matcher = InstanceMatcher(catalog)

            config_dict["instance_type"] = self._instance_matcher.match(parsed_gpu)

        elif instance_type:
            config_dict["instance_type"] = instance_type
        else:
            # No GPU or instance_type specified - let run() find any available instance
            # We'll set a dummy instance_type that run() will override
            config_dict["instance_type"] = "auto"

        # Convert mount URLs to volumes
        if mounts:
            if isinstance(mounts, str):
                # Single mount source auto-mounted
                if mounts.startswith("s3://"):
                    mounts = {"/data": mounts}
                elif mounts.startswith("volume://"):
                    mounts = {"/mnt": mounts}
                else:
                    mounts = {"/data": mounts}

            # Initialize resolver with volume loader
            resolver = URLResolver()
            resolver.add_loader("volume", VolumeLoader())

            volumes = []
            provider = self._ensure_provider()

            for target, url in mounts.items():
                spec = resolver.resolve(url, target, provider)

                # Convert MountSpec to VolumeSpec for existing API
                if spec.mount_type == "volume":
                    volume_spec = VolumeSpec(
                        volume_id=spec.options.get("volume_id"), mount_path=target
                    )
                    volumes.append(volume_spec)
                elif spec.mount_type == "s3fs":
                    # For S3, we pass mount info through environment variables
                    # Why: S3 requires runtime mounting (not provider-level) and
                    # credentials must be available in the instance for s3fs
                    if "env" not in config_dict:
                        config_dict["env"] = {}

                    # Pass AWS credentials from current environment
                    # Security: Only passes if already in env (user's responsibility)
                    if "AWS_ACCESS_KEY_ID" in os.environ:
                        config_dict["env"]["AWS_ACCESS_KEY_ID"] = os.environ["AWS_ACCESS_KEY_ID"]
                    if "AWS_SECRET_ACCESS_KEY" in os.environ:
                        config_dict["env"]["AWS_SECRET_ACCESS_KEY"] = os.environ[
                            "AWS_SECRET_ACCESS_KEY"
                        ]
                    if "AWS_SESSION_TOKEN" in os.environ:
                        config_dict["env"]["AWS_SESSION_TOKEN"] = os.environ["AWS_SESSION_TOKEN"]

                    # Pass S3 mount info through environment variables
                    s3_mount_index = sum(
                        1
                        for k in config_dict.get("env", {}).keys()
                        if k.startswith("S3_MOUNT_") and k.endswith("_BUCKET")
                    )
                    mount_key = f"S3_MOUNT_{s3_mount_index}"
                    config_dict["env"][f"{mount_key}_BUCKET"] = spec.options.get("bucket")
                    config_dict["env"][f"{mount_key}_PATH"] = spec.options.get("path", "")
                    config_dict["env"][f"{mount_key}_TARGET"] = target
                    config_dict["env"]["S3_MOUNTS_COUNT"] = str(s3_mount_index + 1)
                else:
                    # For now, only support volumes and s3
                    raise DataError(
                        f"Mount type '{spec.mount_type}' not yet supported",
                        suggestions=["Use volume:// or s3:// URLs"],
                    )

            config_dict["volumes"] = volumes

        # Create TaskConfig with all fields set
        config = TaskConfig(**config_dict)

        # Use existing run method
        return self.run(config, wait=wait)

    def _load_instance_catalog(self) -> List[CatalogEntry]:
        """Load GPU instance catalog with price-aware caching.

        Maintains in-memory cache of available instance types with current
        spot pricing. Cache TTL balanced between price staleness and API
        quota conservation.

        Returns:
            List[Dict]: Instance specifications with current pricing.
                Each entry contains:
                - name: Instance type identifier
                - gpu_type: GPU model (e.g., "a100-80gb")
                - gpu_count: Number of GPUs
                - price_per_hour: Current spot price
                - available: Capacity availability flag
                - gpu: Nested dict with model and memory_gb

        Performance:
            - Cold start: 200-500ms (provider API call)
            - Cache hit: <1ms (dictionary lookup)
            - Cache TTL: 300s (5 minutes)

        Caching Strategy:
            - TTL ensures prices remain reasonably current
            - Per-instance caching (no shared state)
            - Automatic refresh on expiration
            - No background refresh (lazy loading)

        Implementation Notes:
            - Parses provider-specific formats to standard schema
            - Extracts GPU specs from instance type strings
            - Preserves all provider metadata for compatibility
        """
        # Check cache with 5-minute TTL to avoid stale pricing
        cache_ttl = 300  # 5 minutes
        now = time.time()

        if (
            hasattr(self, "_catalog_cache")
            and hasattr(self, "_catalog_cache_time")
            and now - self._catalog_cache_time < cache_ttl
        ):
            return self._catalog_cache

        # Load from provider
        provider = self._ensure_provider()
        instances = provider.find_instances({}, limit=1000)

        # Convert to dict format for matcher
        catalog = []
        for inst in instances:
            # Provider must parse its own format
            if not hasattr(provider, "parse_catalog_instance"):
                raise FlowError(
                    "Provider does not support catalog parsing",
                    suggestions=[
                        "Provider must implement parse_catalog_instance() method",
                        "Update to a newer version of the provider",
                        "Contact provider maintainer for support",
                    ],
                )
            catalog_entry = provider.parse_catalog_instance(inst)
            catalog.append(catalog_entry)

        # Cache with timestamp
        self._catalog_cache = catalog
        self._catalog_cache_time = now
        return catalog

    def _resolve_data_mounts(self, mounts: Union[str, Dict[str, str]]) -> List[MountSpec]:
        """Convert mounts parameter to list of MountSpec objects.

        Handles automatic mount path assignment based on source type:
        - s3:// sources → /data (common for datasets)
        - volume:// sources → /mnt (common for persistent storage)
        - Other sources → /data (default)

        Args:
            mounts: Storage sources to mount
                - str: Single source auto-mounted to appropriate path
                - Dict[str, str]: Multiple mounts as {mount_path: source_url}

        Returns:
            List[MountSpec]: Mount specifications for TaskConfig

        Examples:
            >>> # Single S3 bucket
            >>> flow._resolve_data_mounts("s3://bucket/data")
            [MountSpec(source="s3://bucket/data", target="/data", ...)]

            >>> # Multiple mounts
            >>> flow._resolve_data_mounts({
            ...     "/training": "s3://bucket/imagenet",
            ...     "/models": "volume://pretrained-v1"
            ... })
            [MountSpec(source="s3://bucket/imagenet", target="/training", ...),
             MountSpec(source="volume://pretrained-v1", target="/models", ...)]
        """
        from flow.api.models import MountSpec

        # Convert single string to dict format
        if isinstance(mounts, str):
            # Auto-determine mount path based on source type
            if mounts.startswith("s3://"):
                # S3 buckets typically mount at /data
                mounts = {"/data": mounts}
            elif mounts.startswith("volume://"):
                # Volumes mount at root by default
                mounts = {"/mnt": mounts}
            else:
                # Default mount point
                mounts = {"/data": mounts}

        # Create MountSpec for each entry
        mount_specs = []
        for target, source in mounts.items():
            # Determine mount type based on source
            if source.startswith("s3://"):
                mount_type = "s3fs"
            elif source.startswith("volume://"):
                mount_type = "volume"
            else:
                mount_type = "bind"

            mount_specs.append(MountSpec(source=source, target=target, mount_type=mount_type))

        return mount_specs

    def get_provider_init(self) -> "IProviderInit":
        """Get provider's initialization interface.

        Provides access to provider-specific configuration and
        initialization capabilities for use by CLI commands.

        Returns:
            IProviderInit: Provider's initialization interface

        Example:
            >>> flow = Flow()
            >>> init_interface = flow.get_provider_init()
            >>> fields = init_interface.get_config_fields()
            >>> print(fields["api_key"].description)
        """
        provider = self._ensure_provider()
        return provider.get_init_interface()

    def list_projects(self) -> List[Dict[str, str]]:
        """List available projects for the authenticated user.

        Delegates to provider's initialization interface to fetch
        projects the current credentials have access to.

        Returns:
            List of project dictionaries with 'id' and 'name' keys

        Raises:
            AuthenticationError: If credentials are invalid
            ProviderError: If API request fails

        Example:
            >>> flow = Flow()
            >>> projects = flow.list_projects()
            >>> for proj in projects:
            ...     print(f"{proj['name']} ({proj['id']})")
        """
        init_interface = self.get_provider_init()
        return init_interface.list_projects()

    def list_ssh_keys(self, project_id: Optional[str] = None) -> List[Dict[str, str]]:
        """List SSH keys available for use.

        Delegates to provider's initialization interface to fetch
        SSH keys that can be added to instances.

        Args:
            project_id: Optional project filter for multi-project providers

        Returns:
            List of SSH key dictionaries with 'id' and 'name' keys

        Raises:
            AuthenticationError: If credentials are invalid
            ProviderError: If API request fails

        Example:
            >>> flow = Flow()
            >>> keys = flow.list_ssh_keys()
            >>> for key in keys:
            ...     print(f"{key['name']} ({key['id']})")
        """
        init_interface = self.get_provider_init()
        return init_interface.list_ssh_keys(project_id)

    def get_ssh_key_manager(self):
        """Get SSH key manager for the current provider.

        Provides access to SSH key management operations including
        listing, creating, and syncing SSH keys between local and
        platform storage.

        Returns:
            SSHKeyManager: Provider's SSH key manager interface

        Raises:
            AttributeError: If provider doesn't support SSH key management

        Example:
            >>> flow = Flow()
            >>> ssh_manager = flow.get_ssh_key_manager()
            >>> keys = ssh_manager.list_keys()
        """
        provider = self._ensure_provider()
        if not hasattr(provider, "ssh_key_manager"):
            raise AttributeError(
                f"Provider {provider.__class__.__name__} doesn't support SSH key management"
            )
        return provider.ssh_key_manager

    def close(self):
        """Release provider connections and system resources.

        Ensures graceful shutdown of network connections, thread pools,
        and any provider-specific resources. Safe to call multiple times.

        Called automatically when using context manager pattern.
        """
        if self._provider and hasattr(self._provider, "close"):
            self._provider.close()

    def __enter__(self):
        """Enter context manager for automatic resource cleanup.

        Returns:
            Flow: Self reference for context variable assignment.
        """
        return self

    def __exit__(self, exc_type, exc_val, exc_tb):
        """Exit context manager with automatic cleanup.

        Ensures provider connections are closed even if exception occurred.
        Does not suppress exceptions.

        Args:
            exc_type: Exception class if error occurred
            exc_val: Exception instance if error occurred
            exc_tb: Exception traceback if error occurred
        """
        self.close()
