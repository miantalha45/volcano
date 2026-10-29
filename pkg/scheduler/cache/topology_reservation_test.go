/*
Copyright 2026 The Volcano Authors.

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

package cache

import (
	"context"
	"errors"
	"fmt"
	"strings"
	"testing"
	"time"

	corev1 "k8s.io/api/core/v1"
	metav1 "k8s.io/apimachinery/pkg/apis/meta/v1"
	"k8s.io/apimachinery/pkg/types"

	schedulingapi "volcano.sh/volcano/pkg/scheduler/api"
	"volcano.sh/volcano/pkg/scheduler/topology/adapter"
	"volcano.sh/volcano/pkg/scheduler/topology/provider"
)

func TestSchedulerCacheReservesAndReleasesExactDeviceTopologyPlan(t *testing.T) {
	resourceName := corev1.ResourceName("nvidia.com/gpu")
	allocationAdapter := newTopologyReservationTestAdapter(resourceName)
	node, cache := newTopologyReservationTestCache(t, []topologyReservationDeviceSpec{{resourceName: resourceName, domainValue: "gpu-domain", deviceValue: "gpu-0"}, {resourceName: resourceName, domainValue: "gpu-domain", deviceValue: "gpu-1"}}, allocationAdapter)
	plan := topologyReservationTestPlan(t, cache, node, map[corev1.ResourceName]int64{resourceName: 2})

	reservation, err := cache.ReserveDeviceTopologyPlan(context.Background(), plan)
	if err != nil {
		t.Fatalf("ReserveDeviceTopologyPlan() error = %v", err)
	}
	if len(allocationAdapter.validatedFacts) != 1 {
		t.Fatalf("ValidateTopology() calls = %d, want 1", len(allocationAdapter.validatedFacts))
	}
	if len(allocationAdapter.reservedPlans) != 1 {
		t.Fatalf("Reserve() calls = %d, want 1", len(allocationAdapter.reservedPlans))
	}
	if got := allocationAdapter.reservedPlans[0]; len(got.Placements) != 1 || len(got.Placements[0].Assignments) != 1 || len(got.Placements[0].Assignments[0].DeviceIDs) != 2 {
		t.Fatalf("Reserve() plan = %#v, want one exact two-device assignment", got)
	}
	if len(reservation.AdapterReservations) != 1 || reservation.AdapterReservations[0].ResourceName != resourceName || reservation.AdapterReservations[0].Token != "nvidia.com/gpu-token-1" {
		t.Fatalf("ReserveDeviceTopologyPlan() reservation = %#v, want adapter handle", reservation)
	}

	assertTopologyReservationAvailability(t, cache, plan, schedulingapi.DeviceHeld)
	if available := cache.DeviceTopologySnapshot().AvailableDeviceIDs(plan.Placements[0].Assignments[0].LocalDomainID); len(available) != 0 {
		t.Fatalf("AvailableDeviceIDs() = %v, want no held devices", available)
	}

	if err := cache.ReleaseDeviceTopologyReservation(context.Background(), reservation); err != nil {
		t.Fatalf("ReleaseDeviceTopologyReservation() error = %v", err)
	}
	if len(allocationAdapter.releasedReservations) != 1 || allocationAdapter.releasedReservations[0].Token != reservation.AdapterReservations[0].Token {
		t.Fatalf("Release() calls = %#v, want returned adapter handle", allocationAdapter.releasedReservations)
	}
	assertTopologyReservationAvailability(t, cache, plan, schedulingapi.DeviceAvailable)
}

func TestSchedulerCacheReservationRollsBackEarlierAdapterFragments(t *testing.T) {
	nvidiaResource := corev1.ResourceName("nvidia.com/gpu")
	amdResource := corev1.ResourceName("amd.com/gpu")
	nvidiaAdapter := newTopologyReservationTestAdapter(nvidiaResource)
	amdAdapter := newTopologyReservationTestAdapter(amdResource)
	nvidiaAdapter.reserveErr = adapter.NewError(adapter.ErrorReservationConflict, errors.New("already reserved"))
	node, cache := newTopologyReservationTestCache(t, []topologyReservationDeviceSpec{{resourceName: nvidiaResource, domainValue: "nvidia-domain", deviceValue: "nvidia-0"}, {resourceName: amdResource, domainValue: "amd-domain", deviceValue: "amd-0"}}, nvidiaAdapter, amdAdapter)
	plan := topologyReservationTestPlan(t, cache, node, map[corev1.ResourceName]int64{nvidiaResource: 1, amdResource: 1})

	_, err := cache.ReserveDeviceTopologyPlan(context.Background(), plan)
	if err == nil || !strings.Contains(err.Error(), "ReservationConflict") {
		t.Fatalf("ReserveDeviceTopologyPlan() error = %v, want reservation conflict", err)
	}
	if len(amdAdapter.reservedPlans) != 1 || len(amdAdapter.releasedReservations) != 1 {
		t.Fatalf("amd adapter calls reserve=%d release=%d, want one each", len(amdAdapter.reservedPlans), len(amdAdapter.releasedReservations))
	}
	if len(nvidiaAdapter.reservedPlans) != 1 {
		t.Fatalf("nvidia adapter Reserve() calls = %d, want 1", len(nvidiaAdapter.reservedPlans))
	}
	assertTopologyReservationAvailability(t, cache, plan, schedulingapi.DeviceAvailable)
}

func TestSchedulerCacheReservationFailsClosedWhenRollbackCannotRelease(t *testing.T) {
	nvidiaResource := corev1.ResourceName("nvidia.com/gpu")
	amdResource := corev1.ResourceName("amd.com/gpu")
	nvidiaAdapter := newTopologyReservationTestAdapter(nvidiaResource)
	nvidiaAdapter.reserveErr = errors.New("backend reserve result unknown")
	amdAdapter := newTopologyReservationTestAdapter(amdResource)
	amdAdapter.releaseErr = errors.New("backend release failed")
	node, cache := newTopologyReservationTestCache(t, []topologyReservationDeviceSpec{{resourceName: nvidiaResource, domainValue: "nvidia-domain", deviceValue: "nvidia-0"}, {resourceName: amdResource, domainValue: "amd-domain", deviceValue: "amd-0"}}, nvidiaAdapter, amdAdapter)
	plan := topologyReservationTestPlan(t, cache, node, map[corev1.ResourceName]int64{nvidiaResource: 1, amdResource: 1})

	_, err := cache.ReserveDeviceTopologyPlan(context.Background(), plan)
	if err == nil || !strings.Contains(err.Error(), "backend reserve result unknown") {
		t.Fatalf("ReserveDeviceTopologyPlan() error = %v, want backend failure", err)
	}
	assertTopologyReservationAvailability(t, cache, plan, schedulingapi.DeviceUnreconciled)
}

func TestSchedulerCacheReservationRejectsStaleAndUnavailablePlansWithoutAdapterCalls(t *testing.T) {
	resourceName := corev1.ResourceName("nvidia.com/gpu")
	allocationAdapter := newTopologyReservationTestAdapter(resourceName)
	node, cache := newTopologyReservationTestCache(t, []topologyReservationDeviceSpec{{resourceName: resourceName, domainValue: "gpu-domain", deviceValue: "gpu-0"}}, allocationAdapter)
	plan := topologyReservationTestPlan(t, cache, node, map[corev1.ResourceName]int64{resourceName: 1})

	stalePlan := plan.Clone()
	stalePlan.Revision++
	if _, err := cache.ReserveDeviceTopologyPlan(context.Background(), stalePlan); err == nil || !strings.Contains(err.Error(), "does not match current revision") {
		t.Fatalf("ReserveDeviceTopologyPlan() stale error = %v, want revision rejection", err)
	}

	cache.Mutex.Lock()
	state := cache.ensureDeviceTopologyState()
	deviceID := plan.Placements[0].Assignments[0].DeviceIDs[0]
	if err := state.ledger.transition(deviceID, schedulingapi.DeviceHeld); err != nil {
		cache.Mutex.Unlock()
		t.Fatalf("ledger transition error = %v", err)
	}
	state.publish()
	cache.Mutex.Unlock()
	plan.Revision = cache.DeviceTopologySnapshot().Revision()
	if _, err := cache.ReserveDeviceTopologyPlan(context.Background(), plan); err == nil || !strings.Contains(err.Error(), "non-available") {
		t.Fatalf("ReserveDeviceTopologyPlan() unavailable error = %v, want availability rejection", err)
	}
	if len(allocationAdapter.reservedPlans) != 0 || len(allocationAdapter.validatedFacts) != 0 {
		t.Fatalf("adapter calls validate=%d reserve=%d, want none after local validation failures", len(allocationAdapter.validatedFacts), len(allocationAdapter.reservedPlans))
	}
}

func TestSchedulerCacheReservationRejectsExpiredFactsWithoutAdapterCalls(t *testing.T) {
	resourceName := corev1.ResourceName("nvidia.com/gpu")
	allocationAdapter := newTopologyReservationTestAdapter(resourceName)
	node, cache := newTopologyReservationTestCache(t, []topologyReservationDeviceSpec{{resourceName: resourceName, domainValue: "gpu-domain", deviceValue: "gpu-0"}}, allocationAdapter)
	cache.deviceTopologyNow = func() time.Time {
		return topologyCacheTestObservedAt.Add(2 * time.Hour)
	}
	plan := topologyReservationTestPlan(t, cache, node, map[corev1.ResourceName]int64{resourceName: 1})

	if _, err := cache.ReserveDeviceTopologyPlan(context.Background(), plan); err == nil || !strings.Contains(err.Error(), "stale provider facts") {
		t.Fatalf("ReserveDeviceTopologyPlan() error = %v, want stale provider facts", err)
	}
	if len(allocationAdapter.validatedFacts) != 0 || len(allocationAdapter.reservedPlans) != 0 {
		t.Fatalf("adapter calls validate=%d reserve=%d, want none for expired facts", len(allocationAdapter.validatedFacts), len(allocationAdapter.reservedPlans))
	}
	assertTopologyReservationAvailability(t, cache, plan, schedulingapi.DeviceAvailable)
}

func TestSchedulerCacheReservationValidatesFabricBeforeAdapterCalls(t *testing.T) {
	nvidiaResource := corev1.ResourceName("nvidia.com/gpu")
	amdResource := corev1.ResourceName("amd.com/gpu")

	t.Run("unknown fabric", func(t *testing.T) {
		allocationAdapter := newTopologyReservationTestAdapter(nvidiaResource)
		node, cache := newTopologyReservationTestCache(t, []topologyReservationDeviceSpec{{resourceName: nvidiaResource, domainValue: "gpu-domain", deviceValue: "gpu-0"}}, allocationAdapter)
		plan := topologyReservationTestPlan(t, cache, node, map[corev1.ResourceName]int64{nvidiaResource: 1})
		plan.FabricID = schedulingapi.FabricDomainID{ProviderID: topologyCacheTestProviderID, Namespace: topologyCacheTestNamespace, Value: "missing-fabric"}

		if _, err := cache.ReserveDeviceTopologyPlan(context.Background(), plan); err == nil || !strings.Contains(err.Error(), "is not current") {
			t.Fatalf("ReserveDeviceTopologyPlan() error = %v, want unknown fabric rejection", err)
		}
		assertTopologyReservationAdapterNotCalled(t, allocationAdapter)
	})

	t.Run("domain outside fabric", func(t *testing.T) {
		nvidiaAdapter := newTopologyReservationTestAdapter(nvidiaResource)
		amdAdapter := newTopologyReservationTestAdapter(amdResource)
		devices := []topologyReservationDeviceSpec{{resourceName: nvidiaResource, domainValue: "nvidia-domain", deviceValue: "nvidia-0"}, {resourceName: amdResource, domainValue: "amd-domain", deviceValue: "amd-0"}}
		node, cache := newTopologyReservationTestCache(t, devices, nvidiaAdapter, amdAdapter)
		fabricID := schedulingapi.FabricDomainID{ProviderID: topologyCacheTestProviderID, Namespace: topologyCacheTestNamespace, Value: "fabric-a"}
		if err := cache.ApplyProviderNodeUpdate(topologyReservationTestFabricUpdate(node, devices, nvidiaResource, fabricID)); err != nil {
			t.Fatalf("ApplyProviderNodeUpdate() error = %v", err)
		}
		plan := topologyReservationTestPlan(t, cache, node, map[corev1.ResourceName]int64{nvidiaResource: 1, amdResource: 1})
		plan.FabricID = fabricID

		if _, err := cache.ReserveDeviceTopologyPlan(context.Background(), plan); err == nil || !strings.Contains(err.Error(), "does not include local domain") {
			t.Fatalf("ReserveDeviceTopologyPlan() error = %v, want fabric member rejection", err)
		}
		assertTopologyReservationAdapterNotCalled(t, nvidiaAdapter)
		assertTopologyReservationAdapterNotCalled(t, amdAdapter)
	})

	t.Run("stale fabric", func(t *testing.T) {
		allocationAdapter := newTopologyReservationTestAdapter(nvidiaResource)
		devices := []topologyReservationDeviceSpec{{resourceName: nvidiaResource, domainValue: "gpu-domain", deviceValue: "gpu-0"}}
		node, cache := newTopologyReservationTestCache(t, devices, allocationAdapter)
		fabricID := schedulingapi.FabricDomainID{ProviderID: topologyCacheTestProviderID, Namespace: topologyCacheTestNamespace, Value: "fabric-a"}
		update := topologyReservationTestFabricUpdate(node, devices, nvidiaResource, fabricID)
		if err := cache.ApplyProviderNodeUpdate(update); err != nil {
			t.Fatalf("ApplyProviderNodeUpdate() error = %v", err)
		}
		cache.deviceTopologyNow = func() time.Time {
			return update.FreshUntil.Add(time.Nanosecond)
		}
		plan := topologyReservationTestPlan(t, cache, node, map[corev1.ResourceName]int64{nvidiaResource: 1})
		plan.FabricID = fabricID

		if _, err := cache.ReserveDeviceTopologyPlan(context.Background(), plan); err == nil || !strings.Contains(err.Error(), "stale owner facts") {
			t.Fatalf("ReserveDeviceTopologyPlan() error = %v, want stale fabric rejection", err)
		}
		assertTopologyReservationAdapterNotCalled(t, allocationAdapter)
	})

	t.Run("stale fabric member", func(t *testing.T) {
		allocationAdapter := newTopologyReservationTestAdapter(nvidiaResource)
		ownerDevices := []topologyReservationDeviceSpec{{resourceName: nvidiaResource, domainValue: "owner-domain", deviceValue: "owner-gpu-0"}}
		ownerNode, cache := newTopologyReservationTestCache(t, ownerDevices, allocationAdapter)
		memberNode := &corev1.Node{ObjectMeta: metav1.ObjectMeta{Name: "member-node", UID: types.UID("member-node-uid"), ResourceVersion: "1"}}
		if err := cache.AddOrUpdateNode(memberNode); err != nil {
			t.Fatalf("AddOrUpdateNode(member) error = %v", err)
		}
		memberDevices := []topologyReservationDeviceSpec{{resourceName: nvidiaResource, domainValue: "member-domain", deviceValue: "member-gpu-0"}}
		memberUpdate := topologyReservationTestUpdate(memberNode, memberDevices)
		if err := cache.ApplyProviderNodeUpdate(memberUpdate); err != nil {
			t.Fatalf("ApplyProviderNodeUpdate(member) error = %v", err)
		}

		fabricID := schedulingapi.FabricDomainID{ProviderID: topologyCacheTestProviderID, Namespace: topologyCacheTestNamespace, Value: "fabric-a"}
		ownerUpdate := topologyReservationTestUpdate(ownerNode, ownerDevices)
		ownerUpdate.SourceGeneration = 2
		ownerUpdate.ObservedAt = topologyCacheTestObservedAt.Add(time.Minute)
		ownerUpdate.FreshUntil = ownerUpdate.ObservedAt.Add(time.Hour)
		ownerFacts := ownerUpdate.Facts.Clone()
		ownerFacts.SourceGeneration = ownerUpdate.SourceGeneration
		ownerFacts.ObservedAt = ownerUpdate.ObservedAt
		ownerFacts.FreshUntil = ownerUpdate.FreshUntil
		ownerFacts.Fabrics = []schedulingapi.FabricDomain{{
			ID:               fabricID,
			OwnerProviderID:  topologyCacheTestProviderID,
			OwnerNodeUID:     ownerNode.UID,
			SourceGeneration: ownerUpdate.SourceGeneration,
			Members: []schedulingapi.FabricMember{
				{
					NodeName:         ownerNode.Name,
					NodeUID:          ownerNode.UID,
					SourceGeneration: ownerUpdate.SourceGeneration,
					LocalDomainIDs:   []schedulingapi.DeviceDomainID{ownerFacts.LocalDomains[0].ID},
				},
				{
					NodeName:         memberNode.Name,
					NodeUID:          memberNode.UID,
					SourceGeneration: memberUpdate.SourceGeneration,
					LocalDomainIDs:   []schedulingapi.DeviceDomainID{memberUpdate.Facts.LocalDomains[0].ID},
				},
			},
		}}
		ownerUpdate.Facts = &ownerFacts
		if err := cache.ApplyProviderNodeUpdate(ownerUpdate); err != nil {
			t.Fatalf("ApplyProviderNodeUpdate(owner) error = %v", err)
		}
		cache.deviceTopologyNow = func() time.Time {
			return memberUpdate.FreshUntil.Add(time.Nanosecond)
		}
		plan := topologyReservationTestPlan(t, cache, ownerNode, map[corev1.ResourceName]int64{nvidiaResource: 1})
		plan.FabricID = fabricID

		if _, err := cache.ReserveDeviceTopologyPlan(context.Background(), plan); err == nil || !strings.Contains(err.Error(), "stale member facts") {
			t.Fatalf("ReserveDeviceTopologyPlan() error = %v, want stale fabric member rejection", err)
		}
		assertTopologyReservationAdapterNotCalled(t, allocationAdapter)
	})
}

func TestSchedulerCacheReservationDoesNotHoldDevicesWhenAdapterTopologyValidationFails(t *testing.T) {
	resourceName := corev1.ResourceName("nvidia.com/gpu")
	allocationAdapter := newTopologyReservationTestAdapter(resourceName)
	allocationAdapter.validateErr = errors.New("adapter does not recognize topology")
	node, cache := newTopologyReservationTestCache(t, []topologyReservationDeviceSpec{{resourceName: resourceName, domainValue: "gpu-domain", deviceValue: "gpu-0"}}, allocationAdapter)
	plan := topologyReservationTestPlan(t, cache, node, map[corev1.ResourceName]int64{resourceName: 1})

	if _, err := cache.ReserveDeviceTopologyPlan(context.Background(), plan); err == nil || !strings.Contains(err.Error(), "adapter does not recognize topology") {
		t.Fatalf("ReserveDeviceTopologyPlan() error = %v, want adapter validation failure", err)
	}
	if len(allocationAdapter.reservedPlans) != 0 || len(allocationAdapter.releasedReservations) != 0 {
		t.Fatalf("adapter calls reserve=%d release=%d, want no backend reservation", len(allocationAdapter.reservedPlans), len(allocationAdapter.releasedReservations))
	}
	assertTopologyReservationAvailability(t, cache, plan, schedulingapi.DeviceAvailable)
}

func TestSchedulerCacheReservationRejectsAmbiguousAssignmentWithoutAdapterCalls(t *testing.T) {
	resourceName := corev1.ResourceName("nvidia.com/gpu")
	allocationAdapter := newTopologyReservationTestAdapter(resourceName)
	node, cache := newTopologyReservationTestCache(t, []topologyReservationDeviceSpec{{resourceName: resourceName, domainValue: "gpu-domain", deviceValue: "gpu-0"}}, allocationAdapter)
	plan := topologyReservationTestPlan(t, cache, node, map[corev1.ResourceName]int64{resourceName: 1})
	plan.Placements[0].Assignments[0].ClaimName = "gpu-claim"

	if _, err := cache.ReserveDeviceTopologyPlan(context.Background(), plan); err == nil || !strings.Contains(err.Error(), "either a container or a claim") {
		t.Fatalf("ReserveDeviceTopologyPlan() error = %v, want ambiguous assignment rejection", err)
	}
	assertTopologyReservationAdapterNotCalled(t, allocationAdapter)
	assertTopologyReservationAvailability(t, cache, plan, schedulingapi.DeviceAvailable)
}

func TestSchedulerCacheReservationRollbackUsesUsableCleanupContext(t *testing.T) {
	nvidiaResource := corev1.ResourceName("nvidia.com/gpu")
	amdResource := corev1.ResourceName("amd.com/gpu")
	nvidiaAdapter := newTopologyReservationTestAdapter(nvidiaResource)
	nvidiaAdapter.reserveErr = adapter.NewError(adapter.ErrorReservationConflict, errors.New("already reserved"))
	amdAdapter := newTopologyReservationTestAdapter(amdResource)
	node, cache := newTopologyReservationTestCache(t, []topologyReservationDeviceSpec{{resourceName: nvidiaResource, domainValue: "nvidia-domain", deviceValue: "nvidia-0"}, {resourceName: amdResource, domainValue: "amd-domain", deviceValue: "amd-0"}}, nvidiaAdapter, amdAdapter)
	plan := topologyReservationTestPlan(t, cache, node, map[corev1.ResourceName]int64{nvidiaResource: 1, amdResource: 1})
	ctx, cancel := context.WithCancel(context.Background())
	cancel()

	if _, err := cache.ReserveDeviceTopologyPlan(ctx, plan); err == nil || !strings.Contains(err.Error(), "ReservationConflict") {
		t.Fatalf("ReserveDeviceTopologyPlan() error = %v, want reservation conflict", err)
	}
	if len(amdAdapter.releaseContextErrors) != 1 || amdAdapter.releaseContextErrors[0] != nil {
		t.Fatalf("rollback Release() context errors = %v, want one usable context", amdAdapter.releaseContextErrors)
	}
	assertTopologyReservationAvailability(t, cache, plan, schedulingapi.DeviceAvailable)
}

func TestSchedulerCacheReleaseMarksOnlyFailedFragmentUnreconciled(t *testing.T) {
	nvidiaResource := corev1.ResourceName("nvidia.com/gpu")
	amdResource := corev1.ResourceName("amd.com/gpu")
	nvidiaAdapter := newTopologyReservationTestAdapter(nvidiaResource)
	amdAdapter := newTopologyReservationTestAdapter(amdResource)
	amdAdapter.releaseErr = errors.New("amd release failed")
	node, cache := newTopologyReservationTestCache(t, []topologyReservationDeviceSpec{{resourceName: nvidiaResource, domainValue: "nvidia-domain", deviceValue: "nvidia-0"}, {resourceName: amdResource, domainValue: "amd-domain", deviceValue: "amd-0"}}, nvidiaAdapter, amdAdapter)
	plan := topologyReservationTestPlan(t, cache, node, map[corev1.ResourceName]int64{nvidiaResource: 1, amdResource: 1})

	reservation, err := cache.ReserveDeviceTopologyPlan(context.Background(), plan)
	if err != nil {
		t.Fatalf("ReserveDeviceTopologyPlan() error = %v", err)
	}
	if err := cache.ReleaseDeviceTopologyReservation(context.Background(), reservation); err == nil || !strings.Contains(err.Error(), "amd release failed") {
		t.Fatalf("ReleaseDeviceTopologyReservation() error = %v, want amd release failure", err)
	}

	snapshot := cache.DeviceTopologySnapshot()
	for _, assignment := range plan.Placements[0].Assignments {
		availability, exists := snapshot.DeviceAvailability(assignment.DeviceIDs[0])
		if !exists {
			t.Fatalf("DeviceAvailability(%q) not found", assignment.DeviceIDs[0].String())
		}
		want := schedulingapi.DeviceAvailable
		if assignment.ResourceName == amdResource {
			want = schedulingapi.DeviceUnreconciled
		}
		if availability != want {
			t.Fatalf("DeviceAvailability(%q) = %q, want %q", assignment.DeviceIDs[0].String(), availability, want)
		}
	}
}

func TestSchedulerCacheReleaseRejectsStaleReservationHandle(t *testing.T) {
	resourceName := corev1.ResourceName("nvidia.com/gpu")
	allocationAdapter := newTopologyReservationTestAdapter(resourceName)
	node, cache := newTopologyReservationTestCache(t, []topologyReservationDeviceSpec{{resourceName: resourceName, domainValue: "gpu-domain", deviceValue: "gpu-0"}}, allocationAdapter)
	plan := topologyReservationTestPlan(t, cache, node, map[corev1.ResourceName]int64{resourceName: 1})

	firstReservation, err := cache.ReserveDeviceTopologyPlan(context.Background(), plan)
	if err != nil {
		t.Fatalf("first ReserveDeviceTopologyPlan() error = %v", err)
	}
	if err := cache.ReleaseDeviceTopologyReservation(context.Background(), firstReservation); err != nil {
		t.Fatalf("first ReleaseDeviceTopologyReservation() error = %v", err)
	}

	secondPlan := topologyReservationTestPlan(t, cache, node, map[corev1.ResourceName]int64{resourceName: 1})
	secondReservation, err := cache.ReserveDeviceTopologyPlan(context.Background(), secondPlan)
	if err != nil {
		t.Fatalf("second ReserveDeviceTopologyPlan() error = %v", err)
	}
	if err := cache.ReleaseDeviceTopologyReservation(context.Background(), firstReservation); err == nil || !strings.Contains(err.Error(), "no longer owns") {
		t.Fatalf("stale ReleaseDeviceTopologyReservation() error = %v, want ownership rejection", err)
	}
	if len(allocationAdapter.releasedReservations) != 1 {
		t.Fatalf("Release() calls = %d, want stale handle rejected before backend release", len(allocationAdapter.releasedReservations))
	}
	assertTopologyReservationAvailability(t, cache, secondPlan, schedulingapi.DeviceHeld)

	if err := cache.ReleaseDeviceTopologyReservation(context.Background(), secondReservation); err != nil {
		t.Fatalf("second ReleaseDeviceTopologyReservation() error = %v", err)
	}
}

func TestSchedulerCacheReservationRollsBackWhenTopologyChangesDuringBackendReservation(t *testing.T) {
	resourceName := corev1.ResourceName("nvidia.com/gpu")
	allocationAdapter := newTopologyReservationTestAdapter(resourceName)
	node, cache := newTopologyReservationTestCache(t, []topologyReservationDeviceSpec{{resourceName: resourceName, domainValue: "gpu-domain", deviceValue: "gpu-0"}}, allocationAdapter)
	plan := topologyReservationTestPlan(t, cache, node, map[corev1.ResourceName]int64{resourceName: 1})
	allocationAdapter.reserveHook = func() {
		cache.Mutex.Lock()
		cache.ensureDeviceTopologyState().publish()
		cache.Mutex.Unlock()
	}

	if _, err := cache.ReserveDeviceTopologyPlan(context.Background(), plan); err == nil || !strings.Contains(err.Error(), "changed from held revision") {
		t.Fatalf("ReserveDeviceTopologyPlan() error = %v, want topology-change rejection", err)
	}
	if len(allocationAdapter.releasedReservations) != 1 {
		t.Fatalf("Release() calls = %d, want rollback after topology change", len(allocationAdapter.releasedReservations))
	}
	assertTopologyReservationAvailability(t, cache, plan, schedulingapi.DeviceAvailable)
}

type topologyReservationDeviceSpec struct {
	resourceName corev1.ResourceName
	domainValue  string
	deviceValue  string
}

type topologyReservationTestAdapter struct {
	contract             adapter.DeviceIdentityContract
	validatedFacts       []schedulingapi.NodeTopologyFacts
	reservedPlans        []schedulingapi.TopologyPlacementPlan
	releasedReservations []adapter.AdapterReservation
	releaseContextErrors []error
	reserveHook          func()
	validateErr          error
	reserveErr           error
	releaseErr           error
}

func newTopologyReservationTestAdapter(resourceName corev1.ResourceName) *topologyReservationTestAdapter {
	return &topologyReservationTestAdapter{contract: adapter.DeviceIdentityContract{
		ProviderID:   topologyCacheTestProviderID,
		ResourceName: resourceName,
		Namespace:    topologyCacheTestNamespace,
	}}
}

func (testAdapter *topologyReservationTestAdapter) Capabilities() adapter.AdapterCapabilities {
	return adapter.AdapterCapabilities{
		ExactDeviceIDs:        true,
		AtomicReservation:     true,
		ImmutableBindHandoff:  true,
		AllocationObservation: true,
		ReleaseObservation:    true,
		Recovery:              true,
	}
}

func (testAdapter *topologyReservationTestAdapter) IdentityContract() adapter.DeviceIdentityContract {
	return testAdapter.contract
}

func (testAdapter *topologyReservationTestAdapter) ValidateTopology(_ context.Context, facts schedulingapi.NodeTopologyFacts) error {
	testAdapter.validatedFacts = append(testAdapter.validatedFacts, facts.Clone())
	return testAdapter.validateErr
}

func (testAdapter *topologyReservationTestAdapter) Reserve(_ context.Context, plan schedulingapi.TopologyPlacementPlan) (adapter.AdapterReservation, error) {
	testAdapter.reservedPlans = append(testAdapter.reservedPlans, plan.Clone())
	if testAdapter.reserveHook != nil {
		testAdapter.reserveHook()
	}
	if testAdapter.reserveErr != nil {
		return adapter.AdapterReservation{}, testAdapter.reserveErr
	}
	return adapter.AdapterReservation{Token: fmt.Sprintf("%s-token-%d", testAdapter.contract.ResourceName, len(testAdapter.reservedPlans)), PlanDigest: fmt.Sprintf("%s-digest-%d", testAdapter.contract.ResourceName, len(testAdapter.reservedPlans))}, nil
}

func (testAdapter *topologyReservationTestAdapter) PrepareBind(context.Context, adapter.AdapterReservation, schedulingapi.TopologyTaskPlacement) (adapter.AllocationHandoff, error) {
	return adapter.AllocationHandoff{}, nil
}

func (testAdapter *topologyReservationTestAdapter) Confirm(context.Context, adapter.AdapterReservation) (adapter.AllocationObservation, error) {
	return adapter.AllocationObservation{}, nil
}

func (testAdapter *topologyReservationTestAdapter) Release(ctx context.Context, reservation adapter.AdapterReservation) error {
	testAdapter.releasedReservations = append(testAdapter.releasedReservations, reservation)
	testAdapter.releaseContextErrors = append(testAdapter.releaseContextErrors, ctx.Err())
	return testAdapter.releaseErr
}

func (testAdapter *topologyReservationTestAdapter) Recover(context.Context) ([]adapter.AdapterReservationState, error) {
	return nil, nil
}

func newTopologyReservationTestCache(t *testing.T, devices []topologyReservationDeviceSpec, adapters ...adapter.AllocationAdapter) (*corev1.Node, *SchedulerCache) {
	t.Helper()
	resourceNames := make([]corev1.ResourceName, 0, len(devices))
	seenResources := make(map[corev1.ResourceName]struct{}, len(devices))
	for _, device := range devices {
		if _, exists := seenResources[device.resourceName]; !exists {
			seenResources[device.resourceName] = struct{}{}
			resourceNames = append(resourceNames, device.resourceName)
		}
	}
	providerRegistry, err := provider.NewRegistry([]provider.Registration{{
		ProviderID:        topologyCacheTestProviderID,
		IdentityNamespace: topologyCacheTestNamespace,
		ResourceNames:     resourceNames,
	}})
	if err != nil {
		t.Fatalf("provider.NewRegistry() error = %v", err)
	}
	adapterRegistry, err := adapter.NewRegistry(adapters)
	if err != nil {
		t.Fatalf("adapter.NewRegistry() error = %v", err)
	}

	cache := NewDefaultMockSchedulerCache("device-topology-reservation-test")
	t.Cleanup(func() {
		ShutdownMockSchedulerCache(cache)
	})
	cache.deviceTopologyNow = func() time.Time {
		return topologyCacheTestObservedAt
	}
	WithDeviceTopologyProviderRegistry(providerRegistry)(cache)
	WithDeviceTopologyAdapterRegistry(adapterRegistry)(cache)
	node := &corev1.Node{ObjectMeta: metav1.ObjectMeta{Name: "node-a", UID: types.UID("node-a-uid"), ResourceVersion: "1"}}
	if err := cache.AddOrUpdateNode(node); err != nil {
		t.Fatalf("AddOrUpdateNode() error = %v", err)
	}
	if err := cache.ApplyProviderNodeUpdate(topologyReservationTestUpdate(node, devices)); err != nil {
		t.Fatalf("ApplyProviderNodeUpdate() error = %v", err)
	}
	return node, cache
}

func topologyReservationTestFabricUpdate(node *corev1.Node, devices []topologyReservationDeviceSpec, memberResource corev1.ResourceName, fabricID schedulingapi.FabricDomainID) provider.ProviderNodeUpdate {
	update := topologyReservationTestUpdate(node, devices)
	update.SourceGeneration = 2
	update.ObservedAt = topologyCacheTestObservedAt.Add(time.Minute)
	update.FreshUntil = update.ObservedAt.Add(time.Hour)
	facts := update.Facts.Clone()
	facts.SourceGeneration = update.SourceGeneration
	facts.ObservedAt = update.ObservedAt
	facts.FreshUntil = update.FreshUntil

	memberDomainIDs := make([]schedulingapi.DeviceDomainID, 0)
	for _, domain := range facts.LocalDomains {
		if domain.ResourceName == memberResource {
			memberDomainIDs = append(memberDomainIDs, domain.ID)
		}
	}
	facts.Fabrics = []schedulingapi.FabricDomain{{
		ID:               fabricID,
		OwnerProviderID:  topologyCacheTestProviderID,
		OwnerNodeUID:     node.UID,
		SourceGeneration: update.SourceGeneration,
		Members: []schedulingapi.FabricMember{{
			NodeName:         node.Name,
			NodeUID:          node.UID,
			SourceGeneration: update.SourceGeneration,
			LocalDomainIDs:   memberDomainIDs,
		}},
	}}
	update.Facts = &facts
	return update
}

func assertTopologyReservationAdapterNotCalled(t *testing.T, allocationAdapter *topologyReservationTestAdapter) {
	t.Helper()
	if len(allocationAdapter.validatedFacts) != 0 || len(allocationAdapter.reservedPlans) != 0 || len(allocationAdapter.releasedReservations) != 0 {
		t.Fatalf("adapter calls validate=%d reserve=%d release=%d, want none", len(allocationAdapter.validatedFacts), len(allocationAdapter.reservedPlans), len(allocationAdapter.releasedReservations))
	}
}

func topologyReservationTestUpdate(node *corev1.Node, devices []topologyReservationDeviceSpec) provider.ProviderNodeUpdate {
	observedAt := topologyCacheTestObservedAt
	facts := schedulingapi.NodeTopologyFacts{
		ProviderID:          topologyCacheTestProviderID,
		NodeName:            node.Name,
		NodeUID:             node.UID,
		NodeResourceVersion: node.ResourceVersion,
		SourceGeneration:    1,
		ObservedAt:          observedAt,
		FreshUntil:          observedAt.Add(time.Hour),
	}
	domains := make(map[corev1.ResourceName]*schedulingapi.DeviceDomain)
	for _, specification := range devices {
		domain, exists := domains[specification.resourceName]
		if !exists {
			domain = &schedulingapi.DeviceDomain{
				ID: schedulingapi.DeviceDomainID{
					ProviderID: topologyCacheTestProviderID,
					Namespace:  topologyCacheTestNamespace,
					NodeUID:    node.UID,
					Value:      specification.domainValue,
				},
				NodeName:     node.Name,
				NodeUID:      node.UID,
				ResourceName: specification.resourceName,
			}
			domains[specification.resourceName] = domain
		}
		deviceID := schedulingapi.DeviceID{ProviderID: topologyCacheTestProviderID, Namespace: topologyCacheTestNamespace, Value: specification.deviceValue}
		domain.DeviceIDs = append(domain.DeviceIDs, deviceID)
		facts.Devices = append(facts.Devices, schedulingapi.TopologyDevice{
			ID:            deviceID,
			ResourceName:  specification.resourceName,
			NodeName:      node.Name,
			NodeUID:       node.UID,
			LocalDomainID: domain.ID,
			Health:        schedulingapi.DeviceHealthy,
		})
	}
	for _, resourceName := range resourceNamesForTopologyReservation(devices) {
		facts.LocalDomains = append(facts.LocalDomains, *domains[resourceName])
	}
	return provider.ProviderNodeUpdate{
		ProviderID:          topologyCacheTestProviderID,
		NodeName:            node.Name,
		NodeUID:             node.UID,
		NodeResourceVersion: node.ResourceVersion,
		SourceGeneration:    facts.SourceGeneration,
		ObservedAt:          facts.ObservedAt,
		FreshUntil:          facts.FreshUntil,
		Operation:           provider.ReplaceFacts,
		Facts:               &facts,
	}
}

func resourceNamesForTopologyReservation(devices []topologyReservationDeviceSpec) []corev1.ResourceName {
	seen := make(map[corev1.ResourceName]struct{}, len(devices))
	result := make([]corev1.ResourceName, 0, len(devices))
	for _, device := range devices {
		if _, exists := seen[device.resourceName]; exists {
			continue
		}
		seen[device.resourceName] = struct{}{}
		result = append(result, device.resourceName)
	}
	return result
}

func topologyReservationTestPlan(t *testing.T, cache *SchedulerCache, node *corev1.Node, quantities map[corev1.ResourceName]int64) schedulingapi.TopologyPlacementPlan {
	t.Helper()
	snapshot := cache.DeviceTopologySnapshot()
	assignments := make([]schedulingapi.TopologyContainerAssignment, 0, len(quantities))
	for _, resourceName := range resourceNamesForTopologyReservationFromQuantities(quantities) {
		domains := snapshot.LocalDomains(node.UID, resourceName)
		if len(domains) != 1 {
			t.Fatalf("LocalDomains(%q) = %#v, want one domain", resourceName, domains)
		}
		availableDeviceIDs := snapshot.AvailableDeviceIDs(domains[0].ID)
		quantity := quantities[resourceName]
		if int64(len(availableDeviceIDs)) < quantity {
			t.Fatalf("AvailableDeviceIDs(%q) = %v, want at least %d", resourceName, availableDeviceIDs, quantity)
		}
		assignments = append(assignments, schedulingapi.TopologyContainerAssignment{
			ContainerName: "trainer",
			ResourceName:  resourceName,
			LocalDomainID: domains[0].ID,
			DeviceIDs:     append([]schedulingapi.DeviceID(nil), availableDeviceIDs[:quantity]...),
		})
	}
	return schedulingapi.TopologyPlacementPlan{
		JobID:            "job-a",
		SchedulingUnitID: "job-a",
		Revision:         snapshot.Revision(),
		Placements: []schedulingapi.TopologyTaskPlacement{{
			TaskID:      "pod-a",
			PodUID:      "pod-a",
			NodeName:    node.Name,
			NodeUID:     node.UID,
			Assignments: assignments,
		}},
	}
}

func resourceNamesForTopologyReservationFromQuantities(quantities map[corev1.ResourceName]int64) []corev1.ResourceName {
	result := make([]corev1.ResourceName, 0, len(quantities))
	for resourceName := range quantities {
		result = append(result, resourceName)
	}
	for left := 0; left < len(result); left++ {
		for right := left + 1; right < len(result); right++ {
			if result[right] < result[left] {
				result[left], result[right] = result[right], result[left]
			}
		}
	}
	return result
}

func assertTopologyReservationAvailability(t *testing.T, cache *SchedulerCache, plan schedulingapi.TopologyPlacementPlan, want schedulingapi.DeviceAvailability) {
	t.Helper()
	snapshot := cache.DeviceTopologySnapshot()
	for _, placement := range plan.Placements {
		for _, assignment := range placement.Assignments {
			for _, deviceID := range assignment.DeviceIDs {
				got, exists := snapshot.DeviceAvailability(deviceID)
				if !exists || got != want {
					t.Fatalf("DeviceAvailability(%q) = (%q, %v), want (%q, true)", deviceID.String(), got, exists, want)
				}
			}
		}
	}
}
