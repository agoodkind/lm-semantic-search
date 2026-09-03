// Package jobscheduler orders indexing work by effective scheduling policy.
package jobscheduler

import (
	"context"
	"fmt"
	"log/slog"
	"sort"
	"sync"
	"time"

	"goodkind.io/lm-semantic-search/internal/model"
	"goodkind.io/lm-semantic-search/internal/platformactivity"
)

const (
	// ReasonWaitingForCapacity means every slot is occupied by equal-priority work.
	ReasonWaitingForCapacity = "waiting for capacity"
	// ReasonHigherPriorityWork means higher-priority work controls admission.
	ReasonHigherPriorityWork = "higher-priority work"
	// ReasonActivityUnavailable means quiet work cannot observe input idle time.
	ReasonActivityUnavailable = "input activity unavailable"
	// ReasonWaitingForInputIdle means the configured idle duration has not elapsed.
	ReasonWaitingForInputIdle = "waiting for input idle"
	// ReasonThermalUnsafe means quiet work cannot run under the current thermal state.
	ReasonThermalUnsafe    = "thermal state unsafe"
	activitySampleInterval = 2 * time.Second
)

// EntryState records one scheduler entry's private lifecycle.
type EntryState uint8

const (
	// EntryWaiting means the entry is queued for capacity.
	EntryWaiting EntryState = iota
	// EntryRunning means the entry owns one capacity slot.
	EntryRunning
	// EntryPaused means the entry released capacity and retained its queue sequence.
	EntryPaused
)

// Entry describes one job competing for scheduler capacity.
type Entry struct {
	JobID          string
	Policy         model.SchedulingPolicy
	QueueSequence  uint64
	State          EntryState
	Reason         string
	PauseRequested bool
	generation     uint64
}

// PolicyUpdateReceipt records whether a queued policy update was staged before
// registration so rollback can restore the prior scheduler state atomically.
type PolicyUpdateReceipt struct {
	jobID             string
	staged            bool
	hadPreviousStaged bool
	previousStaged    model.SchedulingPolicyPatch
	entryGeneration   uint64
	policyGeneration  uint64
}

// Snapshot reports capacity use by scheduling priority.
type Snapshot struct {
	Capacity int
	Running  map[model.JobPriority]int
	Queued   map[model.JobPriority]int
	Paused   map[model.JobPriority]int
	Yields   uint64
	Activity platformactivity.Snapshot
}

// Scheduler admits jobs and requests cooperative priority pauses.
type Scheduler struct {
	mutex                         sync.Mutex
	capacity                      int
	entries                       map[string]*Entry
	registrationPolicies          map[string]model.SchedulingPolicyPatch
	registrationPolicyGenerations map[string]uint64
	pauseGenerations              map[string]uint64
	nextEntryGeneration           uint64
	pauseClaims                   map[string]uint64
	retryWaiting                  map[string]bool
	retryTimer                    *time.Timer
	yields                        uint64
	changed                       chan struct{}
	activitySource                platformactivity.Source
	activity                      platformactivity.Snapshot
	activityCancel                context.CancelFunc
	activityDone                  chan struct{}
	closeOnce                     sync.Once
}

// Lease owns one scheduler entry across running, paused, and waiting states.
type Lease struct {
	scheduler  *Scheduler
	jobID      string
	generation uint64
}

// PauseClaim gives one observer exclusive permission to pause and yield a
// running lease once.
type PauseClaim struct {
	lease      *Lease
	generation uint64
	reason     string
}

// New creates a scheduler that samples host activity when a source is supplied.
func New(
	ctx context.Context,
	capacity int,
	activitySource platformactivity.Source,
) *Scheduler {
	scheduler := &Scheduler{
		mutex:                sync.Mutex{},
		capacity:             capacity,
		entries:              map[string]*Entry{},
		registrationPolicies: map[string]model.SchedulingPolicyPatch{},
		pauseGenerations:     map[string]uint64{},
		nextEntryGeneration:  0,
		pauseClaims:          map[string]uint64{},
		retryWaiting:         map[string]bool{},
		retryTimer:           nil,
		yields:               0,
		changed:              make(chan struct{}),
		activitySource:       activitySource,
		activity: platformactivity.Snapshot{
			InputAvailable:   false,
			InputIdleFor:     0,
			InputReason:      ReasonActivityUnavailable,
			ThermalAvailable: false,
			ThermalUnsafe:    false,
			ThermalReason:    "",
		},
		activityCancel: nil,
		activityDone:   nil,
		closeOnce:      sync.Once{},
	}
	if activitySource == nil {
		return scheduler
	}
	if activity, sampled := sampleActivitySource(ctx, activitySource); sampled {
		scheduler.activity = activity
	}
	activityContext, cancel := context.WithCancel(context.WithoutCancel(ctx))
	scheduler.activityCancel = cancel
	scheduler.activityDone = make(chan struct{})
	go func() {
		defer func() {
			if recovered := recover(); recovered != nil {
				slog.Error(
					"activity sampler panic",
					"err",
					fmt.Errorf("panic: %v", recovered),
				)
			}
		}()
		scheduler.runActivitySampler(activityContext)
	}()
	return scheduler
}

// Close stops activity sampling and closes its source once.
func (scheduler *Scheduler) Close() {
	scheduler.closeOnce.Do(func() {
		if scheduler.activityCancel == nil {
			return
		}
		scheduler.activityCancel()
		<-scheduler.activityDone
		scheduler.activitySource.Close()
	})
}

func (scheduler *Scheduler) runActivitySampler(ctx context.Context) {
	defer close(scheduler.activityDone)
	ticker := time.NewTicker(activitySampleInterval)
	defer ticker.Stop()
	for {
		select {
		case <-ctx.Done():
			return
		case <-ticker.C:
			scheduler.sampleActivity(ctx)
		}
	}
}

func (scheduler *Scheduler) sampleActivity(ctx context.Context) {
	activity, sampled := sampleActivitySource(ctx, scheduler.activitySource)
	if !sampled {
		activity = unavailableActivitySnapshot()
	}
	scheduler.mutex.Lock()
	defer scheduler.mutex.Unlock()
	if scheduler.activity == activity {
		return
	}
	scheduler.activity = activity
	scheduler.rebalanceLocked()
	scheduler.notifyLocked()
}

func unavailableActivitySnapshot() platformactivity.Snapshot {
	return platformactivity.Snapshot{
		InputAvailable:   false,
		InputIdleFor:     0,
		InputReason:      ReasonActivityUnavailable,
		ThermalAvailable: false,
		ThermalUnsafe:    false,
		ThermalReason:    ReasonActivityUnavailable,
	}
}

func sampleActivitySource(
	ctx context.Context,
	source platformactivity.Source,
) (snapshot platformactivity.Snapshot, sampled bool) {
	defer func() {
		if recovered := recover(); recovered != nil {
			slog.Error(
				"activity source sample panic",
				"err",
				fmt.Errorf("panic: %v", recovered),
			)
			snapshot = unavailableActivitySnapshot()
			sampled = false
		}
	}()
	return source.Sample(ctx), true
}

// Acquire registers an entry and waits until it owns capacity or ctx ends.
func (scheduler *Scheduler) Acquire(
	ctx context.Context,
	entry Entry,
) (*Lease, error) {
	if err := ctx.Err(); err != nil {
		if entry.JobID != "" {
			scheduler.DiscardStagedPolicyUpdate(entry.JobID)
		}
		return nil, fmt.Errorf("acquire scheduler lease: %w", err)
	}
	if entry.JobID == "" {
		return nil, fmt.Errorf("scheduler job id is required")
	}
	if err := model.ValidateSchedulingPolicy(entry.Policy); err != nil {
		scheduler.DiscardStagedPolicyUpdate(entry.JobID)
		slog.Warn("validate scheduler policy failed", "job_id", entry.JobID, "err", err)
		return nil, fmt.Errorf("validate scheduler policy: %w", err)
	}

	scheduler.mutex.Lock()
	if _, found := scheduler.entries[entry.JobID]; found {
		scheduler.mutex.Unlock()
		return nil, fmt.Errorf("scheduler job %s already exists", entry.JobID)
	}
	if registrationPolicy, found := scheduler.registrationPolicies[entry.JobID]; found {
		policy, err := model.ApplySchedulingPolicyPatch(
			entry.Policy,
			registrationPolicy,
		)
		if err != nil {
			delete(scheduler.registrationPolicies, entry.JobID)
			delete(scheduler.registrationPolicyGenerations, entry.JobID)
			scheduler.mutex.Unlock()
			wrappedErr := fmt.Errorf("apply scheduler registration policy: %w", err)
			slog.Warn("apply scheduler registration policy failed", "job_id", entry.JobID, "err", wrappedErr)
			return nil, wrappedErr
		}
		entry.Policy = policy
		delete(scheduler.registrationPolicies, entry.JobID)
		delete(scheduler.registrationPolicyGenerations, entry.JobID)
	}
	scheduler.nextEntryGeneration++
	entry.generation = scheduler.nextEntryGeneration
	entry.State = EntryWaiting
	entry.Reason = ReasonWaitingForCapacity
	entry.PauseRequested = false
	scheduler.entries[entry.JobID] = &entry
	scheduler.rebalanceLocked()
	scheduler.notifyLocked()
	scheduler.mutex.Unlock()

	if err := scheduler.waitForRunning(ctx, entry.JobID, entry.generation, true); err != nil {
		return nil, err
	}
	return &Lease{scheduler: scheduler, jobID: entry.JobID, generation: entry.generation}, nil
}

// StagePolicyUpdate applies a policy to a registered entry or stores it for an
// in-flight queued job whose Acquire call has not registered yet.
func (scheduler *Scheduler) StagePolicyUpdate(
	jobID string,
	patch model.SchedulingPolicyPatch,
) (PolicyUpdateReceipt, error) {
	var emptyReceipt PolicyUpdateReceipt
	if jobID == "" {
		return emptyReceipt, fmt.Errorf("scheduler job id is required")
	}
	if _, err := model.ApplySchedulingPolicyPatch(
		model.DefaultSchedulingPolicy(),
		patch,
	); err != nil {
		wrappedErr := fmt.Errorf("validate staged scheduler policy: %w", err)
		slog.Warn("validate staged scheduler policy failed", "job_id", jobID, "err", wrappedErr)
		return emptyReceipt, wrappedErr
	}

	scheduler.mutex.Lock()
	defer scheduler.mutex.Unlock()
	entry, found := scheduler.entries[jobID]
	if !found {
		current, hadPrevious := scheduler.registrationPolicies[jobID]
		scheduler.registrationPolicies[jobID] = mergeSchedulingPolicyPatch(
			current,
			patch,
		)
		scheduler.registrationPolicyGenerations[jobID]++
		return PolicyUpdateReceipt{
			jobID:             jobID,
			staged:            true,
			hadPreviousStaged: hadPrevious,
			previousStaged:    current,
			entryGeneration:   0,
			policyGeneration:  scheduler.registrationPolicyGenerations[jobID],
		}, nil
	}
	if err := scheduler.updatePolicyLocked(entry, patch); err != nil {
		return emptyReceipt, err
	}
	return PolicyUpdateReceipt{
		jobID:             jobID,
		staged:            false,
		hadPreviousStaged: false,
		previousStaged: model.SchedulingPolicyPatch{
			Priority:         nil,
			Quiet:            nil,
			IdleAfterSeconds: nil,
		},
		entryGeneration:  entry.generation,
		policyGeneration: entry.policyGeneration,
	}, nil
}

// RollbackPolicyUpdate restores a staged or registered queued-job policy.
func (scheduler *Scheduler) RollbackPolicyUpdate(
	receipt PolicyUpdateReceipt,
	previousPolicy model.SchedulingPolicy,
) error {
	if receipt.jobID == "" {
		return fmt.Errorf("scheduler policy update receipt is missing a job id")
	}
	if err := model.ValidateSchedulingPolicy(previousPolicy); err != nil {
		wrappedErr := fmt.Errorf("validate scheduler rollback policy: %w", err)
		slog.Warn("validate scheduler rollback policy failed", "job_id", receipt.jobID, "err", wrappedErr)
		return wrappedErr
	}

	scheduler.mutex.Lock()
	defer scheduler.mutex.Unlock()
	if entry, found := scheduler.entries[receipt.jobID]; found {
		if receipt.entryGeneration != entry.generation || receipt.policyGeneration != entry.policyGeneration {
			return nil
		}
		entry.Policy = previousPolicy
		entry.policyGeneration++
		scheduler.rebalanceLocked()
		scheduler.notifyLocked()
		return nil
	}
	if !receipt.staged {
		return fmt.Errorf("scheduler job %s is missing", receipt.jobID)
	}
	if receipt.hadPreviousStaged {
		if scheduler.registrationPolicyGenerations[receipt.jobID] != receipt.policyGeneration {
			return nil
		}
		scheduler.registrationPolicies[receipt.jobID] = receipt.previousStaged
		scheduler.registrationPolicyGenerations[receipt.jobID]++
		return nil
	}
	if scheduler.registrationPolicyGenerations[receipt.jobID] != receipt.policyGeneration {
		return nil
	}
	delete(scheduler.registrationPolicies, receipt.jobID)
	delete(scheduler.registrationPolicyGenerations, receipt.jobID)
	return nil
}

// DiscardStagedPolicyUpdate removes a policy for a job cancelled before
// scheduler registration.
func (scheduler *Scheduler) DiscardStagedPolicyUpdate(jobID string) {
	scheduler.mutex.Lock()
	defer scheduler.mutex.Unlock()
	delete(scheduler.registrationPolicies, jobID)
	delete(scheduler.registrationPolicyGenerations, jobID)
}

// UpdatePolicy applies supplied fields and immediately recomputes admission.
func (scheduler *Scheduler) UpdatePolicy(
	jobID string,
	patch model.SchedulingPolicyPatch,
) error {
	scheduler.mutex.Lock()
	defer scheduler.mutex.Unlock()

	entry, found := scheduler.entries[jobID]
	if !found {
		return fmt.Errorf("scheduler job %s is missing", jobID)
	}
	return scheduler.updatePolicyLocked(entry, patch)
}

func (scheduler *Scheduler) updatePolicyLocked(
	entry *Entry,
	patch model.SchedulingPolicyPatch,
) error {
	policy, err := model.ApplySchedulingPolicyPatch(entry.Policy, patch)
	if err != nil {
		slog.Warn("update scheduler policy failed", "job_id", entry.JobID, "err", err)
		return fmt.Errorf("update scheduler policy: %w", err)
	}
	entry.Policy = policy
	entry.policyGeneration++
	scheduler.rebalanceLocked()
	scheduler.notifyLocked()
	return nil
}

func mergeSchedulingPolicyPatch(
	existing model.SchedulingPolicyPatch,
	incoming model.SchedulingPolicyPatch,
) model.SchedulingPolicyPatch {
	merged := existing
	if incoming.Priority != nil {
		merged.Priority = incoming.Priority
	}
	if incoming.Quiet != nil {
		merged.Quiet = incoming.Quiet
	}
	if incoming.IdleAfterSeconds != nil {
		merged.IdleAfterSeconds = incoming.IdleAfterSeconds
	}
	return merged
}

// Snapshot returns a consistent copy of scheduler counts.
func (scheduler *Scheduler) Snapshot() Snapshot {
	scheduler.mutex.Lock()
	defer scheduler.mutex.Unlock()

	snapshot := Snapshot{
		Capacity: scheduler.capacity,
		Running:  newSchedulerPriorityCounts(),
		Queued:   newSchedulerPriorityCounts(),
		Paused:   newSchedulerPriorityCounts(),
		Yields:   scheduler.yields,
		Activity: scheduler.activity,
	}
	for _, entry := range scheduler.entries {
		switch entry.State {
		case EntryWaiting:
			snapshot.Queued[entry.Policy.Priority]++
		case EntryRunning:
			snapshot.Running[entry.Policy.Priority]++
		case EntryPaused:
			snapshot.Paused[entry.Policy.Priority]++
		}
	}
	return snapshot
}

// Checkpoint reports whether running work must cooperatively pause.
func (lease *Lease) Checkpoint() (bool, string) {
	lease.scheduler.mutex.Lock()
	defer lease.scheduler.mutex.Unlock()

	entry, found := lease.scheduler.entries[lease.jobID]
	if !found || entry.generation != lease.generation || entry.State != EntryRunning {
		return false, ""
	}
	if !entry.PauseRequested || lease.scheduler.pauseClaims[lease.jobID] != 0 {
		return false, ""
	}
	return true, entry.Reason
}

// ClaimPauseRequest claims the current cooperative pause request once.
func (lease *Lease) ClaimPauseRequest() (*PauseClaim, bool) {
	return lease.claimPause("", true)
}

// ClaimYield claims a running lease for one non-priority yield.
func (lease *Lease) ClaimYield(reason string) (*PauseClaim, bool) {
	return lease.claimPause(reason, false)
}

func (lease *Lease) claimPause(
	reason string,
	requireRequest bool,
) (*PauseClaim, bool) {
	lease.scheduler.mutex.Lock()
	defer lease.scheduler.mutex.Unlock()

	entry, found := lease.scheduler.entries[lease.jobID]
	if !found || entry.generation != lease.generation || entry.State != EntryRunning {
		return nil, false
	}
	if lease.scheduler.pauseClaims[lease.jobID] != 0 {
		return nil, false
	}
	if requireRequest && !entry.PauseRequested {
		return nil, false
	}
	if reason == "" {
		reason = entry.Reason
	}
	generation := lease.scheduler.pauseGenerations[lease.jobID] + 1
	lease.scheduler.pauseGenerations[lease.jobID] = generation
	lease.scheduler.pauseClaims[lease.jobID] = generation
	return &PauseClaim{
		lease:      lease,
		generation: generation,
		reason:     reason,
	}, true
}

// Reason returns the scheduling reason captured by this claim.
func (claim *PauseClaim) Reason() string {
	return claim.reason
}

// Cancel releases an unused claim without changing capacity.
func (claim *PauseClaim) Cancel() {
	claim.lease.scheduler.mutex.Lock()
	defer claim.lease.scheduler.mutex.Unlock()
	entry, found := claim.lease.scheduler.entries[claim.lease.jobID]
	if !found || entry.generation != claim.lease.generation {
		return
	}
	if claim.lease.scheduler.pauseClaims[claim.lease.jobID] != claim.generation {
		return
	}
	delete(claim.lease.scheduler.pauseClaims, claim.lease.jobID)
	claim.lease.scheduler.notifyLocked()
}

// Yield consumes this claim and releases capacity once.
func (claim *PauseClaim) Yield() bool {
	claim.lease.scheduler.mutex.Lock()
	defer claim.lease.scheduler.mutex.Unlock()

	scheduler := claim.lease.scheduler
	entry, found := scheduler.entries[claim.lease.jobID]
	if !found || entry.generation != claim.lease.generation || entry.State != EntryRunning ||
		scheduler.pauseClaims[claim.lease.jobID] != claim.generation {
		return false
	}
	delete(scheduler.pauseClaims, claim.lease.jobID)
	delete(scheduler.retryWaiting, claim.lease.jobID)
	entry.State = EntryPaused
	entry.Reason = claim.reason
	entry.PauseRequested = false
	scheduler.yields++
	scheduler.rebalanceLocked()
	scheduler.notifyLocked()
	return true
}

// Yield releases capacity once and retains the entry for reacquisition.
func (lease *Lease) Yield(reason string) bool {
	claim, claimed := lease.ClaimYield(reason)
	if !claimed {
		return false
	}
	return claim.Yield()
}

// RetryAfter yields capacity and joins the scheduler's next shared retry round.
func (lease *Lease) RetryAfter(
	ctx context.Context,
	delay time.Duration,
	reason string,
) error {
	if err := ctx.Err(); err != nil {
		wrappedErr := fmt.Errorf("retry scheduler lease: %w", err)
		slog.Warn("retry scheduler lease canceled", "job_id", lease.jobID, "err", wrappedErr)
		return wrappedErr
	}
	if delay <= 0 {
		return fmt.Errorf("retry delay must be positive")
	}

	lease.scheduler.mutex.Lock()
	entry, found := lease.scheduler.entries[lease.jobID]
	if !found || entry.generation != lease.generation {
		lease.scheduler.mutex.Unlock()
		return fmt.Errorf("scheduler job %s is missing", lease.jobID)
	}
	if entry.State != EntryRunning {
		lease.scheduler.mutex.Unlock()
		return fmt.Errorf("scheduler job %s is not running", lease.jobID)
	}
	delete(lease.scheduler.pauseClaims, lease.jobID)
	entry.State = EntryPaused
	entry.Reason = reason
	entry.PauseRequested = false
	lease.scheduler.retryWaiting[lease.jobID] = true
	lease.scheduler.yields++
	lease.scheduler.startRetryRoundLocked(delay)
	lease.scheduler.rebalanceLocked()
	lease.scheduler.notifyLocked()
	lease.scheduler.mutex.Unlock()

	return lease.scheduler.waitForRunning(ctx, lease.jobID, lease.generation, false)
}

// Reacquire waits for the paused entry to regain capacity.
func (lease *Lease) Reacquire(ctx context.Context) error {
	lease.scheduler.mutex.Lock()
	entry, found := lease.scheduler.entries[lease.jobID]
	if !found || entry.generation != lease.generation {
		lease.scheduler.mutex.Unlock()
		return fmt.Errorf("scheduler job %s is missing", lease.jobID)
	}
	if entry.State == EntryRunning {
		lease.scheduler.mutex.Unlock()
		return nil
	}
	if err := ctx.Err(); err != nil {
		lease.scheduler.mutex.Unlock()
		wrappedErr := fmt.Errorf("reacquire scheduler lease: %w", err)
		slog.Warn("reacquire scheduler lease canceled", "job_id", lease.jobID, "err", wrappedErr)
		return wrappedErr
	}
	if entry.State == EntryPaused {
		delete(lease.scheduler.retryWaiting, lease.jobID)
		entry.State = EntryWaiting
		entry.PauseRequested = false
		lease.scheduler.rebalanceLocked()
		lease.scheduler.notifyLocked()
	}
	lease.scheduler.mutex.Unlock()

	return lease.scheduler.waitForRunning(ctx, lease.jobID, lease.generation, false)
}

// Release removes the entry once from running, waiting, or paused state.
func (lease *Lease) Release() {
	lease.scheduler.mutex.Lock()
	defer lease.scheduler.mutex.Unlock()

	entry, found := lease.scheduler.entries[lease.jobID]
	if !found || entry.generation != lease.generation {
		return
	}
	delete(lease.scheduler.entries, lease.jobID)
	delete(lease.scheduler.pauseClaims, lease.jobID)
	delete(lease.scheduler.pauseGenerations, lease.jobID)
	delete(lease.scheduler.retryWaiting, lease.jobID)
	lease.scheduler.rebalanceLocked()
	lease.scheduler.notifyLocked()
}

// UpdatePolicy applies supplied fields to this lease's entry.
func (lease *Lease) UpdatePolicy(patch model.SchedulingPolicyPatch) error {
	lease.scheduler.mutex.Lock()
	defer lease.scheduler.mutex.Unlock()
	entry, found := lease.scheduler.entries[lease.jobID]
	if !found || entry.generation != lease.generation {
		return fmt.Errorf("scheduler job %s is no longer owned by this lease", lease.jobID)
	}
	return lease.scheduler.updatePolicyLocked(entry, patch)
}

func (scheduler *Scheduler) waitForRunning(
	ctx context.Context,
	jobID string,
	generation uint64,
	removeOnCancel bool,
) error {
	for {
		scheduler.mutex.Lock()
		entry, found := scheduler.entries[jobID]
		if !found || entry.generation != generation {
			scheduler.mutex.Unlock()
			return fmt.Errorf("scheduler job %s is missing", jobID)
		}
		if err := ctx.Err(); err != nil {
			scheduler.cancelWaitLocked(entry, removeOnCancel)
			scheduler.mutex.Unlock()
			wrappedErr := fmt.Errorf("wait for scheduler job %s: %w", jobID, err)
			slog.Warn("scheduler wait canceled", "job_id", jobID, "err", wrappedErr)
			return wrappedErr
		}
		if entry.State == EntryRunning {
			scheduler.mutex.Unlock()
			return nil
		}
		changed := scheduler.changed
		scheduler.mutex.Unlock()

		select {
		case <-changed:
		case <-ctx.Done():
		}
	}
}

func (scheduler *Scheduler) cancelWaitLocked(
	entry *Entry,
	remove bool,
) {
	if remove {
		delete(scheduler.entries, entry.JobID)
		delete(scheduler.registrationPolicies, entry.JobID)
		delete(scheduler.pauseClaims, entry.JobID)
		delete(scheduler.pauseGenerations, entry.JobID)
		delete(scheduler.retryWaiting, entry.JobID)
	} else {
		entry.State = EntryPaused
		entry.PauseRequested = false
		delete(scheduler.pauseClaims, entry.JobID)
		delete(scheduler.retryWaiting, entry.JobID)
		if entry.Reason == "" {
			entry.Reason = ReasonWaitingForCapacity
		}
	}
	scheduler.rebalanceLocked()
	scheduler.notifyLocked()
}

func (scheduler *Scheduler) startRetryRoundLocked(delay time.Duration) {
	if scheduler.retryTimer != nil {
		return
	}
	scheduler.retryTimer = time.AfterFunc(delay, func() {
		defer func() {
			if recovered := recover(); recovered != nil {
				slog.Error("scheduler retry round panic", "err", fmt.Errorf("panic: %v", recovered))
			}
		}()
		scheduler.openRetryRound()
	})
}

func (scheduler *Scheduler) openRetryRound() {
	scheduler.mutex.Lock()
	defer scheduler.mutex.Unlock()

	scheduler.retryTimer = nil
	for jobID := range scheduler.retryWaiting {
		entry, found := scheduler.entries[jobID]
		if found && entry.State == EntryPaused {
			entry.State = EntryWaiting
			entry.PauseRequested = false
		}
		delete(scheduler.retryWaiting, jobID)
	}
	scheduler.rebalanceLocked()
	scheduler.notifyLocked()
}

func (scheduler *Scheduler) rebalanceLocked() {
	waiting := scheduler.eligibleWaitingEntriesLocked()
	runningCount := scheduler.runningCountLocked()
	for runningCount < scheduler.capacity && len(waiting) > 0 {
		entry := waiting[0]
		waiting = waiting[1:]
		entry.State = EntryRunning
		entry.Reason = ""
		entry.PauseRequested = false
		runningCount++
	}

	for _, entry := range scheduler.entries {
		if entry.State == EntryRunning {
			reason := scheduler.quietBlockingReasonLocked(entry.Policy)
			entry.PauseRequested = reason != ""
			entry.Reason = reason
		}
		if entry.State == EntryWaiting {
			entry.Reason = scheduler.waitingReasonLocked(entry)
		}
	}

	selectedVictims := map[string]bool{}
	for _, entry := range scheduler.entries {
		if entry.State == EntryRunning && entry.PauseRequested {
			selectedVictims[entry.JobID] = true
		}
	}
	freeSlots := scheduler.capacity - scheduler.runningCountLocked() + len(selectedVictims)
	waiting = scheduler.eligibleWaitingEntriesLocked()
	for _, waitingEntry := range waiting {
		if freeSlots > 0 {
			freeSlots--
			continue
		}
		victim := scheduler.selectVictimLocked(
			waitingEntry.Policy.Priority,
			selectedVictims,
		)
		if victim == nil {
			continue
		}
		selectedVictims[victim.JobID] = true
		victim.PauseRequested = true
		victim.Reason = ReasonHigherPriorityWork
	}
}

func (scheduler *Scheduler) eligibleWaitingEntriesLocked() []*Entry {
	waiting := scheduler.waitingEntriesLocked()
	eligible := make([]*Entry, 0, len(waiting))
	for _, entry := range waiting {
		if scheduler.quietBlockingReasonLocked(entry.Policy) == "" {
			eligible = append(eligible, entry)
		}
	}
	return eligible
}

func (scheduler *Scheduler) waitingEntriesLocked() []*Entry {
	waiting := make([]*Entry, 0, len(scheduler.entries))
	for _, entry := range scheduler.entries {
		if entry.State == EntryWaiting {
			waiting = append(waiting, entry)
		}
	}
	sort.Slice(waiting, func(i int, j int) bool {
		leftRank := schedulerPriorityRank(waiting[i].Policy.Priority)
		rightRank := schedulerPriorityRank(waiting[j].Policy.Priority)
		if leftRank != rightRank {
			return leftRank < rightRank
		}
		if waiting[i].QueueSequence != waiting[j].QueueSequence {
			return waiting[i].QueueSequence < waiting[j].QueueSequence
		}
		return waiting[i].JobID < waiting[j].JobID
	})
	return waiting
}

func (scheduler *Scheduler) selectVictimLocked(
	waitingPriority model.JobPriority,
	selected map[string]bool,
) *Entry {
	var victim *Entry
	for _, candidate := range scheduler.entries {
		if candidate.State != EntryRunning || selected[candidate.JobID] {
			continue
		}
		if schedulerPriorityRank(candidate.Policy.Priority) <= schedulerPriorityRank(waitingPriority) {
			continue
		}
		if victim == nil || schedulerVictimBefore(candidate, victim) {
			victim = candidate
		}
	}
	return victim
}

func schedulerVictimBefore(left *Entry, right *Entry) bool {
	leftRank := schedulerPriorityRank(left.Policy.Priority)
	rightRank := schedulerPriorityRank(right.Policy.Priority)
	if leftRank != rightRank {
		return leftRank > rightRank
	}
	if left.QueueSequence != right.QueueSequence {
		return left.QueueSequence > right.QueueSequence
	}
	return left.JobID > right.JobID
}

func (scheduler *Scheduler) waitingReasonLocked(entry *Entry) string {
	if reason := scheduler.quietBlockingReasonLocked(entry.Policy); reason != "" {
		return reason
	}
	entryRank := schedulerPriorityRank(entry.Policy.Priority)
	for _, candidate := range scheduler.entries {
		if candidate.JobID == entry.JobID || candidate.State == EntryPaused {
			continue
		}
		if scheduler.quietBlockingReasonLocked(candidate.Policy) != "" {
			continue
		}
		if schedulerPriorityRank(candidate.Policy.Priority) < entryRank {
			return ReasonHigherPriorityWork
		}
	}
	return ReasonWaitingForCapacity
}

func (scheduler *Scheduler) quietBlockingReasonLocked(
	policy model.SchedulingPolicy,
) string {
	if !policy.Quiet {
		return ""
	}
	if scheduler.activity.ThermalAvailable && scheduler.activity.ThermalUnsafe {
		return reasonOrFallback(scheduler.activity.ThermalReason, ReasonThermalUnsafe)
	}
	if policy.Priority == model.JobPriorityHigh {
		return ""
	}
	if !scheduler.activity.InputAvailable {
		return reasonOrFallback(scheduler.activity.InputReason, ReasonActivityUnavailable)
	}
	idleThreshold := time.Duration(policy.IdleAfterSeconds) * time.Second
	if scheduler.activity.InputIdleFor < idleThreshold {
		return reasonOrFallback(scheduler.activity.InputReason, ReasonWaitingForInputIdle)
	}
	return ""
}

func reasonOrFallback(reason string, fallback string) string {
	if reason != "" {
		return reason
	}
	return fallback
}

func (scheduler *Scheduler) runningCountLocked() int {
	running := 0
	for _, entry := range scheduler.entries {
		if entry.State == EntryRunning {
			running++
		}
	}
	return running
}

func (scheduler *Scheduler) notifyLocked() {
	close(scheduler.changed)
	scheduler.changed = make(chan struct{})
}

func schedulerPriorityRank(priority model.JobPriority) int {
	switch priority {
	case model.JobPriorityHigh:
		return 0
	case model.JobPriorityNormal:
		return 1
	case model.JobPriorityLow:
		return 2
	default:
		return 3
	}
}

func newSchedulerPriorityCounts() map[model.JobPriority]int {
	return map[model.JobPriority]int{
		model.JobPriorityHigh:   0,
		model.JobPriorityNormal: 0,
		model.JobPriorityLow:    0,
	}
}
