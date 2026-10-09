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

package harvester

import (
	"context"
	"encoding/json"
	"fmt"
	"strings"
	"sync"

	harvesterbuilder "github.com/harvester/harvester/pkg/builder"
	"github.com/harvester/harvester/pkg/util"
	dbaasv1 "github.com/wso2/open-cloud-datacenter/crds/dbaas/api/v1alpha1"
	corev1 "k8s.io/api/core/v1"
	apierrors "k8s.io/apimachinery/pkg/api/errors"
	"k8s.io/apimachinery/pkg/api/resource"
	metav1 "k8s.io/apimachinery/pkg/apis/meta/v1"
	"k8s.io/apimachinery/pkg/types"
	"k8s.io/client-go/kubernetes"
	"k8s.io/client-go/rest"
	"k8s.io/client-go/util/retry"
	kubevirtv1 "kubevirt.io/api/core/v1"

	harvesterhciov1beta1 "github.com/harvester/harvester/pkg/apis/harvesterhci.io/v1beta1"
	harvesterclientset "github.com/harvester/harvester/pkg/generated/clientset/versioned"
	kvclientset "kubevirt.io/client-go/kubevirt"
)

const (
	vmiPhaseRunning = "Running"
	// dataNetInterface is the VM's tenant-facing NIC, bridged onto the
	// Multus NAD from spec.networkRef. Tenant clients (psql / app pods
	// on the same VLAN) reach the DB through this interface; the
	// published status.endpoint.address is this interface's IP.
	dataNetInterface = "data-net"
)

// GuestBootstrapCompleteMarker is the in-guest path bootstrap.sh touches once
// the master role and its database exist, and that the readiness probe tests
// for before trusting pg_isready. It is declared here rather than in
// internal/credentials — which writes it — because credentials imports this
// package, so the dependency can only point this way.
// TestUserDataTouchesTheProbedBootstrapMarker pins the two in sync.
const GuestBootstrapCompleteMarker = "/var/lib/dbaas/bootstrap-complete"

// TypedClient manages Harvester resources through Harvester's generated
// clientset and standard Kubernetes typed clients.
type TypedClient struct {
	Clientset         harvesterclientset.Interface
	KubeClient        kubernetes.Interface
	KvClientset       kvclientset.Interface
	GrafanaURL        string
	MgmtLogicalSwitch string
	// DefaultImageNamespace is the Harvester namespace ResolveVMImage looks
	// in when its ref carries no explicit "ns/name" prefix. Empty means
	// "default" (the zero value keeps existing behavior for callers that
	// construct a TypedClient directly, e.g. in tests, without setting it).
	DefaultImageNamespace string
}

var _ ClientInterface = (*TypedClient)(nil)

func NewTypedClient(config *rest.Config, grafanaURL string) (*TypedClient, error) {
	clientset, err := harvesterclientset.NewForConfig(config)
	if err != nil {
		return nil, err
	}
	kubeClient, err := kubernetes.NewForConfig(config)
	if err != nil {
		return nil, err
	}
	kvClientset, err := kvclientset.NewForConfig(config)
	if err != nil {
		return nil, err
	}
	return NewTypedClientWithClientsets(clientset, kubeClient, kvClientset, grafanaURL), nil
}

func NewTypedClientWithClientsets(clientset harvesterclientset.Interface, kubeClient kubernetes.Interface, kvClientset kvclientset.Interface, grafanaURL string) *TypedClient {
	return &TypedClient{Clientset: clientset, KubeClient: kubeClient, KvClientset: kvClientset, GrafanaURL: grafanaURL}
}

func (c *TypedClient) ResizeDataVolume(ctx context.Context, ns, vmName, dvName string, newSizeGB int) error {
	newReq := resource.MustParse(fmt.Sprintf("%dGi", newSizeGB))
	return retry.RetryOnConflict(retry.DefaultRetry, func() error {
		vm, err := c.Clientset.KubevirtV1().VirtualMachines(ns).Get(ctx, vmName, metav1.GetOptions{})
		if err != nil {
			return err
		}
		pvcs, err := VolumeClaimTemplates(vm)
		if err != nil {
			return err
		}
		// Index into the slice rather than range-copy: the mutation below must
		// reach the element that gets re-marshalled, independent of whether
		// VolumeClaimTemplates returns pointers or values.
		found := false
		for i := range pvcs {
			if pvcs[i].Name != dvName {
				continue
			}
			found = true
			// Grow-only: Harvester expands the live PVC only when the annotation
			// request exceeds the current size and silently ignores anything <=
			// (vm_controller.go createPVCsFromAnnotation). Skip the write unless
			// we're actually growing, so we never rewrite an unchanged annotation
			// (needless VM update + self-triggered reconcile) nor leave the
			// annotation understating the real PVC. The caller rejects true shrinks.
			if cur, ok := pvcs[i].Spec.Resources.Requests[corev1.ResourceStorage]; ok && newReq.Cmp(cur) <= 0 {
				return nil
			}
			if pvcs[i].Spec.Resources.Requests == nil {
				pvcs[i].Spec.Resources.Requests = corev1.ResourceList{}
			}
			pvcs[i].Spec.Resources.Requests[corev1.ResourceStorage] = newReq
			break
		}
		if !found {
			return fmt.Errorf("data volume claim template %s not found on VM %s/%s", dvName, ns, vmName)
		}
		data, err := json.Marshal(pvcs)
		if err != nil {
			return fmt.Errorf("marshal %s: %w", util.AnnotationVolumeClaimTemplates, err)
		}
		if vm.Annotations == nil {
			vm.Annotations = map[string]string{}
		}
		vm.Annotations[util.AnnotationVolumeClaimTemplates] = string(data)
		_, err = c.Clientset.KubevirtV1().VirtualMachines(ns).Update(ctx, vm, metav1.UpdateOptions{})
		return err
	})
}

func (c *TypedClient) CreatePostgresVM(ctx context.Context, p VMCreateParams) (vmName string, err error) {
	vmName = VMName(p.ID)
	if p.DataVolumeStorageClass == "" {
		return vmName, fmt.Errorf("data volume storage class must not be empty")
	}
	if p.OSDiskPVCName == "" {
		return vmName, fmt.Errorf("OS disk PVC name must not be empty")
	}

	image, err := c.ResolveVMImage(ctx, p.OSImage)
	if err != nil {
		return vmName, err
	}

	vm, err := c.buildPostgresVM(p, vmName, p.CloudInitSecretName,
		fmt.Sprintf("%s/%s", image.Namespace, image.Name), image.StorageClassName, true)
	if err != nil {
		return vmName, err
	}
	vm.OwnerReferences = ownerRefSlice(p.Owner)
	if _, e := c.Clientset.KubevirtV1().VirtualMachines(p.Namespace).Create(ctx, vm, metav1.CreateOptions{}); e != nil {
		err = ignoreAlreadyExists(e)
	}
	return vmName, err
}

// ownerRefSlice wraps an optional controller owner reference for ObjectMeta
// assignment (nil in → nil out, leaving OwnerReferences unset).
func ownerRefSlice(ref *metav1.OwnerReference) []metav1.OwnerReference {
	if ref == nil {
		return nil
	}
	return []metav1.OwnerReference{*ref}
}

func (c *TypedClient) GetVMIReadiness(ctx context.Context, ns, vmName string) (VMIReadiness, error) {
	vmi, err := c.Clientset.KubevirtV1().VirtualMachineInstances(ns).Get(ctx, vmName, metav1.GetOptions{})
	if err != nil {
		return VMIReadiness{}, err
	}

	readiness := VMIReadiness{
		Running: string(vmi.Status.Phase) == vmiPhaseRunning,
		VMIUID:  string(vmi.UID),
	}
	for _, iface := range vmi.Status.Interfaces {
		if iface.Name != dataNetInterface {
			continue
		}
		readiness.IP = iface.IP
		break
	}
	for _, cond := range vmi.Status.Conditions {
		switch cond.Type {
		case kubevirtv1.VirtualMachineInstanceReady:
			readiness.Ready = cond.Status == corev1.ConditionTrue
		case kubevirtv1.VirtualMachineInstanceAgentConnected:
			readiness.AgentConnected = cond.Status == corev1.ConditionTrue
		}
	}
	return readiness, nil
}

// To align behavior with kubevirt v1.1.1, we set runStrategy to Halted when stopping a VM.
// see harvester/pkg/api/vm/handler.go 142 for harvester version 1.7.1
func (c *TypedClient) StopVM(ctx context.Context, ns, vmName string) error {
	return c.updateVM(ctx, ns, vmName, func(vm *kubevirtv1.VirtualMachine) bool {
		runStrategy := kubevirtv1.RunStrategyHalted
		vm.Spec.RunStrategy = &runStrategy
		vm.Spec.Running = nil
		return true
	})
}

// StopVMForCrashLoop atomically halts the VM and records which VMI triggered
// the safety halt. The marker survives a controller crash before DBInstance
// status is persisted.
func (c *TypedClient) StopVMForCrashLoop(ctx context.Context, ns, vmName, haltedVMIUID string) error {
	if haltedVMIUID == "" {
		return fmt.Errorf("halted VMI UID must not be empty")
	}
	return c.updateVM(ctx, ns, vmName, func(vm *kubevirtv1.VirtualMachine) bool {
		runStrategy := kubevirtv1.RunStrategyHalted
		vm.Spec.RunStrategy = &runStrategy
		vm.Spec.Running = nil
		if vm.Annotations == nil {
			vm.Annotations = map[string]string{}
		}
		vm.Annotations[dbaasv1.AnnotationCrashLoopHaltedVMIUID] = haltedVMIUID
		return true
	})
}

// ClearCrashLoopHalt removes only the durable crash-loop marker. Recovery has
// already been initiated out-of-band, so this does not change VM power state.
func (c *TypedClient) ClearCrashLoopHalt(ctx context.Context, ns, vmName string) error {
	return c.updateVM(ctx, ns, vmName, func(vm *kubevirtv1.VirtualMachine) bool {
		if _, ok := vm.Annotations[dbaasv1.AnnotationCrashLoopHaltedVMIUID]; !ok {
			return false
		}
		delete(vm.Annotations, dbaasv1.AnnotationCrashLoopHaltedVMIUID)
		return true
	})
}

func (c *TypedClient) updateVM(ctx context.Context, ns, vmName string, mutate func(*kubevirtv1.VirtualMachine) bool) error {
	return retry.RetryOnConflict(retry.DefaultRetry, func() error {
		vm, err := c.Clientset.KubevirtV1().VirtualMachines(ns).Get(ctx, vmName, metav1.GetOptions{})
		if err != nil {
			return err
		}
		if !mutate(vm) {
			return nil
		}
		_, err = c.Clientset.KubevirtV1().VirtualMachines(ns).Update(ctx, vm, metav1.UpdateOptions{})
		return err
	})
}

// see harvester/pkg/api/vm/handler.go 138 : harvester version 1.7.1
func (c *TypedClient) StartVM(ctx context.Context, ns, vmName string) error {
	return c.KvClientset.KubevirtV1().VirtualMachines(ns).Start(ctx, vmName, &kubevirtv1.StartOptions{})
}

// Perform a Cold Resize of a VM - Stopping the exisintg VM and starting back is the responsibility of the caller.
func (c *TypedClient) ResizeVM(ctx context.Context, ns, vmName string, cpuCores, memoryMB int) error {
	return retry.RetryOnConflict(retry.DefaultRetry, func() error {
		vm, err := c.Clientset.KubevirtV1().VirtualMachines(ns).Get(ctx, vmName, metav1.GetOptions{})
		if err != nil {
			return err
		}
		if vm.Spec.Template.Spec.Domain.CPU == nil {
			vm.Spec.Template.Spec.Domain.CPU = &kubevirtv1.CPU{} // lazy init to avoid nil dereference
		}
		vm.Spec.Template.Spec.Domain.CPU.Cores = uint32(cpuCores)
		if vm.Spec.Template.Spec.Domain.Resources.Limits == nil {
			vm.Spec.Template.Spec.Domain.Resources.Limits = corev1.ResourceList{}
		}
		vm.Spec.Template.Spec.Domain.Resources.Limits[corev1.ResourceCPU] = *resource.NewQuantity(int64(cpuCores), resource.DecimalSI)
		// Memory: set limits only — the Harvester mutating webhook derives domain.memory.guest
		// from resources.limits[memory] on every VM update (pkg/webhook/.../mutator.go).
		vm.Spec.Template.Spec.Domain.Resources.Limits[corev1.ResourceMemory] = resource.MustParse(fmt.Sprintf("%dMi", memoryMB))
		_, err = c.Clientset.KubevirtV1().VirtualMachines(ns).Update(ctx, vm, metav1.UpdateOptions{})
		return err
	})
}

// Deploy the prometheus monitoring stack. Discussion : Harvester already have Prometheus operator, what to do ?
func (c *TypedClient) TeardownAll(ctx context.Context, id, ns string, refs dbaasv1.ResourceRefs) error {
	type deleteTask struct {
		resource string
		name     string
		delete   func() error
	}
	tasks := []deleteTask{
		{"servicemonitors", refs.ServiceMonitor, func() error {
			return c.Clientset.MonitoringV1().ServiceMonitors(ns).Delete(ctx, refs.ServiceMonitor, metav1.DeleteOptions{})
		}},
		{"endpoints", refs.MetricsServiceName, func() error {
			return c.KubeClient.CoreV1().Endpoints(ns).Delete(ctx, refs.MetricsServiceName, metav1.DeleteOptions{})
		}},
		{"services", refs.MetricsServiceName, func() error {
			return c.KubeClient.CoreV1().Services(ns).Delete(ctx, refs.MetricsServiceName, metav1.DeleteOptions{})
		}},
		{"virtualmachines", refs.VMName, func() error {
			return c.Clientset.KubevirtV1().VirtualMachines(ns).Delete(ctx, refs.VMName, metav1.DeleteOptions{})
		}},
		{"secrets", refs.AdminCredentialsSecretName, func() error {
			return c.KubeClient.CoreV1().Secrets(ns).Delete(ctx, refs.AdminCredentialsSecretName, metav1.DeleteOptions{})
		}},
		{"secrets", refs.ConnectionSecretName, func() error {
			return c.KubeClient.CoreV1().Secrets(ns).Delete(ctx, refs.ConnectionSecretName, metav1.DeleteOptions{})
		}},
		{"secrets", refs.CloudInitSecretName, func() error {
			return c.KubeClient.CoreV1().Secrets(ns).Delete(ctx, refs.CloudInitSecretName, metav1.DeleteOptions{})
		}},
	}

	var (
		wg   sync.WaitGroup
		mu   sync.Mutex
		errs []string
	)
	for _, t := range tasks {
		if t.name == "" {
			continue
		}
		wg.Add(1)
		go func(dt deleteTask) {
			defer wg.Done()
			err := dt.delete()
			if err == nil || apierrors.IsNotFound(err) {
				return // successful deletion or already gone
			}
			mu.Lock()
			errs = append(errs, fmt.Sprintf("%s/%s: %v", dt.resource, dt.name, err))
			mu.Unlock()
		}(t)
	}
	wg.Wait()
	if len(errs) > 0 {
		return fmt.Errorf("teardown: %s", strings.Join(errs, "; "))
	}
	return nil
}

// ResolveVMImage resolves a name or display name and verifies that the image is
// imported and has the storage class required to clone it.
func (c *TypedClient) ResolveVMImage(ctx context.Context, ref string) (ResolvedVMImage, error) {
	if ref == "" {
		return ResolvedVMImage{}, fmt.Errorf("%w: reference is empty", ErrVMImageReferenceInvalid)
	}

	ns := c.DefaultImageNamespace
	if ns == "" {
		ns = "default"
	}
	spec := ref
	if i := strings.Index(ref, "/"); i > 0 {
		ns, spec = ref[:i], ref[i+1:]
	}
	if spec == "" {
		return ResolvedVMImage{}, fmt.Errorf("%w: empty image name in reference %q", ErrVMImageReferenceInvalid, ref)
	}

	img, e := c.Clientset.HarvesterhciV1beta1().VirtualMachineImages(ns).Get(ctx, spec, metav1.GetOptions{})
	if e == nil {
		return readyVMImageFields(ns, spec, img)
	}
	if !apierrors.IsNotFound(e) {
		return ResolvedVMImage{}, e
	}

	// fallback: search by displayName
	list, e := c.Clientset.HarvesterhciV1beta1().VirtualMachineImages(ns).List(ctx, metav1.ListOptions{})
	if e != nil {
		return ResolvedVMImage{}, e
	}

	var matched []harvesterhciov1beta1.VirtualMachineImage
	for _, item := range list.Items {
		if item.Spec.DisplayName == spec {
			matched = append(matched, item)
		}
	}

	switch len(matched) {
	case 0:
		return ResolvedVMImage{}, fmt.Errorf("%w: no VirtualMachineImage in namespace %q matching name or displayName %q", ErrVMImageNotFound, ns, spec)
	case 1:
		return readyVMImageFields(ns, matched[0].Name, &matched[0])
	default:
		return ResolvedVMImage{}, fmt.Errorf("%w: %d VirtualMachineImages in namespace %q share displayName %q", ErrVMImageAmbiguous, len(matched), ns, spec)
	}
}

func readyVMImageFields(ns, name string, img *harvesterhciov1beta1.VirtualMachineImage) (ResolvedVMImage, error) {
	if !isVMImageImported(img) {
		return ResolvedVMImage{}, fmt.Errorf("%w: VirtualMachineImage %s/%s is not imported yet (status.conditions missing ImageImported=True)", ErrVMImageNotReady, ns, name)
	}
	sc, err := resolveImageStorageClassName(img)
	if err != nil {
		return ResolvedVMImage{}, err
	}
	return ResolvedVMImage{Namespace: ns, Name: name, StorageClassName: sc}, nil
}

func isVMImageImported(image *harvesterhciov1beta1.VirtualMachineImage) bool {
	if image == nil {
		return false
	}
	return harvesterhciov1beta1.ImageImported.IsTrue(image)
}

func resolveImageStorageClassName(image *harvesterhciov1beta1.VirtualMachineImage) (string, error) {
	if image == nil {
		return "", fmt.Errorf("nil image")
	}
	if image.Status.StorageClassName != "" {
		return image.Status.StorageClassName, nil
	}
	return "", fmt.Errorf("%w: VM image %s/%s does not have a StorageClass yet (not initialized)",
		ErrVMImageNotReady, image.Namespace, image.Name)
}

// VMName is the deterministic name of a DBInstance's VirtualMachine.
func VMName(id string) string {
	return fmt.Sprintf("pg-%s", id)
}

// DataVolumeName is the deterministic name of a DBInstance's data-disk PVC.
// It's a pure naming convention, not a provider call: the PVC itself is
// created later by Harvester from the VM's harvesterhci.io/volumeClaimTemplates
// annotation (see buildPostgresVM below), so there's nothing to reserve up front.
func DataVolumeName(id string) string {
	return fmt.Sprintf("pg-%s-data", id)
}

func (c *TypedClient) buildPostgresVM(p VMCreateParams, vmName, cloudInitSecretName, imageID, imageSC string, running bool) (*kubevirtv1.VirtualMachine, error) {
	annotations := map[string]string{}
	if c.MgmtLogicalSwitch != "" {
		annotations["ovn.kubernetes.io/logical_switch"] = c.MgmtLogicalSwitch
	}

	runStrategy := kubevirtv1.RunStrategyHalted
	if running {
		runStrategy = kubevirtv1.RunStrategyAlways
	}

	labels := map[string]string{dbaasv1.LabelInstance: p.ID, dbaasv1.LabelRole: "primary"}
	templateLabels := map[string]string{dbaasv1.LabelInstance: p.ID}
	osPVCName := p.OSDiskPVCName
	dataPVCName := p.DataVolumeRef
	if dataPVCName == "" {
		dataPVCName = DataVolumeName(p.ID)
	}
	dataSizeGB := p.DataVolumeSizeGB
	if dataSizeGB <= 0 {
		dataSizeGB = 1
	}
	osPVCOption := &harvesterbuilder.PersistentVolumeClaimOption{
		ImageID:          imageID,
		VolumeMode:       corev1.PersistentVolumeBlock,
		AccessMode:       corev1.ReadWriteMany,
		StorageClassName: &imageSC,
	}
	dataPVCOption := &harvesterbuilder.PersistentVolumeClaimOption{
		VolumeMode:       corev1.PersistentVolumeBlock,
		AccessMode:       corev1.ReadWriteMany, // to allow live migration all disks should be ReadWriteMany
		StorageClassName: &p.DataVolumeStorageClass,
	}

	vmBuilder := harvesterbuilder.NewVMBuilder("dbaas-operator").
		Name(vmName).
		Namespace(p.Namespace).
		Labels(labels).
		VirtualMachineInstanceTemplateLabels(templateLabels).
		CPU(p.CPUCores).                         // set spec.template.spec.domain.resources.limits.cpu
		Memory(fmt.Sprintf("%dMi", p.MemoryMB)). // set spec.template.spec.domain.resources.limits.memory
		RunStrategy(runStrategy).
		PVCDisk("os-disk", harvesterbuilder.DiskBusVirtio, false, false, 1, "20Gi", osPVCName, osPVCOption).
		PVCDisk("pgdata-disk", harvesterbuilder.DiskBusVirtio, false, false, 0, fmt.Sprintf("%dGi", dataSizeGB), dataPVCName, dataPVCOption).
		CloudInitDisk("cloudinit", harvesterbuilder.DiskBusVirtio, false, 0, harvesterbuilder.CloudInitSource{
			CloudInitType:         harvesterbuilder.CloudInitTypeNoCloud,
			UserDataSecretName:    cloudInitSecretName,
			NetworkDataSecretName: cloudInitSecretName,
		}).
		NetworkInterface(dataNetInterface, string(kubevirtv1.VirtIO), "", harvesterbuilder.NetworkInterfaceTypeBridge, typedVMNetworkName(p.Namespace, p.NADName))

	vm, err := vmBuilder.VM()
	if err != nil {
		return nil, fmt.Errorf("build VM with Harvester builder helpers: %w", err)
	}
	// Post build fixes
	vm.TypeMeta = metav1.TypeMeta{APIVersion: "kubevirt.io/v1", Kind: "VirtualMachine"}
	vm.Spec.Template.ObjectMeta.Annotations = mergeStringMap(vm.Spec.Template.ObjectMeta.Annotations, annotations) // VMI/launcher-pod annotations (e.g. Kube-OVN logical switch)
	// VM-object annotations read by Harvester's control plane (webhook + VM controller).
	// AnnotationRunStrategy: Harvester's patchRunStrategy webhook reads this on every
	// Halted→non-Halted transition and patches spec.runStrategy to match. Setting it to
	// Always here ensures the webhook confirms our intent instead of overriding to RerunOnFailure.
	if vm.Annotations == nil {
		vm.Annotations = map[string]string{}
	}
	vm.Annotations[util.AnnotationRunStrategy] = string(kubevirtv1.RunStrategyAlways)
	vm.Spec.Template.Spec.Domain.CPU.Sockets = 1
	vm.Spec.Template.Spec.Domain.CPU.Threads = 1

	// Readiness probe: runs inside the guest via the QEMU guest agent virtio
	// channel — no pod-network port exposure required.
	//
	// Both halves are required. pg_isready only asks whether a postmaster
	// answers, which is true well before cloud-init has created the master
	// role and its database — first for the throwaway cluster
	// pg_createcluster starts, then again between the hostssl restart and the
	// bootstrap SQL. Readiness gates DatabaseReady, which gates
	// phase=available, so on its own it told clients "connect now" during a
	// window where PostgreSQL answers every login with
	// "password authentication failed" (its response for a role that does
	// not exist yet). The marker is written by bootstrap.sh only once that
	// SQL has succeeded — see buildUserData in internal/credentials/cloudinit.go.
	vm.Spec.Template.Spec.ReadinessProbe = &kubevirtv1.Probe{
		Handler: kubevirtv1.Handler{
			Exec: &corev1.ExecAction{
				Command: []string{
					"/bin/sh", "-c",
					fmt.Sprintf("test -f %s && pg_isready -h 127.0.0.1 -p %d -U %s -d postgres",
						GuestBootstrapCompleteMarker, p.Port, p.MasterUser),
				},
			},
		},
		InitialDelaySeconds: 30,
		PeriodSeconds:       10,
		TimeoutSeconds:      5,
		// SuccessThreshold=3: require 3 consecutive passes (~30s) before
		// declaring Ready again — recovery-side hysteresis so a single lucky
		// probe doesn't flap the condition back to healthy.
		SuccessThreshold: 3,
		// FailureThreshold=12 @ PeriodSeconds=10 ≈ 2 min of sustained failure
		// before Ready flips False. This probe is the single debounce for
		// database liveness: the controller treats the resulting Ready condition
		// as authoritative and does no further counting (see ensureDatabaseHealth).
		// A guest-agent disconnect also trips it, since the probe execs pg_isready
		// in-guest via the agent.
		FailureThreshold: 12,
	}

	return vm, nil
}

func typedVMNetworkName(namespace, nadName string) string {
	if strings.Contains(nadName, "/") {
		return nadName
	}
	return fmt.Sprintf("%s/%s", namespace, nadName)
}

// VolumeClaimTemplates parses the VM's volumeClaimTemplates annotation
// into PVC templates. It returns pointers so callers can mutate entries in
// place, but callers should still index the slice (pvcs[i]) rather than
// range-copy so the mutation stays correct if this ever returns values.
func VolumeClaimTemplates(vm *kubevirtv1.VirtualMachine) ([]*corev1.PersistentVolumeClaim, error) {
	raw := vm.Annotations[util.AnnotationVolumeClaimTemplates]
	if raw == "" {
		return nil, fmt.Errorf("VM %s/%s has no %s annotation", vm.Namespace, vm.Name, util.AnnotationVolumeClaimTemplates)
	}
	var pvcs []*corev1.PersistentVolumeClaim
	if err := json.Unmarshal([]byte(raw), &pvcs); err != nil {
		return nil, fmt.Errorf("unmarshal %s: %w", util.AnnotationVolumeClaimTemplates, err)
	}
	return pvcs, nil
}

func mergeStringMap(base map[string]string, overlay map[string]string) map[string]string {
	if len(base) == 0 && len(overlay) == 0 {
		return nil
	}
	out := map[string]string{}
	for k, v := range base {
		out[k] = v
	}
	for k, v := range overlay {
		out[k] = v
	}
	return out
}

// ignoreAlreadyExists returns nil if err is an AlreadyExists API error, otherwise err.
func ignoreAlreadyExists(err error) error {
	if apierrors.IsAlreadyExists(err) {
		return nil
	}
	return err
}

// ignoreNotFound returns nil if err is a NotFound API error, otherwise err.
func ignoreNotFound(err error) error {
	if apierrors.IsNotFound(err) {
		return nil
	}
	return err
}

// osDiskVolumeName is the VM disk name buildPostgresVM assigns the OS-disk
// PVC template to (see buildPostgresVM's PVCDisk("os-disk", ...) call).
const osDiskVolumeName = "os-disk"

// currentOSDiskPVCName fetches vmName and returns its current "os-disk"
// volume's claimName. Returns ("", nil, nil), not an error, if the VM or
// that volume doesn't exist yet — shared by GetVMOSDiskImageID and
// GetVMOSDiskPVCName so both self-heal helpers observe the same live state
// through one code path.
func (c *TypedClient) currentOSDiskPVCName(ctx context.Context, ns, vmName string) (string, *kubevirtv1.VirtualMachine, error) {
	vm, err := c.Clientset.KubevirtV1().VirtualMachines(ns).Get(ctx, vmName, metav1.GetOptions{})
	if err != nil {
		if apierrors.IsNotFound(err) {
			return "", nil, nil
		}
		return "", nil, err
	}

	volIdx := -1
	for i := range vm.Spec.Template.Spec.Volumes {
		if vm.Spec.Template.Spec.Volumes[i].Name == osDiskVolumeName {
			volIdx = i
			break
		}
	}
	if volIdx == -1 || vm.Spec.Template.Spec.Volumes[volIdx].VolumeSource.PersistentVolumeClaim == nil {
		return "", vm, nil
	}
	return vm.Spec.Template.Spec.Volumes[volIdx].VolumeSource.PersistentVolumeClaim.ClaimName, vm, nil
}

// GetVMOSDiskImageID returns the harvesterhci.io/imageId annotation
// ("namespace/name") Harvester stamps on the VM's current OS-disk PVC —
// ground truth for the running image, independent of any DBInstance status
// field. Returns ("", nil), not an error, if it can't be determined yet
// (e.g. VM not created).
func (c *TypedClient) GetVMOSDiskImageID(ctx context.Context, ns, vmName string) (string, error) {
	currentPVCName, vm, err := c.currentOSDiskPVCName(ctx, ns, vmName)
	if err != nil || currentPVCName == "" {
		return "", err
	}

	pvcs, err := VolumeClaimTemplates(vm)
	if err != nil {
		return "", err
	}
	for _, pvc := range pvcs {
		if pvc.Name == currentPVCName {
			return pvc.Annotations[harvesterbuilder.AnnotationKeyImageID], nil
		}
	}
	return "", nil
}

// GetVMOSDiskPVCName returns the claimName of the VM's current "os-disk"
// volume — ground truth for which PVC actually backs it, independent of any
// DBInstance status field. Returns ("", nil), not an error, if it can't be
// determined yet (e.g. VM not created).
func (c *TypedClient) GetVMOSDiskPVCName(ctx context.Context, ns, vmName string) (string, error) {
	name, _, err := c.currentOSDiskPVCName(ctx, ns, vmName)
	return name, err
}

// MarkVMPVCsForRemoval lists, in the live VM's harvesterhci.io/
// removedPersistentVolumeClaims annotation, every PVC the VM mounts that
// owned accepts. Harvester's VM finalizer deletes the listed PVCs once the
// VM is being removed — the same mechanism its UI uses to delete volumes
// along with a VM. Deleting them through the VM is what keeps Harvester's
// VM controller from recreating a blank PVC from volumeClaimTemplates, which
// it stops doing only once the VM has a deletionTimestamp. Entries already
// listed are kept. found is false (and nothing is done) when the VM is gone.
func (c *TypedClient) MarkVMPVCsForRemoval(ctx context.Context, ns, vmName string, owned func(pvcName string) bool) (found bool, err error) {
	err = retry.RetryOnConflict(retry.DefaultRetry, func() error {
		vm, getErr := c.Clientset.KubevirtV1().VirtualMachines(ns).Get(ctx, vmName, metav1.GetOptions{})
		if apierrors.IsNotFound(getErr) {
			found = false
			return nil
		}
		if getErr != nil {
			return getErr
		}
		found = true
		if vm.Spec.Template == nil {
			return nil
		}

		existing := vm.Annotations[util.RemovedPVCsAnnotationKey]
		listed := map[string]bool{}
		var names []string
		add := func(name string) {
			if name = strings.TrimSpace(name); name != "" && !listed[name] {
				listed[name] = true
				names = append(names, name)
			}
		}
		for _, name := range strings.Split(existing, ",") {
			add(name)
		}
		for _, vol := range vm.Spec.Template.Spec.Volumes {
			if vol.PersistentVolumeClaim != nil && owned(vol.PersistentVolumeClaim.ClaimName) {
				add(vol.PersistentVolumeClaim.ClaimName)
			}
		}
		want := strings.Join(names, ",")
		if want == existing {
			return nil
		}
		if vm.Annotations == nil {
			vm.Annotations = map[string]string{}
		}
		vm.Annotations[util.RemovedPVCsAnnotationKey] = want
		_, updateErr := c.Clientset.KubevirtV1().VirtualMachines(ns).Update(ctx, vm, metav1.UpdateOptions{})
		return updateErr
	})
	return found, err
}

// ResolveVMImageDisplayName returns the DisplayName of the
// VirtualMachineImage identified by ns/name. See the ClientInterface doc
// comment for why this indirection exists: GetVMOSDiskImageID's caller needs
// to compare against internal/catalog's human-readable ImageName strings,
// not the real (often auto-generated) object name imageID carries.
func (c *TypedClient) ResolveVMImageDisplayName(ctx context.Context, ns, name string) (string, error) {
	img, err := c.Clientset.HarvesterhciV1beta1().VirtualMachineImages(ns).Get(ctx, name, metav1.GetOptions{})
	if err != nil {
		if apierrors.IsNotFound(err) {
			return "", nil
		}
		return "", err
	}
	return img.Spec.DisplayName, nil
}

// SwapVMOSDisk repoints the "os-disk" volumeClaimTemplates entry to a new
// revision-suffixed PVC backed by newImageRef's StorageClass, and repoints
// the "os-disk" volume's claimName to match. Mirrors ResizeDataVolume's
// read-modify-write idiom over the harvesterhci.io/volumeClaimTemplates
// annotation, under the same RetryOnConflict.
func (c *TypedClient) SwapVMOSDisk(ctx context.Context, ns, vmName, instID, newImageRef string) (oldPVCName, newPVCName string, err error) {
	image, err := c.ResolveVMImage(ctx, newImageRef)
	if err != nil {
		return "", "", err
	}
	imageID := fmt.Sprintf("%s/%s", image.Namespace, image.Name)

	err = retry.RetryOnConflict(retry.DefaultRetry, func() error {
		oldPVCName, newPVCName = "", ""

		vm, err := c.Clientset.KubevirtV1().VirtualMachines(ns).Get(ctx, vmName, metav1.GetOptions{})
		if err != nil {
			return err
		}

		volIdx := -1
		for i := range vm.Spec.Template.Spec.Volumes {
			if vm.Spec.Template.Spec.Volumes[i].Name == osDiskVolumeName {
				volIdx = i
				break
			}
		}
		// Hard-fail rather than silently skip: updating the annotation without
		// repointing the actual boot volume would leave the VM booting from a
		// PVC the annotation no longer describes.
		if volIdx == -1 {
			return fmt.Errorf("VM %s/%s has no %q volume; refusing to update %s without repointing the boot volume",
				ns, vmName, osDiskVolumeName, util.AnnotationVolumeClaimTemplates)
		}
		if vm.Spec.Template.Spec.Volumes[volIdx].VolumeSource.PersistentVolumeClaim == nil {
			return fmt.Errorf("VM %s/%s %q volume is not PVC-backed; refusing to swap its OS disk",
				ns, vmName, osDiskVolumeName)
		}
		currentPVCName := vm.Spec.Template.Spec.Volumes[volIdx].VolumeSource.PersistentVolumeClaim.ClaimName

		pvcs, err := VolumeClaimTemplates(vm)
		if err != nil {
			return err
		}
		pvcIdx := -1
		for i := range pvcs {
			if pvcs[i].Name == currentPVCName {
				pvcIdx = i
				break
			}
		}
		if pvcIdx == -1 {
			return fmt.Errorf("%s on VM %s/%s has no entry named %q",
				util.AnnotationVolumeClaimTemplates, ns, vmName, currentPVCName)
		}
		current := pvcs[pvcIdx]

		// Idempotent no-op: already on the target StorageClass.
		if current.Spec.StorageClassName != nil && *current.Spec.StorageClassName == image.StorageClassName {
			newPVCName = currentPVCName
			return nil
		}

		newPVCName = fmt.Sprintf("pg-%s-os-%s", instID, image.Name)
		pvcs[pvcIdx] = &corev1.PersistentVolumeClaim{
			ObjectMeta: metav1.ObjectMeta{
				Name:        newPVCName,
				Annotations: map[string]string{harvesterbuilder.AnnotationKeyImageID: imageID},
			},
			Spec: corev1.PersistentVolumeClaimSpec{
				AccessModes:      current.Spec.AccessModes,
				Resources:        current.Spec.Resources,
				VolumeMode:       current.Spec.VolumeMode,
				StorageClassName: &image.StorageClassName,
			},
		}

		data, err := json.Marshal(pvcs)
		if err != nil {
			return fmt.Errorf("marshal %s: %w", util.AnnotationVolumeClaimTemplates, err)
		}
		if vm.Annotations == nil {
			vm.Annotations = map[string]string{}
		}
		vm.Annotations[util.AnnotationVolumeClaimTemplates] = string(data)
		vm.Spec.Template.Spec.Volumes[volIdx].VolumeSource.PersistentVolumeClaim.ClaimName = newPVCName

		if _, err := c.Clientset.KubevirtV1().VirtualMachines(ns).Update(ctx, vm, metav1.UpdateOptions{}); err != nil {
			return err
		}
		oldPVCName = currentPVCName
		return nil
	})
	if err != nil {
		return "", "", err
	}
	return oldPVCName, newPVCName, nil
}

// DeletePVC deletes a PVC by name. Idempotent; NotFound is success.
func (c *TypedClient) DeletePVC(ctx context.Context, ns, name string) error {
	return ignoreNotFound(c.KubeClient.CoreV1().PersistentVolumeClaims(ns).Delete(ctx, name, metav1.DeleteOptions{}))
}

// DeletePVCWithUID deletes the PVC only if it is still the object with uid.
// NotFound is success; a different object under the name is a Conflict.
func (c *TypedClient) DeletePVCWithUID(ctx context.Context, ns, name string, uid types.UID) error {
	return ignoreNotFound(c.KubeClient.CoreV1().PersistentVolumeClaims(ns).Delete(ctx, name, metav1.DeleteOptions{
		Preconditions: &metav1.Preconditions{UID: &uid},
	}))
}

// CreateVMBackup requests a durable Harvester backup of sourceVMName.
// It uses type Backup; type Snapshot provides only local snapshots.
func (c *TypedClient) CreateVMBackup(ctx context.Context, ns, name, sourceVMName string, owner *metav1.OwnerReference) error {

	_, err := c.Clientset.HarvesterhciV1beta1().VirtualMachineBackups(ns).Get(ctx, name, metav1.GetOptions{})
	if err == nil {
		return nil
	}
	if !apierrors.IsNotFound(err) {
		return err
	}

	vmBackup := &harvesterhciov1beta1.VirtualMachineBackup{
		ObjectMeta: metav1.ObjectMeta{
			Name:            name,
			Namespace:       ns,
			OwnerReferences: ownerRefSlice(owner),
		},
		Spec: harvesterhciov1beta1.VirtualMachineBackupSpec{
			Source: corev1.TypedLocalObjectReference{
				APIGroup: ptr(kubevirtv1.SchemeGroupVersion.Group),
				Kind:     kubevirtv1.VirtualMachineGroupVersionKind.Kind,
				Name:     sourceVMName,
			},
			Type: harvesterhciov1beta1.Backup,
		},
	}
	_, err = c.Clientset.HarvesterhciV1beta1().VirtualMachineBackups(ns).Create(ctx, vmBackup, metav1.CreateOptions{})
	return ignoreAlreadyExists(err)
}

// GetVMBackupStatus returns the translated status of a VirtualMachineBackup.
// dataVolumePVCName identifies which volume is the PostgreSQL data volume —
// a VirtualMachineBackup covers every volume on the source VM, but DBaaS
// restore only ever needs this one.
func (c *TypedClient) GetVMBackupStatus(ctx context.Context, ns, name, dataVolumePVCName string) (VMBackupStatus, error) {
	vmBackup, err := c.Clientset.HarvesterhciV1beta1().VirtualMachineBackups(ns).Get(ctx, name, metav1.GetOptions{})
	if err != nil {
		return VMBackupStatus{}, err
	}

	status := VMBackupStatus{
		CreatedAt:  vmBackup.CreationTimestamp.Time,
		ReadyToUse: vmBackup.Status.ReadyToUse != nil && *vmBackup.Status.ReadyToUse,
		Progress:   vmBackup.Status.Progress,
	}
	if vmBackup.Status.Error != nil && vmBackup.Status.Error.Message != nil {
		status.ErrorMessage = *vmBackup.Status.Error.Message
	}
	for _, vb := range vmBackup.Status.VolumeBackups {
		if vb.PersistentVolumeClaim.ObjectMeta.Name != dataVolumePVCName {
			continue
		}
		if vb.Name != nil {
			status.DataVolumeSnapshotName = *vb.Name
		}
		break
	}
	return status, nil
}

// DeleteVMBackup deletes a VirtualMachineBackup by name. Idempotent; NotFound
// is success.
func (c *TypedClient) DeleteVMBackup(ctx context.Context, ns, name string) error {
	return ignoreNotFound(c.Clientset.HarvesterhciV1beta1().VirtualMachineBackups(ns).Delete(ctx, name, metav1.DeleteOptions{}))
}

// restoreVolumeSnapshotAPIGroup is the CSI external-snapshotter API group a
// restore PVC's dataSource references. Not vendored as a typed dependency —
// a TypedLocalObjectReference only needs the group/kind/name strings, and
// pulling in the snapshot clientset just for that would be unjustified for
// what's otherwise a plain Kubernetes PVC create.
const restoreVolumeSnapshotAPIGroup = "snapshot.storage.k8s.io"

// CreateRestorePVC creates a PVC that restores data from an existing
// VolumeSnapshot — the same same-namespace mechanism Harvester's own restore
// controller uses internally (getDataSourceSameNs), without going through
// VirtualMachineRestore. AlreadyExists is swallowed — see the interface doc
// for why callers must still verify the result. Matches the data disk's
// existing shape (ReadWriteMany, Block) so the restored PVC attaches to a new
// VM the same way an ordinary one would.
func (c *TypedClient) CreateRestorePVC(ctx context.Context, ns, pvcName, volumeSnapshotName string, sizeGB int, storageClassName string, labels map[string]string) error {
	pvc := &corev1.PersistentVolumeClaim{
		ObjectMeta: metav1.ObjectMeta{
			Name:      pvcName,
			Namespace: ns,
			Labels:    labels,
		},
		Spec: corev1.PersistentVolumeClaimSpec{
			AccessModes: []corev1.PersistentVolumeAccessMode{corev1.ReadWriteMany},
			VolumeMode:  ptr(corev1.PersistentVolumeBlock),
			Resources: corev1.VolumeResourceRequirements{
				Requests: corev1.ResourceList{
					corev1.ResourceStorage: resource.MustParse(fmt.Sprintf("%dGi", sizeGB)),
				},
			},
			StorageClassName: &storageClassName,
			DataSource: &corev1.TypedLocalObjectReference{
				APIGroup: ptr(restoreVolumeSnapshotAPIGroup),
				Kind:     "VolumeSnapshot",
				Name:     volumeSnapshotName,
			},
		},
	}
	_, err := c.KubeClient.CoreV1().PersistentVolumeClaims(ns).Create(ctx, pvc, metav1.CreateOptions{})
	return ignoreAlreadyExists(err)
}

// GetPVC returns the live PVC straight from the API server (not a cache).
func (c *TypedClient) GetPVC(ctx context.Context, ns, name string) (*corev1.PersistentVolumeClaim, error) {
	return c.KubeClient.CoreV1().PersistentVolumeClaims(ns).Get(ctx, name, metav1.GetOptions{})
}

// GetVolumeSnapshotState reads the VolumeSnapshot straight from the API
// server, through the snapshot.storage.k8s.io client Harvester's own
// clientset already carries.
func (c *TypedClient) GetVolumeSnapshotState(ctx context.Context, ns, name string) (VolumeSnapshotState, error) {
	vs, err := c.Clientset.SnapshotV1().VolumeSnapshots(ns).Get(ctx, name, metav1.GetOptions{})
	if err != nil {
		return VolumeSnapshotState{}, err
	}
	state := VolumeSnapshotState{Deleting: !vs.DeletionTimestamp.IsZero()}
	if vs.Status != nil {
		state.ReadyToUse = vs.Status.ReadyToUse != nil && *vs.Status.ReadyToUse
		if vs.Status.Error != nil && vs.Status.Error.Message != nil {
			state.ErrorMessage = *vs.Status.Error.Message
		}
	}
	return state, nil
}

func ptr[T any](v T) *T {
	return &v
}
