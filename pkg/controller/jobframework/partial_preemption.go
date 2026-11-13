/*
Copyright The Kubernetes Authors.

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

package jobframework

import (
	"cmp"
	"context"
	"fmt"
	"slices"
	"strconv"

	"github.com/go-logr/logr"
	corev1 "k8s.io/api/core/v1"
	policyv1 "k8s.io/api/policy/v1"
	apierrors "k8s.io/apimachinery/pkg/api/errors"
	metav1 "k8s.io/apimachinery/pkg/apis/meta/v1"
	"k8s.io/klog/v2"
	"k8s.io/utils/ptr"
	ctrl "sigs.k8s.io/controller-runtime"
	"sigs.k8s.io/controller-runtime/pkg/client"

	kueue "sigs.k8s.io/kueue/apis/kueue/v1beta2"
	"sigs.k8s.io/kueue/pkg/constants"
	"sigs.k8s.io/kueue/pkg/features"
	cmputil "sigs.k8s.io/kueue/pkg/util/cmp"
	"sigs.k8s.io/kueue/pkg/util/parallelize"
	utilpod "sigs.k8s.io/kueue/pkg/util/pod"
	"sigs.k8s.io/kueue/pkg/workload"
	"sigs.k8s.io/kueue/pkg/workloadslicing"
)

// reconcilePartialPreemption evicts the over-target Pods of an admitted elastic job whose Workload
// carries a partial-preemption reclaim target, so each PodSet drains to its target. The integration
// chooses which Pods leave (see JobWithPartialPreemption); without the hook nothing is evicted.
// Eviction goes through the Eviction API so PodDisruptionBudgets are honored.
func (r *JobReconciler) reconcilePartialPreemption(ctx context.Context, job GenericJob, wl *kueue.Workload) error {
	if wl == nil || wl.Status.Admission == nil ||
		!features.Enabled(features.PartialPreemption) ||
		!workload.HasPendingPreemptionTargetCount(wl) {
		return nil
	}
	targets := make(map[kueue.PodSetReference]int32)
	for i := range wl.Status.Admission.PodSetAssignments {
		psa := &wl.Status.Admission.PodSetAssignments[i]
		if psa.PartialPreemption != nil && psa.PartialPreemption.TargetCount != nil {
			targets[psa.Name] = *psa.PartialPreemption.TargetCount
		}
	}
	if len(targets) == 0 {
		return nil
	}
	pods, err := r.reclaimCandidates(ctx, job, wl, targets)
	if err != nil || len(pods) == 0 {
		return err
	}
	return parallelize.Until(ctx, len(pods), func(i int) error {
		return evictPodForReclaim(ctx, r.client, ctrl.LoggerFrom(ctx), pods[i])
	})
}

// reclaimCandidates returns the Pods the integration chooses to evict. Only integrations that
// implement JobWithPartialPreemption reclaim Pods; others return none.
func (r *JobReconciler) reclaimCandidates(ctx context.Context, job GenericJob, wl *kueue.Workload, targets map[kueue.PodSetReference]int32) ([]*corev1.Pod, error) {
	ppJob, ok := job.(JobWithPartialPreemption)
	if !ok {
		return nil, nil
	}
	return ppJob.PodsToReclaim(ctx, r.client, wl, targets)
}

// evictPodForReclaim evicts one Pod through the Eviction API.
func evictPodForReclaim(ctx context.Context, c client.Client, log logr.Logger, pod *corev1.Pod) error {
	// TODO: Derive the grace period from the Kueue partial preemption timeout once it is configurable.
	eviction := &policyv1.Eviction{
		Name:      pod.Name,
		Namespace: pod.Namespace,
		DeleteOptions: &metav1.DeleteOptions{
			GracePeriodSeconds: ptr.To[int64](30),
		},
	}
	if err := c.SubResource("eviction").Create(ctx, pod, eviction); err != nil {
		if apierrors.IsNotFound(err) {
			return nil
		}
		if apierrors.IsTooManyRequests(err) {
			log.V(3).Info("partial-preemption eviction blocked by PodDisruptionBudget, will retry", "pod", klog.KObj(pod))
			return err
		}
		return fmt.Errorf("evicting pod %s: %w", klog.KObj(pod), err)
	}
	log.V(3).Info("evicted elastic pod above partial-preemption target", "pod", klog.KObj(pod))
	return nil
}

// ParsePartialPreemptionMinCount returns the partial-preemption minimum set by the
// kueue.x-k8s.io/podset-partial-preemption-min-count annotation, or nil if the annotation is
// absent. It returns an error if the value is not a non-negative 32-bit integer.
func ParsePartialPreemptionMinCount(annotations map[string]string) (*int32, error) {
	value, found := annotations[constants.PodSetPartialPreemptionMinCountAnnotation]
	if !found {
		return nil, nil
	}
	minCount, err := strconv.ParseInt(value, 10, 32)
	if err != nil || minCount < 0 {
		return nil, fmt.Errorf("must be a non-negative integer, got %q", value)
	}
	return ptr.To(int32(minCount)), nil
}

// PodsAboveTargets returns, for each PodSet with a target, the Pods to evict so that at most
// target running Pods remain. Terminated, terminating and gated Pods are not counted and not
// returned. Pods are evicted in this order: not yet scheduled, then the lowest
// controller.kubernetes.io/pod-deletion-cost, then the newest.
func PodsAboveTargets(ctx context.Context, c client.Client, wl *kueue.Workload, targets map[kueue.PodSetReference]int32) ([]*corev1.Pod, error) {
	pods, err := workloadslicing.ListPodsForWorkloadSlice(ctx, c, wl.Namespace, workloadslicing.SliceName(wl))
	if err != nil {
		return nil, err
	}
	running := make(map[kueue.PodSetReference][]*corev1.Pod)
	for _, p := range pods {
		if utilpod.IsTerminated(p) || p.DeletionTimestamp != nil || utilpod.HasGate(p, kueue.ElasticJobSchedulingGate) {
			continue
		}
		ps := kueue.PodSetReference(p.Labels[constants.PodSetLabel])
		if _, ok := targets[ps]; ok {
			running[ps] = append(running[ps], p)
		}
	}
	var toEvict []*corev1.Pod
	for ps, target := range targets {
		candidates := running[ps]
		extra := len(candidates) - int(target)
		if extra <= 0 {
			continue
		}
		slices.SortFunc(candidates, compareForEviction)
		toEvict = append(toEvict, candidates[:extra]...)
	}
	return toEvict, nil
}

// compareForEviction orders Pods so that the ones to evict first come first.
func compareForEviction(a, b *corev1.Pod) int {
	return cmp.Or(
		// Pods that are not scheduled yet first.
		cmputil.CompareBool(a.Spec.NodeName != "", b.Spec.NodeName != ""),
		// Then the lowest deletion cost.
		cmp.Compare(podDeletionCost(a), podDeletionCost(b)),
		// Then the newest.
		b.CreationTimestamp.Compare(a.CreationTimestamp.Time),
		cmp.Compare(a.Name, b.Name),
	)
}

// podDeletionCost returns the Pod's deletion cost, or 0 if it is unset or invalid, as the
// ReplicaSet controller does.
func podDeletionCost(p *corev1.Pod) int32 {
	cost, err := strconv.ParseInt(p.Annotations[corev1.PodDeletionCost], 10, 32)
	if err != nil {
		return 0
	}
	return int32(cost)
}
