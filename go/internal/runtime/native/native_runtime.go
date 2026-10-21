// Copyright 2025 The Ray Authors.
//
// Licensed under the Apache License, Version 2.0 (the "License");
// you may not use this file except in compliance with the License.
// You may obtain a copy of the License at
//
//  http://www.apache.org/licenses/LICENSE-2.0
//
// Unless required by applicable law or agreed to in writing, software
// distributed under the License is distributed on an "AS IS" BASIS,
// WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
// See the License for the specific language governing permissions and
// limitations under the License.

// Package native provides native implementation of the Runtime interface.
//
// Design notes:
// 1. Implements the contract.Runtime interface.
// 2. Indirectly calls CGO through the coreworker package.
// 3. Manages runtime state and thread safety.
// 4. GCS client uses lazy loading to reduce initialization overhead.
package native

import (
	"context"
	"errors"
	"fmt"
	"strconv"
	"sync"
	"sync/atomic"
	"time"

	"github.com/ray-project/ray/go/internal/common"
	"github.com/ray-project/ray/go/internal/gcs/native"
	"github.com/ray-project/ray/go/internal/runtime/actor"
	"github.com/ray-project/ray/go/internal/runtime/base"
	cgoboundary "github.com/ray-project/ray/go/internal/runtime/cgo"
	cgocallback "github.com/ray-project/ray/go/internal/runtime/cgo"
	cgointerfaces "github.com/ray-project/ray/go/internal/runtime/cgo"
	"github.com/ray-project/ray/go/internal/runtime/objectstore"
	"github.com/ray-project/ray/go/internal/runtime/resource"
	"github.com/ray-project/ray/go/internal/runtime/serializer"
	rayerrors "github.com/ray-project/ray/go/pkg/errors"
	"github.com/ray-project/ray/go/pkg/gcs"
	"github.com/ray-project/ray/go/pkg/ids"
	"github.com/ray-project/ray/go/pkg/log"
	"github.com/ray-project/ray/go/pkg/options"
	"github.com/ray-project/ray/go/pkg/runtime/api"
	"github.com/ray-project/ray/go/pkg/runtime/contract"
	"github.com/ray-project/ray/go/pkg/runtime/function"
	"github.com/ray-project/ray/go/pkg/runtime/object"
	"github.com/ray-project/ray/go/pkg/runtime/submitter"
	"github.com/ray-project/ray/go/proto"
)

var logger = log.WithName("native")

// Compile-time type checks to ensure interface implementations.
// These variables are never used at runtime; they exist solely to trigger
// compile-time errors if the types don't implement the interfaces correctly.
var _ contract.Runtime = (*NativeRuntime)(nil)
var _ contract.RuntimeHandle = (*NativeHandleImpl)(nil)

// globalWorkerContext is the package-level singleton instance of NativeWorkerContext.
// NativeWorkerContext is stateless (all methods call CGO functions), so a single
// instance can be shared across all NativeRuntime instances.
var globalWorkerContext = &cgointerfaces.NativeWorkerContext{}

var (
	ErrRuntimeAlreadyInitialized = errors.New("runtime already initialized")
	ErrRuntimeNotInitialized     = errors.New("runtime not initialized")
	ErrGCSClientNotAvailable     = errors.New("GCS client not available")
)

// NativeRuntime is the native implementation of the Runtime interface.
type NativeRuntime struct {
	opts            base.InitializeOptions
	handle          *cgoboundary.Handle
	mu              sync.RWMutex
	// shutdownLock is handed to the object store, which holds its read side
	// around every CGO reference-count call and its write side here around the
	// C++ teardown. It is separate from mu so that a caller already holding mu
	// (e.g. an object-store getter) can still release a reference without a
	// recursive read lock.
	shutdownLock sync.RWMutex
	gcsClient       atomic.Pointer[gcs.Client]
	gcsInitError    atomic.Pointer[error]
	initialized     atomic.Bool
	workerContext   *cgointerfaces.NativeWorkerContext
	objectStore     object.ObjectStore
	executor        *cgointerfaces.NativeTaskExecutor
	functionManager *function.FunctionManager
	resourceManager resource.ResourceManager
	actorManager    *actor.ActorManager
	// ownerAddressCache caches each owner actor's rpc.Address by ActorID so a
	// Put-with-owner does not re-query GCS on every call. An owner actor's
	// address is stable for the lifetime of the actor (Java caches it when the
	// ActorHandle is created), so the cache is safe and is keyed per runtime.
	ownerAddressCache sync.Map // map[ids.ActorID]*proto.Address
	// ownerAddressResolveLocks holds one lock per owner actor so concurrent
	// first-time resolutions for the SAME actor share a single GCS RPC
	// (single-flight on cache miss) without a global lock serializing
	// unrelated actors' resolutions.
	ownerAddressResolveLocks sync.Map // map[ids.ActorID]*sync.Mutex
}

// NewNativeRuntime creates a new NativeRuntime instance.
func NewNativeRuntime(opts base.InitializeOptions) (*NativeRuntime, error) {
	return &NativeRuntime{
		opts:            opts,
		handle:          nil,
		workerContext:   globalWorkerContext, // Use package-level singleton
		resourceManager: resource.NewResourceManager(),
		actorManager:    actor.NewActorManager(),
	}, nil
}

// Start starts the native runtime.
//
// Thread safety: Uses atomic.Bool.CompareAndSwap to prevent duplicate initialization.
// GCS client is not initialized here, but lazily loaded on first access.
func (nr *NativeRuntime) Start() error {
	if !nr.initialized.CompareAndSwap(false, true) {
		logger.Info("NativeRuntime.Start() rejected - already initialized")
		return ErrRuntimeAlreadyInitialized
	}

	nr.mu.Lock()
	defer nr.mu.Unlock()

	// Set up task executor callback before initializing core worker.
	// This ensures the callback is ready when tasks start arriving.
	// Initialize function manager first, then create executor with it
	logger.Info("creating FunctionManager and TaskExecutor")
	nr.functionManager = function.NewFunctionManager(nil)
	nr.executor = cgointerfaces.NewNativeTaskExecutor(nr.functionManager)
	cgocallback.SetTaskExecutor(nr.executeTask)

	// Call coreworker CGO initialization
	logger.Info("calling cgoboundary.Initialize()",
		"gcsAddress", nr.opts.Network.GcsAddress,
		"workerType", nr.opts.WorkerType)
	handle, err := cgoboundary.Initialize(nr.opts)
	if err != nil {
		logger.Error(err, "cgoboundary.Initialize() returned error",
			"gcsAddress", nr.opts.Network.GcsAddress,
			"workerType", nr.opts.WorkerType,
		)
		nr.initialized.Store(false)
		return fmt.Errorf("failed to initialize core worker: %w", err)
	}

	if handle == nil {
		logger.Error(nil, "cgoboundary.Initialize() returned nil handle - this should not happen")
		nr.initialized.Store(false)
		return fmt.Errorf("cgoboundary.Initialize() returned nil handle")
	}

	nr.handle = handle

	// Install the cgo metric backend as the default backend. This must happen
	// after cgoboundary.Initialize() so the C++ core worker (and its stats
	// module) is ready; metric registration/recording before this point would
	// fail with "metric backend not registered". Local mode never reaches this
	// path and therefore intentionally keeps the backend unregistered.
	cgointerfaces.RegisterDefaultBackend()

	// Register the serializer's buffer pool with the object package.
	// This is done explicitly in Start() rather than in init() to:
	// 1. Follow dependency inversion principle (composition root pattern)
	// 2. Make the dependency explicit and testable
	// 3. Avoid implicit package initialization order dependencies
	// The serializer package provides the concrete implementation (BufferPoolWrapper)
	// which is injected into the object package at runtime startup.
	object.SetDefaultBufferPool(&serializer.BufferPoolWrapper{})

	// Create ObjectStore during Start() for zero-overhead access in the hot path.
	// The shutdown lock is wired in so RemoveLocalReference -- the object-store
	// CGO call that drops an ObjectRef's local reference from the release worker
	// and from the submit path's pass-by-ref argument cleanup -- holds the read
	// side while the C++ CoreWorker is alive; Shutdown takes the write side across
	// the teardown. Constructing the store without it leaves the lock nil and
	// RemoveLocalReference dereferences a nil pointer. RemoveLocalReference is the
	// only object-store CGO call gated by this lock; Put/Get/Wait/Delete and
	// AddLocalReference are not covered by it.
	//
	// The owner-address resolver looks up the owner actor's rpc.Address via GCS,
	// mirroring Java's GcsClient.getActorAddress (ActorTableData.address), so a
	// Put-with-owner can pass the owner address to the C++ side. It is bound to
	// this runtime's real GCS lookup, which stays lazily initialized.
	nativeStore := objectstore.NewNativeObjectStore(&nr.shutdownLock, nr.newOwnerAddressResolver(func(ctx context.Context, actorID ids.ActorID) (*proto.ActorTableData, error) {
		gcsClient, err := nr.GetGcsClient()
		if err != nil {
			return nil, fmt.Errorf("failed to get GCS client: %w", err)
		}
		return gcsClient.GetActorInfo(ctx, actorID)
	}))
	nr.objectStore = nativeStore

	// Register the Go task executor callback with C++.
	// This must be called after SetTaskExecutor() and before RunTaskExecutionLoop().
	cgocallback.RegisterTaskExecutorCallback()

	logger.Info("Native runtime started successfully")
	return nil
}

// newOwnerAddressResolver returns the owner-address resolver injected into the
// native object store. getActorInfo is a parameter rather than a direct GCS
// call so the cache and single-flight behaviour can be tested without a GCS.
//
// Resolved addresses are cached by ActorID: an owner actor's address is stable,
// so a Put-with-owner hits the cache instead of a GCS RPC on every call. On a
// cache miss a per-actor lock makes concurrent first-time resolutions of the
// same actor share a single RPC without serializing unrelated actors.
func (nr *NativeRuntime) newOwnerAddressResolver(getActorInfo func(context.Context, ids.ActorID) (*proto.ActorTableData, error)) func(context.Context, ids.ActorID) (*proto.Address, error) {
	return func(ctx context.Context, actorID ids.ActorID) (*proto.Address, error) {
		if cached, ok := nr.ownerAddressCache.Load(actorID); ok {
			return cached.(*proto.Address), nil
		}
		// Per-actor single-flight: concurrent first-time resolutions for the
		// same actor share one GCS RPC; different actors do not block each
		// other.
		mu, _ := nr.ownerAddressResolveLocks.LoadOrStore(actorID, &sync.Mutex{})
		actorMu := mu.(*sync.Mutex)
		actorMu.Lock()
		defer actorMu.Unlock()
		if cached, ok := nr.ownerAddressCache.Load(actorID); ok {
			return cached.(*proto.Address), nil
		}
		actorInfo, err := getActorInfo(ctx, actorID)
		if err != nil {
			return nil, fmt.Errorf("failed to get actor info for owner %s: %w", actorID.Hex(), err)
		}
		if actorInfo == nil || actorInfo.Address == nil {
			return nil, fmt.Errorf("owner actor %s has no address", actorID.Hex())
		}
		nr.ownerAddressCache.Store(actorID, actorInfo.Address)
		return actorInfo.Address, nil
	}
}

// executeTask is the task execution callback registered with C++.
// It is called by C++ when a task is received during task execution loop.
//
// This method delegates based on the task type:
//   - Normal tasks (TaskTypeNormal): Execute via executor.Execute()
//   - Actor creation tasks (TaskTypeActorCreation): construct the actor instance
//     via the registered "<init>" constructor and store it in the ActorManager.
//   - Actor method tasks (TaskTypeActorTask): look up the stored instance and
//     invoke the method via reflection with the instance as the receiver.
//
// Thread safety: The ActorManager is concurrency-safe; this method can be called
// concurrently by multiple task execution threads.
//
// Parameters:
//   - taskType: Type of task (matches ray::rpc::TaskType enum values)
//   - functionDescriptor: Function descriptor identifying the function to execute
//   - args: Function arguments (may contain ObjectRef or serialized values)
//   - numReturns: Number of expected return values
//   - actorID: Actor ID (nil for normal tasks, non-nil for actor tasks)
//
// Returns:
//   - []function.SerializedObject: Task execution results
//   - error: Execution error (if any)
func (nr *NativeRuntime) executeTask(
	taskType int,
	functionDescriptor function.FunctionDescriptor,
	args []function.FunctionArg,
	numReturns int,
	actorID ids.ActorID,
) ([]function.SerializedObject, error) {
	// A panic from a user function propagates to the caller GoExecuteTask (see
	// go/internal/runtime/cgo/task_executor.go), which recovers it and serializes a task
	// execution exception error object; no recovery is needed at this layer.

	// The Go descriptor is only needed for actor-related tasks; the executor
	// performs this conversion itself for normal tasks (which dominate the
	// workload), so converting here unconditionally would duplicate the work on
	// every normal task.
	switch contract.TaskType(taskType) {
	case contract.TaskTypeActorCreation:
		// Actor creation: run the registered constructor and keep the instance.
		goDesc, err := function.FromBaseFunctionDescriptor(functionDescriptor)
		if err != nil {
			return nil, fmt.Errorf("invalid function descriptor: %w", err)
		}
		instance, err := nr.actorManager.ConstructActor(goDesc, args)
		if err != nil {
			return nil, err
		}
		nr.actorManager.SetInstance(actorID, instance)
		return nil, nil
	case contract.TaskTypeActorTask:
		// Method calls on the same actor are serialized by the C++ core worker's
		// ConcurrencyGroupManager according to the actor's max_concurrency; the Go
		// side performs no additional per-actor locking (Java parity).
		goDesc, err := function.FromBaseFunctionDescriptor(functionDescriptor)
		if err != nil {
			return nil, fmt.Errorf("invalid function descriptor: %w", err)
		}
		results, execErr := nr.actorManager.ExecuteActorMethod(actorID, goDesc, args)
		if execErr != nil && rayerrors.IsActorExitError(execErr) {
			// Intentional actor exit (api.ExitActor). Tell the C++ CoreWorker the
			// actor should exit so it tears the worker down with
			// INTENDED_USER_EXIT; that is what makes the raylet mark the actor dead
			// and release its resources. Python's ray.actor.exit_actor does the same
			// via set_current_actor_should_exit(). Without it the actor stays ALIVE
			// and keeps holding its CPUs.
			nr.workerContext.SetCurrentActorShouldExit()
		}
		return results, execErr
	default:
		// Normal task: delegate to the executor (which also handles the case
		// where the actor ID is nil for ordinary function calls).
		return nr.executor.Execute(functionDescriptor, args, numReturns)
	}
}

// Shutdown shuts down the native runtime.
//
// Thread safety: Uses atomic.Bool.CompareAndSwap to ensure shutdown happens only once.
// ObjectStore is closed along with the runtime to ensure proper resource cleanup.
//
// Shutdown order is critical:
// 1. Close GCS client FIRST (before C++ shutdown, so C++ objects are still valid)
// 2. Clear worker resources (before C++ shutdown)
// 3. Clear ObjectStore reference
// 4. Shutdown C++ LAST (handle.Shutdown() calls C++ shutdown which releases all C++ objects)
func (nr *NativeRuntime) Shutdown() error {
	logger.Info("Native runtime shutdown started")

	if !nr.initialized.CompareAndSwap(true, false) {
		logger.Info("Native runtime shutdown skipped: not initialized")
		return ErrRuntimeNotInitialized
	}

	// Block an in-flight RemoveLocalReference for the whole teardown: it is the
	// one object-store CGO call that takes the read side of this lock, so once the
	// write lock is held that call cannot reach the C++ CoreWorker while the
	// CoreWorker is being destroyed. The store's other CGO calls are not gated by
	// this lock.
	nr.shutdownLock.Lock()
	defer nr.shutdownLock.Unlock()

	nr.mu.Lock()
	if nr.handle == nil {
		nr.mu.Unlock()
		logger.Info("Native runtime shutdown skipped: handle is nil")
		return ErrRuntimeNotInitialized
	}

	// Clear handle while holding lock
	handle := nr.handle
	nr.handle = nil
	nr.mu.Unlock()

	// IMPORTANT: Close Go-layer resources BEFORE C++ shutdown
	// This ensures C++ objects are still valid when Go calls into C++

	// Close GCS client first (uses C++ CGcsClient internally)
	client := nr.gcsClient.Swap(nil)
	if client != nil && *client != nil {
		if err := (*client).Close(); err != nil {
			logger.Error(err, "Failed to close GCS client during shutdown. This is non-fatal as the process will exit.",
				"gcsAddress", (*client).Address(),
			)
		} else {
			logger.Info("GCS client closed")
		}
	}

	// Note: ClearWorkerResources is intentionally NOT called during shutdown.
	// The worker resource cache is only used to avoid repeated Raylet queries,
	// and it will be automatically cleaned up when the process exits.
	// Calling WorkerContext() during shutdown would return nil because initialized
	// is set to false at the start of Shutdown(), before C++ CoreWorker is actually
	// shutdown. This would cause a nil pointer dereference.

	// Clear ObjectStore reference
	nr.objectStore = nil
	logger.Info("ObjectStore cleared during shutdown")

	// Shutdown C++ LAST - after all Go-layer cleanup is done
	handle.Shutdown()

	logger.Info("Native runtime shutdown complete")
	return nil
}

// GetObjectStore returns the internal ObjectStore instance.
// This method is part of the Runtime interface and is called by RuntimeHandle.ObjectStore()
// to access the ObjectStore. The ObjectStore is created during Start() and cleared
// during Shutdown() to maintain proper lifecycle management.
//
// Thread safety: ObjectStore is created during Start() before any concurrent access,
// so no synchronization is needed in this getter.
//
// Note: After Shutdown() is called, this method returns nil.
func (nr *NativeRuntime) GetObjectStore() object.ObjectStore {
	return nr.objectStore
}

// GetTaskSubmitter returns the task submitter for submitting tasks.
// This method is part of the Runtime interface and is used by the API layer
// to obtain a TaskSubmitter for task submission operations.
//
// Thread safety: Creates a new NativeTaskSubmitter instance on each call.
// The FunctionManager is stateless, so multiple instances can coexist safely.
//
// Note: Returns nil if the runtime is not initialized.
func (nr *NativeRuntime) GetTaskSubmitter() submitter.TaskSubmitter {
	nr.mu.RLock()
	defer nr.mu.RUnlock()

	if nr.handle == nil {
		return nil
	}

	// Reuse the same FunctionManager instance
	return cgointerfaces.NewNativeTaskSubmitter(nr.functionManager)
}

// Run runs the task execution loop.
//
// Note: This method is only called in Worker mode.
func (nr *NativeRuntime) Run() error {
	// Only hold lock while checking handle to avoid blocking other operations
	// during long-running task execution loop.
	nr.mu.RLock()
	handle := nr.handle
	nr.mu.RUnlock()

	if handle == nil {
		return ErrRuntimeNotInitialized
	}

	// Run without holding lock to avoid blocking other operations
	return handle.RunTaskExecutionLoop()
}

// IsInitialized checks whether the runtime has been initialized.
func (nr *NativeRuntime) IsInitialized() bool {
	nr.mu.RLock()
	defer nr.mu.RUnlock()
	return nr.handle != nil
}

// GetNodeIPAddress returns the node IP address from runtime options.
func (nr *NativeRuntime) GetNodeIPAddress() string {
	return nr.opts.Network.NodeIPAddress
}

// GetFunctionManager returns the function manager for internal use.
// This is used by the worker package to register functions from the global registry.
//
// Note: This method is only intended for use during worker startup.
// Returns nil if the runtime is not initialized.
func (nr *NativeRuntime) GetFunctionManager() function.Manager {
	nr.mu.RLock()
	defer nr.mu.RUnlock()
	return nr.functionManager
}

// RegisterActorConstructor implements contract.ActorConstructorRegistrar.
// It registers an actor "<init>" constructor so that ACTOR_CREATION_TASK can be
// executed locally. The constructor is keyed by the actor descriptor's String()
// value (matching the descriptor used by api.Actor and the task spec).
func (nr *NativeRuntime) RegisterActorConstructor(descKey string, ctor contract.ActorConstructor) {
	nr.mu.RLock()
	am := nr.actorManager
	nr.mu.RUnlock()
	if am == nil {
		logger.Error(nil, "actor manager not initialized, cannot register actor constructor")
		return
	}
	am.RegisterConstructor(descKey, ctor)
}

// Compile-time check that NativeRuntime implements the actor constructor
// registrar contract.
var _ contract.ActorConstructorRegistrar = (*NativeRuntime)(nil)

// GetGcsClient returns the GCS client, initializing it lazily if needed.
//
// Thread safety: Uses atomic operations for lock-free concurrent access.
// The client is initialized lazily on first access. If initialization fails,
// subsequent calls will retry (unlike sync.Once which only executes once).
func (nr *NativeRuntime) GetGcsClient() (gcs.Client, error) {
	// Fast path: check if client already exists (lock-free)
	if client := nr.gcsClient.Load(); client != nil {
		return *client, nil
	}

	// Check if runtime is initialized
	nr.mu.RLock()
	handle := nr.handle
	nr.mu.RUnlock()

	if handle == nil {
		return nil, ErrRuntimeNotInitialized
	}

	// Need to initialize - use mutex to prevent concurrent initialization
	nr.mu.Lock()
	defer nr.mu.Unlock()

	// Double-check after acquiring lock
	if client := nr.gcsClient.Load(); client != nil {
		return *client, nil
	}

	// Create GCS client options from runtime options
	// Convert []byte to ids.ClusterID
	var clusterID ids.ClusterID
	if len(nr.opts.Job.ClusterID) > 0 {
		var err error
		clusterID, err = ids.ClusterIDFromBinary(nr.opts.Job.ClusterID)
		if err != nil {
			logger.Error(err, "Failed to create ClusterID, using nil ClusterID")
			clusterID = ids.NilClusterID()
		}
	} else {
		clusterID = ids.NilClusterID()
	}

	opts := gcs.ClientOptions{
		Address:   nr.opts.Network.GcsAddress,
		ClusterID: clusterID,
		TimeoutMs: 5000, // Default timeout
	}

	logger.Info("Initializing GCS client lazily",
		"address", opts.Address,
		"timeoutMs", opts.TimeoutMs,
	)

	// Initialize GCS client using CGO implementation
	client, err := native.ConnectClient(opts)
	if err != nil {
		logger.Error(err, "Failed to connect GCS client",
			"address", opts.Address,
		)
		initErr := fmt.Errorf("failed to connect GCS client: %w", err)
		nr.gcsInitError.Store(&initErr)
		return nil, initErr
	}

	// Store client atomically
	nr.gcsClient.Store(&client)
	// Clear any previous error
	nr.gcsInitError.Store(nil)
	logger.Info("GCS client initialized successfully")

	return client, nil
}

// CloseGcsClient closes the GCS client if it was initialized.
//
// Thread safety: Uses atomic operations for safe concurrent access.
// This is typically called during shutdown, but can be called independently.
func (nr *NativeRuntime) CloseGcsClient() error {
	client := nr.gcsClient.Swap(nil) // Atomically set to nil and get old value
	if client != nil && *client != nil {
		if err := (*client).Close(); err != nil {
			logger.Error(err, "Failed to close GCS client")
			return err
		}
		logger.Info("GCS client closed")
	}
	return nil
}

// WorkerContext returns the worker context accessor.
//
// Implementation: Returns the package-level singleton NativeWorkerContext instance.
// NativeWorkerContext is stateless (all methods call CGO functions) and thread-safe,
// so a single global instance (globalWorkerContext) is shared across all NativeRuntime
// instances to avoid unnecessary allocations on the hot path.
// Phase: Phase 1 (Basic context retrieval)
//
// Thread safety: NativeWorkerContext methods are thread-safe as they call C++ functions.
// The singleton instance is safe to share across goroutines.
func (r *NativeRuntime) WorkerContext() base.WorkerContext {
	// Return nil if runtime is not initialized to avoid accessing uninitialized CoreWorker
	if !r.initialized.Load() {
		return nil
	}
	// Return package-level singleton instance
	return r.workerContext
}

// GetRunMode returns the current run mode (cluster or local).
//
// Currently always returns RunModeCluster since the native implementation
// is designed for cluster mode operation.
//
// Returns:
//   - RunMode: The current run mode
func (nr *NativeRuntime) GetRunMode() base.RunMode {
	return base.RunModeCluster
}

// IsLocalMode returns true if running in local mode.
//
// The native implementation always runs in cluster mode, so this method
// always returns false.
//
// Note: This method is not part of WorkerContext interface, so it remains
// in the Runtime interface.
func (nr *NativeRuntime) IsLocalMode() bool {
	return false
}

// WasCurrentActorRestarted returns true if the current actor was restarted
// due to failure or other reasons.
//
// This method queries the GCS client to retrieve the actor's NumRestarts
// field and returns true if it is greater than zero.
//
// Returns:
//   - bool: True if the actor was restarted, false otherwise
func (nr *NativeRuntime) WasCurrentActorRestarted() bool {
	// Get current actor ID from WorkerContext
	ctx := nr.WorkerContext()
	if ctx == nil {
		return false
	}
	actorID := ctx.GetCurrentActorID()
	if actorID.IsNil() {
		// Not in actor context
		return false
	}

	// Get GCS client
	gcsClient, err := nr.GetGcsClient()
	if err != nil || gcsClient == nil {
		logger.Error(err, "Failed to get GCS client for actor restart check")
		return false
	}

	// Get actor info from GCS
	bgCtx := context.Background()
	actorInfo, err := gcsClient.GetActorInfo(bgCtx, actorID)
	if err != nil {
		logger.Error(err, "Failed to get actor info", "actorID", actorID)
		return false
	}

	// Check if NumRestarts > 0
	return int(actorInfo.NumRestarts) > 0
}

// GetAllNodeInfo returns information about all nodes in the cluster.
//
// Phase 2: This method will query the GCS client to retrieve comprehensive
// information about all nodes currently in the Ray cluster.
//
// Returns:
//   - []NodeInfo: Slice of NodeInfo for all nodes, or empty slice on error
func (nr *NativeRuntime) GetAllNodeInfo() []base.NodeInfo {
	// Get GCS client
	gcsClient, err := nr.GetGcsClient()
	if err != nil || gcsClient == nil {
		return []base.NodeInfo{}
	}

	// Get all nodes from GCS
	ctx := context.Background()
	nodesMap, err := gcsClient.GetAll(ctx, nil)
	if err != nil {
		logger.Error(err, "Failed to get all nodes from GCS")
		return []base.NodeInfo{}
	}

	// Convert protobuf to NodeInfo slice
	result := make([]base.NodeInfo, 0, len(nodesMap))
	for _, protoNode := range nodesMap {
		result = append(result, convertNodeInfo(protoNode))
	}

	return result
}

// GetAllActorInfo returns information about all actors in the cluster.
//
// Phase 2: This method will query the GCS client to retrieve comprehensive
// information about all actors currently registered in the Ray cluster.
//
// Returns:
//   - []ActorInfo: Slice of ActorInfo for all actors, or empty slice on error
func (nr *NativeRuntime) GetAllActorInfo() []base.ActorInfo {
	// GetAllActorInfo is the unfiltered form of GetAllActorInfoByFilter: a nil
	// job ID (NilJobID()) and ActorStateAny apply no job/state filter, so it
	// delegates to keep the GCS query and conversion logic in one place.
	return nr.GetAllActorInfoByFilter(ids.NilJobID(), contract.ActorStateAny)
}

// GetAllActorInfoByFilter returns actor information filtered by job ID and
// actor state. Consistent with Java RuntimeContext.getAllActorInfo(JobId,
// ActorState). A zero jobID means no job filter; ActorStateAny means no state
// filter.
func (nr *NativeRuntime) GetAllActorInfoByFilter(jobID ids.JobID, state contract.ActorState) []contract.ActorInfo {
	// Get GCS client
	gcsClient, err := nr.GetGcsClient()
	if err != nil || gcsClient == nil {
		logger.Error(err, "Failed to get GCS client when querying actors by filter")
		return []contract.ActorInfo{}
	}

	// The GCS actor_state_map and the proto ActorTableData_ActorState enum have
	// no DRAINING state, so a DRAINING filter can never match any actor. Short
	// circuit to an empty result instead of falling back to "no filter", which
	// would silently return all actors (see actorStateToGCSName).
	if state == contract.ActorStateDraining {
		return []contract.ActorInfo{}
	}

	// Build jobID pointer: nil means "all jobs".
	var jobIDPtr *ids.JobID
	if !jobID.IsNil() {
		j := jobID
		jobIDPtr = &j
	}

	// Build state filter: nil means "no state filter". The filter is pushed
	// down to the GCS (ListActorsByFilter) rather than pulling all actors and
	// filtering in memory, consistent with Java RuntimeContext.getAllActorInfo.
	var stateName *gcs.ActorStateName
	if state != contract.ActorStateAny {
		s, err := actorStateToGCSName(state)
		if err != nil {
			// An unmappable state must not silently degrade to "no filter"
			// (which would return all actors); report it and return empty.
			logger.Error(err, "Unsupported actor state for GCS state filter")
			return []contract.ActorInfo{}
		}
		stateName = &s
	}

	ctx := context.Background()
	actors, err := gcsClient.ListActorsByFilter(ctx, jobIDPtr, stateName)
	if err != nil {
		logger.Error(err, "Failed to get actors from GCS by filter")
		return []contract.ActorInfo{}
	}

	// Convert protobuf to ActorInfo slice.
	result := make([]contract.ActorInfo, 0, len(actors))
	for _, protoActor := range actors {
		result = append(result, convertActorInfo(protoActor))
	}

	return result
}

// actorStateToGCSName maps a contract.ActorState to the actor state name used
// by the GCS getAll_actor_info filter. It returns an error for states that
// cannot be represented in the GCS filter, so callers must not fall back to a
// "no filter" query (which would silently return all actors) for them.
//
// ActorStateDraining is not mapped: the GCS C++ actor_state_map
// (actor_info_accessor.cc) has no "DRAINING" key, so passing it would silently
// insert a default value (0 = DEPENDENCIES_UNREADY) and return the wrong actors.
// The proto ActorTableData_ActorState enum also has no DRAINING value, so it
// cannot be represented downstream. GetAllActorInfoByFilter short circuits a
// DRAINING request to an empty result before reaching this function.
func actorStateToGCSName(state contract.ActorState) (gcs.ActorStateName, error) {
	switch state {
	case contract.ActorStatePending:
		return gcs.ActorStateNamePendingCreation, nil
	case contract.ActorStateAlive:
		return gcs.ActorStateNameAlive, nil
	case contract.ActorStateDead:
		return gcs.ActorStateNameDead, nil
	case contract.ActorStateRestarting:
		return gcs.ActorStateNameRestarting, nil
	case contract.ActorStateDraining:
		return "", fmt.Errorf("actor state %v (DRAINING) has no GCS filter representation", state)
	default:
		return "", fmt.Errorf("unknown actor state %v", state)
	}
}

// GetResourceIds returns the resource name -> resource ID/capacity mapping
// for the current worker. The data source is C++ CoreWorker::GetResourceIDs()
// via the cgo bridge. Consistent with Java RayRuntime.getAvailableResourceIds().
func (nr *NativeRuntime) GetResourceIds() map[string][]contract.ResourceValue {
	nr.mu.RLock()
	handle := nr.handle
	nr.mu.RUnlock()
	if handle == nil {
		return map[string][]contract.ResourceValue{}
	}
	entries, err := handle.GetResourceIds()
	if err != nil {
		// GetResourceIds has no error return in the contract.Runtime interface,
		// so a CGO failure degrades to an empty map (logged above). Callers of
		// GetResourceIds cannot distinguish a real backend failure from the
		// legitimate "no resources" case, which is acceptable for this
		// low-frequency diagnostic API.
		logger.Error(err, "GetResourceIds failed")
		return map[string][]contract.ResourceValue{}
	}
	result := make(map[string][]contract.ResourceValue, len(entries))
	for _, e := range entries {
		values := make([]contract.ResourceValue, 0, len(e.ResourceIds))
		for _, rid := range e.ResourceIds {
			values = append(values, contract.ResourceValue{
				ResourceID: rid.Index,
				Capacity:   rid.Quantity,
			})
		}
		result[e.Name] = values
	}
	return result
}

// GetGpuIds returns the IDs of GPUs allocated to the current worker.
//
// This method retrieves GPU resource IDs from the resource manager and maps
// them to actual CUDA device IDs using the CUDA_VISIBLE_DEVICES environment
// variable. The mapping is necessary because CUDA_VISIBLE_DEVICES may reorder
// or restrict which physical GPU devices are visible to the process.
//
// For example, if CUDA_VISIBLE_DEVICES="0,2,4" and the resource manager
// assigns GPU resource IDs ["0", "1"], the returned CUDA device IDs will be
// ["0", "2"] (the first and second entries in CUDA_VISIBLE_DEVICES).
//
// Returns:
//   - []string: List of CUDA device IDs (e.g., ["0", "2", "4"]), or empty
//     slice if no GPUs are allocated or CUDA_VISIBLE_DEVICES is not set
func (nr *NativeRuntime) GetGpuIds() []string {
	// 1. Get current worker ID
	workerID := nr.WorkerContext().GetCurrentWorkerId()
	if workerID.IsNil() {
		logger.Info("Cannot get GPU IDs: worker ID is nil")
		return []string{}
	}

	// 2. Query resource manager for GPU resource IDs
	resourceIds := nr.resourceManager.GetWorkerResourceIds(workerID)

	// 3. Extract GPU resource IDs from resource map
	gpuResourceIds := object.ParseGPUResourceIds(resourceIds)
	if len(gpuResourceIds) == 0 {
		// No GPU resources allocated
		return []string{}
	}

	// 4. Read CUDA_VISIBLE_DEVICES environment variable
	cudaVisibleDevices := object.GetCudaVisibleDevices()

	// 5. Map GPU resource IDs to actual CUDA device IDs
	if cudaVisibleDevices == nil {
		// CUDA_VISIBLE_DEVICES not set, return resource IDs as-is
		return gpuResourceIds
	}

	// Map resource IDs to CUDA device IDs
	var gpuIds []string
	for _, resId := range gpuResourceIds {
		idx, err := strconv.Atoi(resId)
		if err != nil || idx < 0 || idx >= len(cudaVisibleDevices) {
			// Invalid index, skip this resource ID
			logger.Info("Invalid GPU resource ID", "resourceId", resId, "error", err)
			continue
		}
		gpuIds = append(gpuIds, cudaVisibleDevices[idx])
	}

	return gpuIds
}

// GetCurrentActorHandle returns the handle of the current actor.
//
// This method creates a NativeActorHandle with the current actor ID.
//
// Returns:
//   - submitter.ActorHandle: Actor handle if in actor context, nil otherwise
func (nr *NativeRuntime) GetCurrentActorHandle() submitter.ActorHandle {
	// Get current actor ID from WorkerContext
	ctx := nr.WorkerContext()
	if ctx == nil {
		return nil
	}
	actorID := ctx.GetCurrentActorID()
	if actorID.IsNil() {
		// Not in actor context
		return nil
	}

	// Create NativeActorHandle with the current actor ID
	return &object.NativeActorHandle{
		ActorID:  actorID,
		Language: object.LanguageGo,
	}
}

// CreateRuntimeEnv creates an empty runtime env.
func (nr *NativeRuntime) CreateRuntimeEnv() contract.RuntimeEnv {
	return contract.RuntimeEnv{}
}

// DeserializeRuntimeEnv deserializes a serialized runtime env JSON string.
func (nr *NativeRuntime) DeserializeRuntimeEnv(serializedRuntimeEnv string) (contract.RuntimeEnv, error) {
	return contract.UnmarshalRuntimeEnv(serializedRuntimeEnv)
}

// NativeHandleImpl implements contract.RuntimeHandle interface for native runtime.
type NativeHandleImpl struct {
	runtime *NativeRuntime
}

// IsRuntimeHandle implements the marker method (exported to allow implementation in other packages).
func (h *NativeHandleImpl) IsRuntimeHandle() {}

// Runtime returns the underlying runtime implementation.
func (h *NativeHandleImpl) Runtime() contract.Runtime {
	return h.runtime
}

// ObjectStore returns the object store for storing and retrieving objects.
func (h *NativeHandleImpl) ObjectStore() object.ObjectStore {
	return h.runtime.GetObjectStore()
}

// NativeRuntimeFactory is the factory implementation for native runtime.
type NativeRuntimeFactory struct{}

// Initialize initializes the native runtime and returns a handle.
func (f *NativeRuntimeFactory) Initialize(opts *options.InitializeOptions) (contract.RuntimeHandle, error) {
	// Driver bootstrap: resolve the local node's connection info from GCS when
	// the caller did not supply it (e.g. an in-process driver launched outside
	// of `ray job submit`). The C++ CoreWorker reads the raylet port from these
	// options before it can talk to the raylet, so they cannot be left at zero.
	if opts != nil && opts.WorkerType == options.WorkerTypeDriver {
		if err := bootstrapDriverOptions(opts); err != nil {
			return nil, err
		}
	}

	// Convert API options to internal options
	baseOpts, err := convertToBaseOptions(opts)
	if err != nil {
		return nil, fmt.Errorf("failed to convert options: %w", err)
	}

	// Create NativeRuntime instance
	runtime, err := NewNativeRuntime(baseOpts)
	if err != nil {
		return nil, fmt.Errorf("failed to create native runtime: %w", err)
	}

	// Start the runtime (this initializes CGO core worker)
	if err := runtime.Start(); err != nil {
		return nil, fmt.Errorf("failed to start native runtime: %w", err)
	}

	// Create and return handle
	handle := &NativeHandleImpl{runtime: runtime}
	return handle, nil
}

// CreateRuntime creates a new NativeRuntime instance with the given options.
// This method implements the base.RuntimeFactory interface.
// Note: This function only creates the runtime instance, it does not start it.
// The caller is responsible for calling Start() to initialize the CGO core worker.
func (f *NativeRuntimeFactory) CreateRuntime(opts base.InitializeOptions) (contract.Runtime, error) {
	runtime, err := NewNativeRuntime(opts)
	if err != nil {
		return nil, fmt.Errorf("failed to create native runtime: %w", err)
	}

	return runtime, nil
}

// helper function: convert API options to base options
func convertToBaseOptions(apiOpts *options.InitializeOptions) (base.InitializeOptions, error) {
	if apiOpts == nil {
		return base.InitializeOptions{}, nil
	}

	// Perform conversion - map all fields from API options to base options
	// Note: Need to convert between different types (string <-> []byte, int32 <-> int)
	jobIDBytes, err := ids.JobIDFromHex(apiOpts.Job.JobID)
	if err != nil {
		return base.InitializeOptions{}, fmt.Errorf("invalid JobID: %w", err)
	}

	var clusterIDBytes []byte
	if apiOpts.Job.ClusterID != "" {
		clusterIDBytes = []byte(apiOpts.Job.ClusterID)
	}

	return base.InitializeOptions{
		WorkerType: apiOpts.WorkerType,
		Network: base.NetworkOptions{
			NodeIPAddress:   apiOpts.Network.NodeIPAddress,
			NodeManagerPort: int(apiOpts.Network.NodeManagerPort),
			GcsAddress:      apiOpts.Network.GcsAddress,
		},
		Job: base.JobOptions{
			JobID:     jobIDBytes.Binary(),
			ClusterID: clusterIDBytes,
			JobConfig: []byte(apiOpts.Job.JobConfig),
		},
		Runtime: base.RuntimeOptions{
			StoreSocket:      apiOpts.Runtime.StoreSocket,
			RayletSocket:     apiOpts.Runtime.RayletSocket,
			LogDir:           apiOpts.Runtime.LogDir,
			StartupToken:     int(apiOpts.Runtime.StartupToken),
			RuntimeEnvHash:   int(apiOpts.Runtime.RuntimeEnvHash),
			MetricsAgentPort: base.NormalizeMetricsAgentPort(apiOpts.Runtime.MetricsAgentPort),
			WorkerIDHex:      apiOpts.Runtime.WorkerIDHex,
		},
	}, nil
}

// bootstrapDriverOptions fills in the local node's connection info from GCS
// when an in-process (cluster-mode) driver did not supply it explicitly.
// Ray Python resolves this in `node.py` by querying the GCS node table; the
// C++ CoreWorker needs the node_manager_port to connect to the raylet, so the
// values cannot remain zero.
//
// Only the fields that are still zero are overwritten; values the caller set
// are preserved.
func bootstrapDriverOptions(opts *options.InitializeOptions) error {
	// Short-circuit if the caller already provided the connection info.
	if opts.Network.NodeManagerPort != 0 && opts.Runtime.RayletSocket != "" &&
		opts.Runtime.StoreSocket != "" {
		return nil
	}

	nodeIP := opts.Network.NodeIPAddress
	if nodeIP == "" {
		// Detect from the GCS address perspective, matching the C++ / Python
		// node-IP resolution strategy (multi-homed hosts pick the interface
		// that can reach GCS).
		nodeIP = common.GetNodeIpAddressFromPerspective(&opts.Network.GcsAddress)
	}

	// Connect to GCS and ask for the node this driver should connect to.
	client, err := native.ConnectClient(gcs.ClientOptions{
		Address:   opts.Network.GcsAddress,
		ClusterID: ids.NilClusterID(),
		TimeoutMs: 10000,
	})
	if err != nil {
		return fmt.Errorf("bootstrapDriverOptions: connect to GCS failed: %w", err)
	}
	defer client.Close()

	ctx, cancel := context.WithTimeout(context.Background(), 15*time.Second)
	defer cancel()

	node, err := client.GetNodeToConnect(ctx, nodeIP)
	if err != nil {
		return fmt.Errorf("bootstrapDriverOptions: get node info failed: %w", err)
	}
	if node == nil {
		return fmt.Errorf("bootstrapDriverOptions: GCS returned no node info for ip %s", nodeIP)
	}

	if opts.Network.NodeManagerPort == 0 {
		opts.Network.NodeManagerPort = node.GetNodeManagerPort()
	}
	if opts.Runtime.RayletSocket == "" {
		opts.Runtime.RayletSocket = node.GetRayletSocketName()
	}
	if opts.Runtime.StoreSocket == "" {
		opts.Runtime.StoreSocket = node.GetObjectStoreSocketName()
	}
	if opts.Network.NodeIPAddress == "" {
		// Prefer the address the node manager advertises for connecting back.
		if addr := node.GetNodeManagerAddress(); addr != "" {
			opts.Network.NodeIPAddress = addr
		} else {
			opts.Network.NodeIPAddress = nodeIP
		}
	}

	log.Log.Info("driver bootstrap resolved node info from GCS",
		"node_id", node.GetNodeId(), "ip", opts.Network.NodeIPAddress, "port", opts.Network.NodeManagerPort)
	return nil
}

// runtimeFactoryRegistered tracks whether the runtime factory has been registered.
var runtimeFactoryRegistered atomic.Bool

// init automatically registers the native runtime initializer when the package is loaded.
// This is the key mechanism that allows api.InitWithOptions() to work without importing internal packages.
func init() {
	// Register the native runtime initializer for cluster modes (Driver/Worker).
	api.RegisterInitializer(options.WorkerTypeDriver, func(opts *options.InitializeOptions) (contract.RuntimeHandle, error) {
		factory := &NativeRuntimeFactory{}
		return factory.Initialize(opts)
	})
	api.RegisterInitializer(options.WorkerTypeWorker, func(opts *options.InitializeOptions) (contract.RuntimeHandle, error) {
		factory := &NativeRuntimeFactory{}
		return factory.Initialize(opts)
	})

	// Also register the old-style runtime factory for backward compatibility
	if runtimeFactoryRegistered.CompareAndSwap(false, true) {
		base.SetRuntimeFactory(&NativeRuntimeFactory{})
	}
}
