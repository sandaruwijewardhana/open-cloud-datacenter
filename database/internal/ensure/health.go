/*
Copyright 2026.

Licensed under the Apache License, Version 2.0 (the "License");
you may not use this file except in compliance with the License.
You may obtain a copy of the License at

    http://www.apache.org/licenses/LICENSE-2.0

Unless required by applicable law or agreed to in writing, software
distributed under the License is distributed on an "AS IS" BASIS,
WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
See the License for the specific language governing permissions and
limitations under the License.
*/

package ensure

import (
	"context"
	"fmt"
	"time"

	corev1 "k8s.io/api/core/v1"
	apierrors "k8s.io/apimachinery/pkg/api/errors"
	metav1 "k8s.io/apimachinery/pkg/apis/meta/v1"
	"sigs.k8s.io/controller-runtime/pkg/log"

	dbaasv1 "github.com/wso2/open-cloud-datacenter/crds/dbaas/api/v1alpha1"
	"github.com/wso2/open-cloud-datacenter/crds/dbaas/internal/harvester"
)

const (
	// healthRequeue is the timer fallback while waiting for the VM/PostgreSQL to
	// come up. The VMI watch usually re-triggers sooner; the timer covers windows
	// with no VMI events (e.g. before the VMI object exists).
	healthRequeue = 10 * time.Second

	// crashLoopParkRequeue is the cold re-probe cadence while parked under
	// CrashLoopHalted. Status is unchanged between probes, so the DeepEqual skip
	// keeps the loop write-free.
	crashLoopParkRequeue = 30 * time.Second

	// Crash-loop detection for unplanned restarts. Under
	// RunStrategyAlways KubeVirt recreates the VMI on every guest exit, so a
	// crash-looping VM "recovers" forever on its own. A chain of unplanned
	// restarts (VMI UID changes), each within crashLoopWindow of the previous,
	// reaching crashLoopThreshold halts the VM and parks the instance under the
	// CrashLoopHalted condition.
	crashLoopThreshold = 3                // chained unplanned restarts before giving up
	crashLoopWindow    = 10 * time.Minute // max gap between restarts to extend the chain
)

type healthStep struct{ Dependencies }

func newHealthStep(deps Dependencies) Step { return &healthStep{Dependencies: deps} }

func (*healthStep) Name() string { return "health" }

// Run checks readiness and liveness from one VMI observation. Parked
// instances are probed every 30 seconds for administrator-initiated recovery.
// The crash-loop guard runs before readiness checks and may halt the VM.
//
// During provisioning or an update, failed readiness returns Pending. Once
// the generation is reconciled, it reports Degraded without restarting the
// VM and returns Satisfied so aggregate readiness can be updated.
func (r *healthStep) Run(ctx context.Context, inst *dbaasv1.DBInstance) Result {
	// Desired stopped: there is nothing to gate on
	if !inst.Spec.WantRunning() {
		inst.SetCurrentCondition(dbaasv1.ConditionDatabaseReady, metav1.ConditionFalse,
			dbaasv1.ReasonStopped, "instance is stopped")
		return Satisfied()
	}

	readiness, err := r.Harvester.GetVMIReadiness(ctx, inst.Namespace, inst.Status.Resources.VMName)
	if err != nil {
		if !apierrors.IsNotFound(err) {
			// An unobserved VMI is not a health signal: Degraded is left untouched
			// and no VM operation is issued — the error just backs off.
			return Transient(err)
		}
		readiness = harvester.VMIReadiness{} // VMI object gone: boot gate / parked
	}

	// Check manual recovery before restart counting so a new VMI (manually up) can prove healthy
	// without being immediately halted again.
	if inst.Status.IsConditionTrue(dbaasv1.ConditionCrashLoopHalted) {
		// The old VMI may remain healthy during teardown; only a new UID proves a manual recovery start.
		recoveryVMI := readiness.VMIUID != "" && readiness.VMIUID != inst.Status.LastKnownVMIUID
		if recoveryVMI && readiness.Running && readiness.Ready && readiness.AgentConnected && readiness.IP != "" {
			if err := r.Harvester.ClearCrashLoopHalt(ctx, inst.Namespace, inst.Status.Resources.VMName); err != nil {
				return Transient(err)
			}
			r.Recorder.Eventf(inst, corev1.EventTypeNormal, string(dbaasv1.ReasonRecovered),
				"VM healthy again after crash-loop halt; resuming reconciliation")
			inst.Status.RemoveCondition(dbaasv1.ConditionCrashLoopHalted)
			// Re-snapshot the recovered VMI so its UID is not counted as another
			// unplanned restart.
			inst.Status.LastKnownVMIUID = readiness.VMIUID
			inst.Status.RecentUnplannedRestarts = 0
			// Fall through with the healthy VMI snapshot to update endpoint and readiness now.
		} else if recoveryVMI && readiness.Running && readiness.Ready && readiness.AgentConnected {
			msg := "recovery VM healthy; waiting for data-net IP"
			return PendingAfter(dbaasv1.ReasonVMBooting, msg, healthRequeue)
		} else {
			msg := "crash-loop halted; VM kept down — start the VM out-of-band once repaired to recover"
			return PendingAfter(dbaasv1.ReasonCrashLoopHalted, msg, crashLoopParkRequeue)
		}
	}

	// Crash-loop guard: first on every non-parked path, before readiness gates.
	if res, halted := r.trackRestarts(ctx, inst, readiness); halted {
		return res
	}

	port := specPortWithDefault(inst.Spec.Port, r.databaseDefaults().Port)

	// Readiness gates booting / change in flight instances; steady state failures are report-only.
	caughtUp := inst.Status.ObservedGeneration == inst.Generation

	if !readiness.Running || readiness.IP == "" {
		if caughtUp {
			r.reportDegraded(inst, readiness)
			return Satisfied() //Report only by design, nothing left controller can do
		}
		msg := "VM booting; waiting for guest agent and data-net IP"
		inst.SetCurrentCondition(dbaasv1.ConditionDatabaseReady, metav1.ConditionFalse, dbaasv1.ReasonVMBooting, msg)
		return PendingAfter(dbaasv1.ReasonVMBooting, msg, healthRequeue)
	}

	if !readiness.Ready {
		if caughtUp {
			r.reportDegraded(inst, readiness)
			return Satisfied()
		}
		msg := fmt.Sprintf("PostgreSQL initializing; readiness probe not passing at %s:%d", readiness.IP, port)
		inst.SetCurrentCondition(dbaasv1.ConditionDatabaseReady, metav1.ConditionFalse, dbaasv1.ReasonPostgresInitializing, msg)
		return PendingAfter(dbaasv1.ReasonPostgresInitializing, msg, healthRequeue)
	}

	// Healthy: clear any Degraded, refresh the endpoint (the data-net IP can
	// change after a restart or live migration), report ready.
	inst.Status.RemoveCondition(dbaasv1.ConditionDegraded)
	dbName := inst.EffectiveDBName()
	inst.Status.Endpoint = &dbaasv1.Endpoint{
		Address: readiness.IP,
		Port:    port,
		JDBCURL: fmt.Sprintf("jdbc:postgresql://%s:%d/%s?ssl=true&sslmode=verify-ca", readiness.IP, port, dbName),
	}
	inst.SetCurrentCondition(dbaasv1.ConditionDatabaseReady, metav1.ConditionTrue,
		dbaasv1.ReasonPostgresReady, "PostgreSQL is ready")
	return Satisfied()
}

// trackRestarts detects unplanned restarts (VMI UID changes — distinct from live
// migration, which preserves the UID) and chain-counts them into the crash-loop
// guard. It runs before any gate so a Pending return can never starve it. The
// restart history lives in status because it cannot be reconstructed from one
// VMI snapshot — it is an accumulated observation, never a step gate.
//
// At the threshold the VM is halted HERE, at detection (under RunStrategyAlways
// KubeVirt would otherwise restart it forever); ensurePowerState then refuses to
// start it while CrashLoopHalted but never fights an out-of-band recovery start.
func (r *healthStep) trackRestarts(ctx context.Context, inst *dbaasv1.DBInstance, readiness harvester.VMIReadiness) (Result, bool) {
	if readiness.VMIUID == "" {
		return Result{}, false
	}
	if inst.Status.LastKnownVMIUID == "" {
		// First observation of a running VMI — snapshot the baseline.
		inst.Status.LastKnownVMIUID = readiness.VMIUID
		return Result{}, false
	}
	if inst.Status.LastKnownVMIUID == readiness.VMIUID {
		return Result{}, false
	}

	log.FromContext(ctx).Info("unplanned VMI restart detected",
		"oldUID", inst.Status.LastKnownVMIUID, "newUID", readiness.VMIUID)
	r.Recorder.Eventf(inst, corev1.EventTypeWarning, string(dbaasv1.ReasonVMRestarting),
		"Unplanned VMI restart detected (UID %s → %s)", inst.Status.LastKnownVMIUID, readiness.VMIUID)
	inst.Status.RestartCount++ // observability only
	inst.Status.LastKnownVMIUID = readiness.VMIUID

	// Chain arithmetic: each restart within crashLoopWindow of the previous
	// extends the chain; a longer quiet gap starts a new one.
	now := metav1.Now()
	if inst.Status.LastUnplannedRestartTime != nil &&
		now.Sub(inst.Status.LastUnplannedRestartTime.Time) < crashLoopWindow {
		inst.Status.RecentUnplannedRestarts++
	} else {
		inst.Status.RecentUnplannedRestarts = 1
	}
	inst.Status.LastUnplannedRestartTime = &now

	if inst.Status.RecentUnplannedRestarts < crashLoopThreshold {
		return Result{}, false // absorbed; gates/Degraded reflect the reboot
	}

	// Threshold reached: halt now, then park under CrashLoopHalted. If the halt
	// fails nothing is recorded — the whole detection re-runs next pass.
	if err := r.Harvester.StopVMForCrashLoop(ctx, inst.Namespace, inst.Status.Resources.VMName, readiness.VMIUID); err != nil {
		log.FromContext(ctx).Error(err, "StopVMForCrashLoop failed during crash-loop halt (will retry)")
		return Transient(err), true
	}
	msg := fmt.Sprintf("VM crash loop: %d unplanned restarts, each within %s of the previous; VM halted, manual intervention required",
		inst.Status.RecentUnplannedRestarts, crashLoopWindow)
	r.Recorder.Eventf(inst, corev1.EventTypeWarning, string(dbaasv1.ReasonCrashLoopDetected), "%s", msg)
	inst.SetCurrentCondition(dbaasv1.ConditionCrashLoopHalted, metav1.ConditionTrue, dbaasv1.ReasonCrashLoopDetected, msg)
	inst.SetCurrentCondition(dbaasv1.ConditionDatabaseReady, metav1.ConditionFalse, dbaasv1.ReasonCrashLoopDetected, msg)
	inst.Status.RemoveCondition(dbaasv1.ConditionDegraded)
	return PendingAfter(dbaasv1.ReasonCrashLoopHalted, msg, crashLoopParkRequeue), true
}

// reportDegraded records caught-up failures without blocking reconciliation.
// VMI Ready is authoritative because its exec probe fails on guest-agent loss;
// Running and AgentConnected only attribute the cause.
func (r *healthStep) reportDegraded(inst *dbaasv1.DBInstance, readiness harvester.VMIReadiness) {
	reason := dbaasv1.ReasonPostgresUnreachable
	msg := "PostgreSQL readiness probe failing; database not accepting connections"
	switch {
	case !readiness.Running:
		reason = dbaasv1.ReasonVMRestarting
		msg = "VMI not running; VM restarting or halted out-of-band"
	case !readiness.AgentConnected:
		reason = dbaasv1.ReasonGuestAgentDisconnected
		msg = "Guest agent disconnected; cannot run readiness probe — database health unknown"
	}
	// Emit a Warning only when entering Degraded or when the cause changes, not on
	// every pass: the condition carries the persistent signal, and spamming status
	// would defeat the DeepEqual write-skip and self-trigger reconciles.
	if !hasConditionReason(inst, dbaasv1.ConditionDegraded, reason) {
		r.Recorder.Eventf(inst, corev1.EventTypeWarning, string(reason), "%s", msg)
	}
	inst.SetCurrentCondition(dbaasv1.ConditionDegraded, metav1.ConditionTrue, reason, msg)
	inst.SetCurrentCondition(dbaasv1.ConditionDatabaseReady, metav1.ConditionFalse, reason, msg)
}
