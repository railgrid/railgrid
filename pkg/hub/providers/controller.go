/*
Copyright 2026 The Railgrid Authors.

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

package providers

import (
	"context"
	"fmt"
	"io"
	"net/http"
	"net/url"
	"sort"
	"strings"
	"sync"
	"time"

	"k8s.io/apimachinery/pkg/api/equality"
	apierrors "k8s.io/apimachinery/pkg/api/errors"
	metav1 "k8s.io/apimachinery/pkg/apis/meta/v1"
	"k8s.io/client-go/rest"
	"k8s.io/klog/v2"
	ctrl "sigs.k8s.io/controller-runtime"
	"sigs.k8s.io/controller-runtime/pkg/client"

	mcbuilder "sigs.k8s.io/multicluster-runtime/pkg/builder"
	mcmanager "sigs.k8s.io/multicluster-runtime/pkg/manager"
	mcreconcile "sigs.k8s.io/multicluster-runtime/pkg/reconcile"

	providersv1alpha1 "github.com/railgrid/railgrid/apis/providers/v1alpha1"
	"github.com/railgrid/railgrid/pkg/kcppaths"
)

// CatalogReconciler keeps the in-process Registry in sync with the cluster's
// CatalogEntry resources AND provisions the kcp-side artefacts each provider
// needs (sub-workspace + APIResourceSchemas + APIExport).
//
// Scope as of Phase 1B:
//   - On create/update: parse spec.ui.url and spec.backend.url, set the
//     registry entry, and apply the inline APIResourceSchemas + APIExport in
//     the per-provider sub-workspace.
//   - On delete: drop the registry entry. (Cascade GC of the sub-workspace
//     and its APIExport is deferred — Phase 5 hardening.)
//
// Deferred:
//   - Heartbeat-driven readiness (Phase 1C).
//   - Provider ServiceAccount + kubeconfig Secret mint (only required for
//     providers that ship a controller — Phase 1D).
//   - RBAC grant + MaximalPermissionPolicy enabling tenant Enable (Phase 3).
type CatalogReconciler struct {
	mgr   mcmanager.Manager
	reg   *Registry
	prov  *Provisioner
	noKCP bool // true when running without kcp — skip workspace-cluster resolve
	// hubExternalURL / hubInternalURL are retained for parity with the
	// onboarding service's kubeconfig minting; the reconciler itself no longer
	// mints kubeconfigs (admin onboarding does).
	hubExternalURL string
	hubInternalURL string

	// edgeRoutes resolves an org-owned provider's edge transport. Nil in
	// registry-only mode and on hubs that predate edge transport.
	edgeRoutes EdgeRouteResolver
	// healthClient performs bounded, same-authority readiness probes for
	// platform-provider backends. Org-owned backends are never sent here.
	healthClient httpDoer
	// uiClient fetches platform-provider /main.js bundles for the SRI pin the
	// portal loads them with (see ui_integrity.go). Nil means the default
	// bounded client. Org-owned UIs are never dialled.
	uiClient httpDoer
	// uiIntegrity caches the pin per provider so the reconciles a heartbeat
	// status write triggers do not re-fetch the bundle every 30s; a version
	// change or UIIntegrityResync forces a re-hash.
	uiIntegrityMu sync.Mutex
	uiIntegrity   map[providerKey]uiIntegrityRecord

	// clusterPaths caches logical-cluster-ID → canonical workspace path. The
	// path is what tells a platform provider apart from an org-owned one and
	// attributes the latter to its Org; the reconcile request carries only the
	// cluster ID. It is read from the cluster's own LogicalCluster object, which
	// kcp stamps with the kcp.io/path annotation at workspace creation.
	//
	// Cached because it never changes for a given cluster: a workspace cannot be
	// re-parented or renamed. Entries are only ever added, so the map is bounded
	// by the number of provider workspaces the hub has observed.
	clusterPathsMu sync.RWMutex
	clusterPaths   map[string]string

	// sweepCredentials deletes rotated-out provider token Secrets whose grace
	// period lapsed, reporting how many went and when the next one lapses. Nil
	// means "use the Provisioner"; it is a field so tests can observe the call
	// without a live kcp.
	sweepCredentials func(ctx context.Context, cluster string) (int, time.Time, error)

	// resolveAPIGroups reads spec.resources[].group off a provider's APIExport.
	// Nil means "use the Provisioner"; it is a field so tests can supply a fake
	// export without a live kcp.
	resolveAPIGroups func(ctx context.Context, workspacePath, exportName string) ([]string, error)
}

// ConditionAPIGroupsUnknown is set on a CatalogEntry whose provider declares an
// APIExport that the hub cannot (yet) read the served API groups from.
//
// It is not folded into Ready. A provider with an unreadable export is still
// routable, still discoverable, and its UI and backend still work; what it
// cannot do is own an API group, so every scoped-identity rule naming one of
// its groups is refused with unknown_group until the export is readable. That
// is a narrow, silent failure without a condition to point at, which is exactly
// why there is one.
const ConditionAPIGroupsUnknown = "APIGroupsUnknown"

// apiGroupResolver returns the APIExport group reader for this reconcile, or
// nil when there is nothing to read with (registry-only mode).
func (r *CatalogReconciler) apiGroupResolver() func(context.Context, string, string) ([]string, error) {
	if r.resolveAPIGroups != nil {
		return r.resolveAPIGroups
	}
	if r.prov == nil {
		return nil
	}
	return r.prov.ResolveAPIExportGroups
}

// credentialSweeper returns the sweep to run for this reconcile, or nil when
// there is nothing to sweep with (registry-only mode).
func (r *CatalogReconciler) credentialSweeper() func(context.Context, string) (int, time.Time, error) {
	if r.sweepCredentials != nil {
		return r.sweepCredentials
	}
	if r.prov == nil {
		return nil
	}
	return r.prov.SweepExpiredProviderTokens
}

type httpDoer interface {
	Do(*http.Request) (*http.Response, error)
}

const backendHealthTimeout = 3 * time.Second

func defaultBackendHealthClient() *http.Client {
	return &http.Client{
		Timeout: backendHealthTimeout,
		// A provider-controlled redirect cannot move the hub's health probe to
		// another authority. The 3xx response itself is unhealthy.
		CheckRedirect: func(*http.Request, []*http.Request) error { return http.ErrUseLastResponse },
	}
}

// CatalogReconcilerOptions threads optional extras into the reconciler
// without bloating its constructor signature. All fields optional.
type CatalogReconcilerOptions struct {
	// HubExternalURL / HubInternalURL are kept for symmetry with the
	// admin onboarding service; the catalog controller no longer provisions or
	// mints kubeconfigs, so they are currently unused by the reconciler.
	HubExternalURL string
	HubInternalURL string

	// EdgeRoutes resolves an org-owned provider's edge transport and reconciles
	// the hub-owned Service in front of it. Nil leaves org-owned providers on
	// their declared backend URL, which is the pre-edge-transport behaviour.
	EdgeRoutes EdgeRouteResolver

	// Provisioner configures the Provisioner these controllers build — notably
	// WithWorkspaceClusterAdmin, which decides the role a provider's
	// ServiceAccount is bound to in its own workspace. Nil means the
	// Provisioner defaults, so a caller that forgets it gets the wide,
	// backwards-compatible binding rather than silently narrowing one.
	Provisioner []ProvisionerOption
}

// SetupCatalogWithManager wires the reconciler into a multicluster manager.
// kcpConfig is the admin rest.Config used only to RESOLVE each provider's
// workspace cluster ID (read-only) for the Enable flow. Pass nil to run the
// controller in registry-only mode (no kcp reads). The hub no longer
// provisions providers — that moved to admin onboarding + provider Helm init.
func SetupCatalogWithManager(mgr mcmanager.Manager, reg *Registry, kcpConfig *rest.Config, opts CatalogReconcilerOptions) error {
	r := &CatalogReconciler{
		mgr:            mgr,
		reg:            reg,
		noKCP:          kcpConfig == nil,
		hubExternalURL: opts.HubExternalURL,
		hubInternalURL: opts.HubInternalURL,
		edgeRoutes:     opts.EdgeRoutes,
		healthClient:   defaultBackendHealthClient(),
		uiClient:       defaultUIAssetClient(),
		uiIntegrity:    map[providerKey]uiIntegrityRecord{},
		clusterPaths:   map[string]string{},
	}
	if kcpConfig != nil {
		r.prov = NewProvisioner(kcpConfig, opts.Provisioner...)
	}
	return mcbuilder.ControllerManagedBy(mgr).
		Named("provider-catalog").
		For(&providersv1alpha1.CatalogEntry{}).
		Complete(r)
}

// workspacePath returns the canonical kcp workspace path for a logical cluster,
// caching the result.
//
// The read goes through the hub's kcp-admin config (r.prov), NOT the
// multicluster client for this request. That client is scoped to the
// providers.railgrid.ai APIExport virtual workspace, and a VW serves only the
// resources its APIExport declares — providers.railgrid.ai declares none beyond
// catalogentries, so core.kcp.io/LogicalCluster is not reachable there at all.
//
// An error return means "unknown", and callers MUST NOT fall back to a default
// scope: "" is the platform-global scope, which is the most privileged one in
// the registry, so guessing it on failure would publish an Org's provider to
// every tenant. A successful read with no path annotation is different and is
// reported as (""), nil: every workspace this hub creates goes through the
// Workspace API, which always stamps the annotation, so an unannotated cluster
// cannot be an org provider workspace.
func (r *CatalogReconciler) workspacePath(ctx context.Context, clusterName string) (string, error) {
	r.clusterPathsMu.RLock()
	path, ok := r.clusterPaths[clusterName]
	r.clusterPathsMu.RUnlock()
	if ok {
		return path, nil
	}

	path, err := r.prov.ResolveClusterPath(ctx, clusterName)
	if err != nil {
		// Not cached: a transient read failure must not pin a scope for the
		// lifetime of the process.
		return "", err
	}

	// Safe to cache either way now: a workspace cannot be renamed or
	// re-parented, so its path is fixed for the life of the cluster.
	r.clusterPathsMu.Lock()
	r.clusterPaths[clusterName] = path
	r.clusterPathsMu.Unlock()
	return path, nil
}

// scopeFor resolves which Org owns the providers in a logical cluster: the
// owning Org's UUID, or "" for a platform provider workspace.
//
// Without kcp (r.prov == nil) everything is platform-scoped. That is correct
// rather than a fallback: org-owned providers cannot exist without kcp, since
// the hub has to create their workspaces.
//
// Note the shape of the "" answer: any resolvable path that is not an
// org-provider path maps to platform scope, which is the widest one. That is
// safe only because of who can reach this reconciler at all — the catalog
// manager's cluster set is exactly the logical clusters holding a Ready
// providers.railgrid.ai APIBinding, and the only three sources are
// root:railgrid:system:providers plus the two provider-workspace trees, all
// hub-created. A tenant cannot put their own workspace into that set: the
// `workspace` WorkspaceType binds only core.railgrid.ai, and nothing grants
// tenants `bind` on providers.railgrid.ai.
//
// If that ever changes — if providers.railgrid.ai becomes bindable from a team
// workspace — a tenant could register a CatalogEntry that lands here with a
// non-provider path and be published platform-wide. Re-derive this default
// before widening that bind.
func (r *CatalogReconciler) scopeFor(ctx context.Context, clusterName string) (string, error) {
	if r.prov == nil {
		return "", nil
	}
	path, err := r.workspacePath(ctx, clusterName)
	if err != nil {
		return "", err
	}
	orgUUID, _, ok := kcppaths.SplitOrgProviderPath(path)
	if !ok {
		return "", nil
	}
	return orgUUID, nil
}

// Reconcile parses one CatalogEntry and updates the registry + status.
func (r *CatalogReconciler) Reconcile(ctx context.Context, req mcreconcile.Request) (ctrl.Result, error) {
	logger := klog.FromContext(ctx).WithValues("catalogentry", req.Name, "cluster", req.ClusterName)

	cl, err := r.mgr.GetCluster(ctx, req.ClusterName)
	if err != nil {
		return ctrl.Result{}, fmt.Errorf("getting cluster %s: %w", req.ClusterName, err)
	}
	c := cl.GetClient()

	var entry providersv1alpha1.CatalogEntry
	if err := c.Get(ctx, req.NamespacedName, &entry); err != nil {
		if apierrors.IsNotFound(err) {
			// Deletion. The object is gone, so its workspace path — and with it
			// its scope — is no longer resolvable; drop by the cluster the event
			// came from instead, which identifies the record unambiguously
			// across scopes.
			if r.reg.DeleteByCluster(string(req.ClusterName), req.Name) {
				logger.Info("Removed provider from registry")
			}
			return ctrl.Result{}, nil
		}
		return ctrl.Result{}, err
	}

	// Ownership comes from the workspace the entry lives in, never from a field
	// on the entry: the provider's own init writes the CatalogEntry, so anything
	// self-declared could claim another Org's scope.
	//
	// Failing the reconcile (rather than defaulting the scope) is deliberate:
	// the default would be platform-global, the widest scope there is, so a
	// resolution failure would publish an Org's provider to every tenant and
	// make it routable by bare name. Requeueing just delays the entry appearing.
	orgUUID, err := r.scopeFor(ctx, string(req.ClusterName))
	if err != nil {
		return ctrl.Result{}, fmt.Errorf("resolving provider scope for cluster %s: %w", req.ClusterName, err)
	}
	if orgUUID != "" {
		logger = logger.WithValues("orgUUID", orgUUID)
	}

	// Snapshot the status as observed. Every hub replica runs this reconciler
	// (the registry it maintains is request-path state, so it cannot be
	// leader-gated), which makes an unconditional status write a cross-replica
	// write storm: each Update bumps the resource version, every other
	// replica's watch fires, and they all write again. Every exit path below
	// goes through updateStatusIfChanged, which writes only a real diff.
	observedStatus := *entry.Status.DeepCopy()

	// Validate the action map before any endpoint is admitted into the
	// registry. A malformed declaration must fail closed: keeping a previous
	// registry record would allow an action whose contract no longer matches
	// the CatalogEntry observed by the controller.
	if err := providersv1alpha1.ValidateProviderActions(entry.Spec.Actions); err != nil {
		r.reg.DeleteScoped(orgUUID, entry.Name)
		now := metav1.NewTime(time.Now())
		entry.Status.Endpoints = &providersv1alpha1.ProviderEndpoints{}
		setCondition(&entry.Status.Conditions, metav1.Condition{
			Type:               "Ready",
			Status:             metav1.ConditionFalse,
			Reason:             "InvalidActions",
			Message:            err.Error(),
			LastTransitionTime: now,
			ObservedGeneration: entry.Generation,
		})
		if requeue, statusErr := updateStatusIfChanged(ctx, c, &entry, observedStatus); statusErr != nil {
			return ctrl.Result{}, fmt.Errorf("updating invalid-action status: %w", statusErr)
		} else if requeue {
			return ctrl.Result{Requeue: true}, nil
		}
		logger.Info("Rejected invalid provider action declarations", "error", err.Error())
		return ctrl.Result{}, nil
	}

	// Data-plane verbs gate what the scoped-identity service will mint on this
	// provider's {resource}/{verb} coordinates, so a malformed declaration
	// fails closed exactly as a malformed action does: the provider leaves the
	// registry rather than keeping a stale, wider verb surface.
	if dataPlaneErr := validateDataPlaneDeclaration(&entry); dataPlaneErr != nil {
		r.reg.DeleteScoped(orgUUID, entry.Name)
		now := metav1.NewTime(time.Now())
		entry.Status.Endpoints = &providersv1alpha1.ProviderEndpoints{}
		setCondition(&entry.Status.Conditions, metav1.Condition{
			Type:               "Ready",
			Status:             metav1.ConditionFalse,
			Reason:             "InvalidDataPlaneVerbs",
			Message:            dataPlaneErr.Error(),
			LastTransitionTime: now,
			ObservedGeneration: entry.Generation,
		})
		if requeue, statusErr := updateStatusIfChanged(ctx, c, &entry, observedStatus); statusErr != nil {
			return ctrl.Result{}, fmt.Errorf("updating invalid-data-plane status: %w", statusErr)
		} else if requeue {
			return ctrl.Result{Requeue: true}, nil
		}
		logger.Info("Rejected invalid provider data-plane verb declarations", "error", dataPlaneErr.Error())
		return ctrl.Result{}, nil
	}

	// Compositions gate what the scoped-identity service will mint on ANOTHER
	// provider's kinds (clause E), so a malformed declaration fails closed the
	// same way: the provider leaves the registry rather than keeping a stale,
	// wider composition surface that an admin already consented to.
	if compositionErr := r.validateCompositionDeclaration(orgUUID, &entry); compositionErr != nil {
		r.reg.DeleteScoped(orgUUID, entry.Name)
		now := metav1.NewTime(time.Now())
		entry.Status.Endpoints = &providersv1alpha1.ProviderEndpoints{}
		setCondition(&entry.Status.Conditions, metav1.Condition{
			Type:               "Ready",
			Status:             metav1.ConditionFalse,
			Reason:             "InvalidCompositions",
			Message:            compositionErr.Error(),
			LastTransitionTime: now,
			ObservedGeneration: entry.Generation,
		})
		if requeue, statusErr := updateStatusIfChanged(ctx, c, &entry, observedStatus); statusErr != nil {
			return ctrl.Result{}, fmt.Errorf("updating invalid-composition status: %w", statusErr)
		} else if requeue {
			return ctrl.Result{Requeue: true}, nil
		}
		logger.Info("Rejected invalid provider composition declarations", "error", compositionErr.Error())
		return ctrl.Result{}, nil
	}

	dependencies := make([]Dependency, 0, len(entry.Spec.Dependencies))
	for _, dep := range entry.Spec.Dependencies {
		dependency := Dependency{Name: dep.Name}
		for _, composition := range dep.Composes {
			dependency.Composes = append(dependency.Composes, Composition{
				Group:    composition.Group,
				Resource: composition.Resource,
				Verbs:    providersv1alpha1.CompositionVerbStrings(composition.Verbs),
			})
		}
		dependencies = append(dependencies, dependency)
	}

	prov := Provider{
		Name:         entry.Name,
		OrgUUID:      orgUUID,
		DisplayName:  entry.Spec.DisplayName,
		Description:  entry.Spec.Description,
		IconURL:      entry.Spec.IconURL,
		Category:     entry.Spec.Category,
		Dependencies: dependencies,
		Version:      entry.Spec.Version,
		// The cluster this entry was observed in is where a heartbeat must be
		// written back. Providers register their CatalogEntry in their own
		// workspace, so there is no single path the recorder could assume.
		CatalogEntryCluster: string(req.ClusterName),
	}
	prov.HubAccess = append([]providersv1alpha1.ProviderHubAccess(nil), entry.Spec.HubAccess...)

	// An org-owned provider runs in the tenant's own cluster, so its data plane
	// travels the edge tunnel rather than a URL the hub dials. Resolve that
	// route from the binding the HUB recorded at registration — never from this
	// CatalogEntry, which the tenant's own chart wrote — and reconcile the
	// hub-owned Service the tunnel lands on.
	//
	// A failure here is not fatal to the registry entry: the provider still
	// exists, is still discoverable, and its control half (Templates, Instances
	// through kcp) is unaffected. It just has no reachable backend, which the
	// proxy reports as 503 rather than dialling an address inside someone
	// else's cluster.
	var edgeRouteErr error
	if orgUUID != "" && entry.Spec.Backend != nil {
		if r.edgeRoutes == nil {
			edgeRouteErr = fmt.Errorf("edge route resolver is unavailable")
		} else if route, err := r.edgeRoutes.ResolveProviderEdgeRoute(ctx, orgUUID, entry.Name, entry.Spec.Backend.URL); err != nil {
			edgeRouteErr = err
			logger.Info("Could not resolve edge route for org-owned provider; its backend stays unroutable",
				"provider", entry.Name, "error", err.Error())
		} else if !route.Usable() {
			edgeRouteErr = fmt.Errorf("edge route is not yet usable")
			logger.Info("Edge route for org-owned provider is not yet usable", "provider", entry.Name)
		} else {
			prov.EdgeRoute = route
		}
	}

	if sh := entry.Spec.SelfHosting; sh != nil {
		mapped := &SelfHosting{
			Supported:   sh.Supported,
			Namespace:   sh.Namespace,
			ReleaseName: sh.ReleaseName,
			DocsURL:     sh.DocsURL,
			ValuesDoc:   sh.ValuesDoc,
		}
		if sh.Chart != nil {
			mapped.ChartRepo = sh.Chart.Repository
			mapped.ChartName = sh.Chart.Name
			mapped.ChartVersion = sh.Chart.Version
		}
		for _, v := range sh.RequiredValues {
			mapped.RequiredValues = append(mapped.RequiredValues, SelfHostingValue{
				Name:        v.Name,
				Description: v.Description,
				IdentityFor: v.IdentityFor,
				Value:       v.Value,
			})
		}
		prov.SelfHosting = mapped
	}
	// Liveness travels through status so it reaches every hub replica, not just
	// the one whose heartbeat endpoint the provider happened to hit.
	if entry.Status.LastHeartbeat != nil {
		prov.LastHeartbeat = entry.Status.LastHeartbeat.Time
		prov.HeartbeatRequired = true
		prov.HeartbeatStale = time.Since(prov.LastHeartbeat) > HeartbeatTTL
		prov.ReportedVersion = entry.Status.ReportedVersion
	}
	if entry.Spec.APIExport != nil {
		prov.APIExportName = entry.Spec.APIExport.Name
		// The export lives in the workspace the entry was observed in. For an
		// org-owned provider that is the Org's own provider workspace, not the
		// platform parent — binding the platform path would resolve to a
		// different (or absent) export.
		if orgUUID != "" {
			prov.APIExportPath = kcppaths.OrgProviderPath(orgUUID, entry.Name)
		} else {
			prov.APIExportPath = providersParentWorkspace + ":" + entry.Name
		}
		for _, c := range entry.Spec.APIExport.PermissionClaims {
			claim := PermissionClaim{
				Group:        c.Group,
				Resource:     c.Resource,
				Verbs:        append([]string(nil), c.Verbs...),
				TenantScoped: c.TenantScoped,
			}
			if c.Selector != nil {
				claim.MatchLabels = copyLabels(c.Selector.MatchLabels)
			}
			prov.PermissionClaims = append(prov.PermissionClaims, claim)
		}
	}

	// Which API groups this provider serves is READ from its APIExport, never
	// inferred from the export's name. `edges.providers.railgrid.ai` serves
	// `edges.railgrid.ai`; `ai.railgrid.ai` serves `ai.railgrid.ai`;
	// `kuery.providers.railgrid.ai` serves its own name. The convention is not
	// a rule and one export may serve several groups, so the only source that
	// can be trusted is spec.resources[].group on the object itself.
	//
	// It is re-read on EVERY reconcile rather than watched. The catalog
	// controller's clients are the providers.railgrid.ai APIExport virtual
	// workspace, which serves catalogentries and nothing else — APIExports are
	// not reachable there at all, so there is no cheap watch to take. Instead
	// the read rides the reconciles this entry already gets: the provider's
	// `init` writes the export and then its heartbeat, and a heartbeating
	// provider re-reconciles every SweepInterval; an entry whose groups are
	// still unknown requeues on the same cadence below until they resolve.
	var apiGroupErr error
	if prov.APIExportName != "" {
		if resolve := r.apiGroupResolver(); resolve == nil {
			apiGroupErr = fmt.Errorf("the hub has no kcp client to read APIExport %q with", prov.APIExportName)
		} else if groups, err := resolve(ctx, prov.APIExportPath, prov.APIExportName); err != nil {
			apiGroupErr = err
		} else {
			prov.APIGroups = groups
		}
		if apiGroupErr != nil {
			// A read failure must not RETRACT groups the hub already resolved:
			// an APIExport's group set does not change because kcp was briefly
			// unreachable, and dropping it would revoke every consumer's
			// cross-provider identity on the next refresh. status carries the
			// last successful read — written by whichever replica managed it,
			// and surviving a hub restart — so it is the fallback. Only a
			// provider whose export has NEVER been read has no groups.
			prov.APIGroups = append([]string(nil), entry.Status.APIGroups...)
			logger.Info("WARNING could not read provider APIExport groups",
				"export", prov.APIExportPath+":"+prov.APIExportName,
				"lastKnown", prov.APIGroups, "err", apiGroupErr.Error())
		}
	}

	// Builtin (first-party) providers declare spec.ui.builtinRoute instead
	// of a URL. The portal renders the named Vue route in-tree, so there's
	// no proxy target and no /main.js bundle to load — UIURL stays nil.
	if entry.Spec.UI != nil {
		prov.BuiltinRoute = entry.Spec.UI.BuiltinRoute
		for _, c := range entry.Spec.UI.Children {
			prov.Children = append(prov.Children, NavChild{
				DisplayName:  c.DisplayName,
				BuiltinRoute: c.BuiltinRoute,
			})
		}
	}
	parsedActions, actionSchemaErr := ParseProviderActions(entry.Spec.Actions)
	if actionSchemaErr != nil {
		r.reg.DeleteScoped(orgUUID, entry.Name)
		now := metav1.NewTime(time.Now())
		entry.Status.Endpoints = &providersv1alpha1.ProviderEndpoints{}
		setCondition(&entry.Status.Conditions, metav1.Condition{
			Type:               "Ready",
			Status:             metav1.ConditionFalse,
			Reason:             "InvalidActionSchemas",
			Message:            actionSchemaErr.Error(),
			LastTransitionTime: now,
			ObservedGeneration: entry.Generation,
		})
		if requeue, statusErr := updateStatusIfChanged(ctx, c, &entry, observedStatus); statusErr != nil {
			return ctrl.Result{}, fmt.Errorf("updating invalid-action-schema status: %w", statusErr)
		} else if requeue {
			return ctrl.Result{Requeue: true}, nil
		}
		logger.Info("Rejected provider action schemas", "error", actionSchemaErr.Error())
		return ctrl.Result{}, nil
	}
	prov.Actions = parsedActions
	prov.DataPlaneVerbs = dataPlaneVerbsFor(entry.Spec.DataPlane)
	seenSkillPackages := make(map[string]struct{}, len(entry.Spec.AssistantSkills))
	var assistantSkillBytes int64
	for _, skill := range entry.Spec.AssistantSkills {
		if skillErr := providersv1alpha1.ValidateProviderAssistantSkill(skill); skillErr != nil {
			// Skill packages are independent of provider routing and action
			// declarations. Omit only the malformed package so valid sibling
			// skills and actions remain available; App Studio receives no
			// partially validated artifact.
			logger.Info("Omitting invalid provider assistant skill", "packageName", skill.PackageName, "error", skillErr.Error())
			continue
		}
		if _, duplicate := seenSkillPackages[skill.PackageName]; duplicate {
			logger.Info("Omitting duplicate provider assistant skill", "packageName", skill.PackageName)
			continue
		}
		packageBytes := int64(len([]byte(skill.Skill)))
		for _, resource := range skill.Resources {
			packageBytes += int64(len([]byte(resource.Content)))
		}
		if assistantSkillBytes+packageBytes > providersv1alpha1.ProviderAssistantSkillsMaxAggregateBytes {
			logger.Info("Omitting provider assistant skill after aggregate bound", "packageName", skill.PackageName, "maxBytes", providersv1alpha1.ProviderAssistantSkillsMaxAggregateBytes)
			continue
		}
		seenSkillPackages[skill.PackageName] = struct{}{}
		assistantSkillBytes += packageBytes
		resources := make([]ProviderAssistantSkillResource, 0, len(skill.Resources))
		for _, resource := range skill.Resources {
			resources = append(resources, ProviderAssistantSkillResource{Path: resource.Path, Content: resource.Content})
		}
		prov.AssistantSkills = append(prov.AssistantSkills, ProviderAssistantSkill{
			PackageName: skill.PackageName,
			Version:     skill.Version,
			Digest:      skill.Digest,
			Skill:       skill.Skill,
			Resources:   resources,
		})
	}
	sort.Slice(prov.AssistantSkills, func(i, j int) bool {
		if prov.AssistantSkills[i].PackageName != prov.AssistantSkills[j].PackageName {
			return prov.AssistantSkills[i].PackageName < prov.AssistantSkills[j].PackageName
		}
		return prov.AssistantSkills[i].Version < prov.AssistantSkills[j].Version
	})

	var parseErrs []string
	var backendHealthErr error
	if entry.Spec.UI != nil && entry.Spec.UI.URL != "" {
		u, err := ParseURL(entry.Spec.UI.URL)
		if err != nil {
			parseErrs = append(parseErrs, "ui.url: "+err.Error())
		} else {
			prov.UIURL = u
		}
	}
	if entry.Spec.Backend != nil {
		u, err := ParseURL(entry.Spec.Backend.URL)
		if err != nil {
			parseErrs = append(parseErrs, "backend.url: "+err.Error())
		} else {
			prov.BackendURL = u
			// Platform providers are hub-operated and their declared service URL
			// is an admitted in-cluster route. Org-owned provider URLs name an
			// address inside a tenant cluster; direct probing would bypass the
			// hub-owned edge route and turn tenant input into an SSRF primitive.
			if orgUUID == "" {
				prov.BackendHealthRequired = true
				healthClient := r.healthClient
				if healthClient == nil {
					healthClient = defaultBackendHealthClient()
				}
				if err := probeBackendHealth(ctx, healthClient, u, entry.Spec.Backend.HealthPath); err != nil {
					backendHealthErr = err
				} else {
					prov.BackendHealthy = true
				}
			}
		}
	}
	// There is no virtual-workspace endpoint to parse: spec.virtualWorkspace was
	// removed from the CatalogEntry. The hub never routed
	// /services/providers/{name}/vw/*; custom verbs belong on the data-plane
	// grammar (docs/provider-connectivity-contract.md).

	// If this CatalogEntry name matches a first-party provider that
	// registered LocalUIAssets via BuiltinSpec, plumb the embedded FS into
	// the registry record so the UI proxy serves /ui/providers/{name}/*
	// from the hub binary instead of forwarding to an external URL.
	if spec, ok := BuiltinByName(entry.Name); ok && spec.LocalUIAssets != nil && prov.UIURL == nil && prov.BuiltinRoute == "" {
		prov.LocalUIAssets = spec.LocalUIAssets
	}

	// Pin the bundle the portal will execute in its own document. The pin is
	// keyed on the running version so a chart upgrade or a heartbeat that
	// reports a new version re-hashes on this reconcile; otherwise a cached
	// pin is reused until UIIntegrityResync.
	uiVersion := uiIntegrityVersion(entry.Spec.Version, entry.Status.ReportedVersion)
	if integrity, ok := r.pinUIIntegrity(ctx, logger, prov, uiVersion); ok {
		prov.MainJSIntegrity = integrity
	}

	// EndpointsValid covers spec parse health and "the provider offers
	// something": a URL endpoint OR a builtin Vue route OR a backend proxy
	// target OR embedded UI assets OR an APIExport. Heartbeat-driven readiness
	// is layered on by the sweeper (see Provider.Ready()).
	//
	// An APIExport alone counts: such a provider contributes CRDs to the
	// workspaces that Enable it and is fully usable via kubectl and the kcp
	// proxy with no hub-proxied surface at all. That shape is the common case
	// for org-owned providers, which frequently ship an API and no portal UI.
	// It opens no route — the proxies independently 404 when UIURL/BackendURL
	// are nil — it only stops the portal from rendering the provider as broken.
	prov.EndpointsValid = len(parseErrs) == 0 &&
		(prov.UIURL != nil || prov.BackendURL != nil ||
			prov.BuiltinRoute != "" || prov.LocalUIAssets != nil || prov.APIExportName != "")

	r.reg.Upsert(prov)
	// Render URLs as strings: a nil *url.URL panics klog's stringer (shows as
	// "<panic: ...>" in logs), which is the common case for builtins (localUI).
	logger.Info("Upserted provider", "endpointsValid", prov.EndpointsValid, "ui", urlString(prov.UIURL), "backend", urlString(prov.BackendURL), "localUI", prov.LocalUIAssets != nil)

	// The hub no longer provisions the per-provider workspace, schemas,
	// APIExport, SA, or kubeconfig — that moved to admin onboarding
	// (pkg/hub/admin) plus the provider's own Helm `init` (railgrid-provider-sdk).
	// We only RESOLVE the provider workspace's logical cluster ID (read-only)
	// so the admin providers API can report where a provider lives.
	switch {
	case entry.Spec.APIExport == nil:
		// No export to bind, so nothing needs the RBAC subject.
	case orgUUID != "":
		// An org-owned provider always registers its CatalogEntry from inside
		// its own workspace, so the cluster the entry was observed in IS the
		// provider workspace — no lookup needed. (Platform providers can't take
		// this shortcut: the builtin entries are seeded into
		// root:railgrid:system:providers, a different workspace from the one they
		// describe.)
		entry.Status.Workspace = kcppaths.OrgProviderPath(orgUUID, entry.Name)
		r.reg.SetWorkspaceCluster(orgUUID, entry.Name, string(req.ClusterName))
	case r.prov != nil:
		// Returns empty until the provider has been onboarded, which is the
		// correct gate.
		if cluster, err := r.prov.ResolveWorkspaceCluster(ctx, entry.Name); err != nil {
			logger.Info("WARNING could not resolve provider workspace cluster", "err", err.Error())
		} else if cluster != "" {
			entry.Status.Workspace = providersParentWorkspace + ":" + entry.Name
			r.reg.SetWorkspaceCluster("", entry.Name, cluster)
		}
	}

	// Rotated-out provider credentials die here. Rotation only writes an expiry
	// onto the retired token Secret; something has to come back later and
	// delete it, and this reconciler is the one loop that runs for every
	// provider workspace the hub knows — platform and org-owned alike, without
	// the hub having to enumerate every Org's tree. The CatalogEntry lives in
	// the provider's own workspace, so the cluster it was observed in IS the
	// workspace holding the Secrets; a cluster with no provider ServiceAccount
	// (a builtin entry seeded into system:providers) sweeps to a no-op.
	var credentialExpiryPending bool
	if sweep := r.credentialSweeper(); sweep != nil {
		deleted, next, err := sweep(ctx, string(req.ClusterName))
		switch {
		case err != nil:
			// Never fatal to the reconcile: a provider whose old credential
			// outlives its grace period by one interval is a smaller problem
			// than a registry that stops tracking the provider at all.
			logger.Info("WARNING could not sweep expired provider token Secrets", "err", err.Error())
		case deleted > 0:
			logger.Info("Deleted expired provider token Secrets", "count", deleted)
		}
		credentialExpiryPending = !next.IsZero()
	}

	// Update status.
	now := metav1.NewTime(time.Now())
	entry.Status.Endpoints = &providersv1alpha1.ProviderEndpoints{}
	if prov.UIURL != nil {
		entry.Status.Endpoints.UI = prov.UIURL.String()
	}
	if prov.BackendURL != nil {
		entry.Status.Endpoints.Backend = prov.BackendURL.String()
	}
	// Mirror the resolved projection so it is inspectable where an operator
	// already looks — `kubectl get catalogentry -o yaml` — and so /api/providers
	// can show which groups a provider actually owns. It doubles as the
	// cross-replica and cross-restart carrier the read-failure path above falls
	// back to.
	entry.Status.APIGroups = append([]string(nil), prov.APIGroups...)
	if prov.APIExportName == "" {
		removeCondition(&entry.Status.Conditions, ConditionAPIGroupsUnknown)
	} else {
		groupsCondition := metav1.Condition{
			Type:               ConditionAPIGroupsUnknown,
			LastTransitionTime: now,
			ObservedGeneration: entry.Generation,
		}
		if len(prov.APIGroups) > 0 {
			groupsCondition.Status = metav1.ConditionFalse
			groupsCondition.Reason = "APIGroupsResolved"
			groupsCondition.Message = fmt.Sprintf("APIExport %s serves API groups: %s.",
				prov.APIExportName, strings.Join(prov.APIGroups, ", "))
		} else {
			groupsCondition.Status = metav1.ConditionTrue
			groupsCondition.Reason = "APIExportUnreadable"
			groupsCondition.Message = fmt.Sprintf(
				"The API groups APIExport %s serves could not be read, so no scoped identity may name them. %s",
				prov.APIExportName, apiGroupsUnknownDetail(apiGroupErr))
			logger.Info("Provider API groups are unknown; cross-provider rules naming them will be refused",
				"export", prov.APIExportPath+":"+prov.APIExportName)
		}
		setCondition(&entry.Status.Conditions, groupsCondition)
	}
	entry.Status.UI = nil
	if prov.MainJSIntegrity != "" {
		entry.Status.UI = &providersv1alpha1.ProviderUIStatus{
			MainJSIntegrity:        prov.MainJSIntegrity,
			MainJSIntegrityVersion: uiVersion,
		}
	}
	if !prov.BackendHealthRequired {
		removeCondition(&entry.Status.Conditions, "BackendHealthy")
	} else {
		backendCondition := metav1.Condition{
			Type:               "BackendHealthy",
			LastTransitionTime: now,
			ObservedGeneration: entry.Generation,
		}
		if prov.BackendHealthy {
			backendCondition.Status = metav1.ConditionTrue
			backendCondition.Reason = "HealthCheckSucceeded"
			backendCondition.Message = "Provider backend health check succeeded."
		} else {
			backendCondition.Status = metav1.ConditionFalse
			backendCondition.Reason = "HealthCheckFailed"
			backendCondition.Message = "Provider backend health check failed."
			logger.Info("Provider backend health check failed", "error", backendHealthErr)
		}
		setCondition(&entry.Status.Conditions, backendCondition)
	}

	cond := metav1.Condition{
		Type:               "Ready",
		LastTransitionTime: now,
		ObservedGeneration: entry.Generation,
	}
	switch {
	case len(parseErrs) > 0:
		cond.Status = metav1.ConditionFalse
		cond.Reason = "InvalidEndpoint"
		cond.Message = fmt.Sprintf("Endpoint parse errors: %v", parseErrs)
	case edgeRouteErr != nil:
		cond.Status = metav1.ConditionFalse
		cond.Reason = "BackendUnroutable"
		cond.Message = "Provider backend route is unavailable."
	case prov.BackendHealthRequired && !prov.BackendHealthy:
		cond.Status = metav1.ConditionFalse
		cond.Reason = "BackendUnhealthy"
		cond.Message = "Provider backend is unavailable."
	case prov.HeartbeatRequired && prov.HeartbeatStale:
		cond.Status = metav1.ConditionFalse
		cond.Reason = "HeartbeatStale"
		cond.Message = "Provider heartbeat is stale."
	case prov.EndpointsValid:
		cond.Status = metav1.ConditionTrue
		cond.Reason = "Ready"
		cond.Message = "Provider endpoints and health checks are ready."
	default:
		cond.Status = metav1.ConditionFalse
		cond.Reason = "NoEndpoint"
		cond.Message = "CatalogEntry declares no UI or Backend endpoint."
	}
	setCondition(&entry.Status.Conditions, cond)

	if requeue, err := updateStatusIfChanged(ctx, c, &entry, observedStatus); err != nil {
		return ctrl.Result{}, fmt.Errorf("updating status: %w", err)
	} else if requeue {
		return ctrl.Result{Requeue: true}, nil
	}
	// An entry whose API groups are still unknown retries on the sweep cadence:
	// the gap closes by itself once the provider's `init` has applied its
	// APIExport, and nothing else would bring this entry back.
	apiGroupsUnknown := prov.APIExportName != "" && len(prov.APIGroups) == 0
	if prov.BackendHealthRequired || prov.HeartbeatRequired || edgeRouteErr != nil || credentialExpiryPending || apiGroupsUnknown {
		return ctrl.Result{RequeueAfter: SweepInterval}, nil
	}
	if prov.MainJSIntegrity != "" || prov.LocalUIAssets != nil || (prov.UIURL != nil && prov.OrgUUID == "") {
		// Nothing else drives a periodic reconcile for this entry, so schedule
		// the SRI resync (and the retry after a failed hash fetch) here.
		return ctrl.Result{RequeueAfter: UIIntegrityResync}, nil
	}
	return ctrl.Result{}, nil
}

// probeBackendHealth builds a same-authority endpoint from backend and the
// provider's relative healthPath, then requires HTTP 200 within a bounded
// interval. Absolute URLs and traversal are rejected before any request.
func probeBackendHealth(ctx context.Context, client httpDoer, backend *url.URL, healthPath string) error {
	if backend == nil {
		return fmt.Errorf("backend URL is missing")
	}
	if backend.Scheme != "http" && backend.Scheme != "https" {
		return fmt.Errorf("backend URL must use http or https")
	}
	if healthPath == "" {
		healthPath = "/healthz"
	}
	rel, err := url.Parse(healthPath)
	if err != nil {
		return fmt.Errorf("invalid healthPath: %w", err)
	}
	if rel.IsAbs() || rel.Host != "" || rel.User != nil || rel.Opaque != "" || rel.Fragment != "" {
		return fmt.Errorf("healthPath must be a local HTTP path")
	}
	decodedPath, err := url.PathUnescape(rel.EscapedPath())
	if err != nil {
		return fmt.Errorf("invalid healthPath escaping: %w", err)
	}
	for _, segment := range strings.Split(decodedPath, "/") {
		if segment == "." || segment == ".." {
			return fmt.Errorf("healthPath must not contain traversal segments")
		}
	}
	if decodedPath == "" {
		return fmt.Errorf("healthPath must not be empty")
	}
	if !strings.HasPrefix(decodedPath, "/") {
		decodedPath = "/" + decodedPath
	}
	target := *backend
	target.Path = singleJoiningSlash(backend.Path, decodedPath)
	target.RawPath = ""
	target.RawQuery = rel.RawQuery
	target.Fragment = ""

	probeCtx, cancel := context.WithTimeout(ctx, backendHealthTimeout)
	defer cancel()
	req, err := http.NewRequestWithContext(probeCtx, http.MethodGet, target.String(), nil)
	if err != nil {
		return fmt.Errorf("build health request: %w", err)
	}
	resp, err := client.Do(req)
	if err != nil {
		return fmt.Errorf("request failed: %w", err)
	}
	defer func() { _ = resp.Body.Close() }()
	_, _ = io.Copy(io.Discard, io.LimitReader(resp.Body, 4096))
	if resp.StatusCode != http.StatusOK {
		return fmt.Errorf("returned HTTP %d", resp.StatusCode)
	}
	return nil
}

// updateStatusIfChanged writes entry's status only when it differs from what
// was observed, and reports whether the caller should requeue after a conflict.
// Skipping no-op writes is what keeps N hub replicas reconciling the same
// CatalogEntry from bumping its resource version in a loop.
func updateStatusIfChanged(
	ctx context.Context,
	c client.Client,
	entry *providersv1alpha1.CatalogEntry,
	observed providersv1alpha1.CatalogEntryStatus,
) (requeue bool, err error) {
	if equality.Semantic.DeepEqual(observed, entry.Status) {
		return false, nil
	}
	if err := c.Status().Update(ctx, entry); err != nil {
		if apierrors.IsConflict(err) {
			return true, nil
		}
		return false, err
	}
	return false, nil
}

// apiGroupsUnknownDetail explains WHY the group list is empty, which is two
// different situations an operator fixes differently: the export could not be
// read at all, or it was read and declares no resources yet (its `init` has
// applied the export but not the schemas).
func apiGroupsUnknownDetail(err error) string {
	if err != nil {
		return "Reading it failed: " + err.Error()
	}
	return "The APIExport declares no resources yet; the provider's init may not have applied its schemas."
}

// urlString renders a *url.URL for logging, returning "" for nil (a nil
// *url.URL panics klog's stringer).
func urlString(u *url.URL) string {
	if u == nil {
		return ""
	}
	return u.String()
}

// setCondition is a small upsert helper for metav1.Condition slices.
func setCondition(conds *[]metav1.Condition, c metav1.Condition) {
	for i, existing := range *conds {
		if existing.Type == c.Type {
			if existing.Status == c.Status {
				c.LastTransitionTime = existing.LastTransitionTime
			}
			if equality.Semantic.DeepEqual(existing, c) {
				return
			}
			(*conds)[i] = c
			return
		}
	}
	*conds = append(*conds, c)
}

func removeCondition(conds *[]metav1.Condition, conditionType string) {
	for i, condition := range *conds {
		if condition.Type == conditionType {
			*conds = append((*conds)[:i], (*conds)[i+1:]...)
			return
		}
	}
}

// validateDataPlaneDeclaration checks a CatalogEntry's data-plane verbs.
//
// Beyond shape, it enforces the one structural rule the hub can check here: a
// provider declares verbs on resources its OWN APIExport serves, so declaring
// any verb without declaring an APIExport is rejected. The hub cannot go
// further at this layer — the CatalogEntry names the export but not the
// resources it serves, and the APIResourceSchemas live in the provider's
// workspace — so a verb on a resource the export does not actually serve is
// caught where it matters instead: the coordinate is only ever granted
// alongside a resourceNames-scoped rule on that same resource, which authorizes
// nothing if the resource is not real.
func validateDataPlaneDeclaration(entry *providersv1alpha1.CatalogEntry) error {
	if err := providersv1alpha1.ValidateProviderDataPlane(entry.Spec.DataPlane); err != nil {
		return err
	}
	if entry.Spec.DataPlane == nil || len(entry.Spec.DataPlane.Verbs) == 0 {
		return nil
	}
	if entry.Spec.APIExport == nil || strings.TrimSpace(entry.Spec.APIExport.Name) == "" {
		return fmt.Errorf("dataPlane.verbs requires spec.apiExport: a provider declares verbs on resources its own APIExport serves")
	}
	return nil
}

// validateCompositionDeclaration checks a CatalogEntry's composition
// declarations: shape first, then the one thing the registry can answer —
// that each composed group really is a group the named dependency SERVES.
//
// "Serves" is the dependency's APIGroups — read from its APIExport — and not
// its APIExport NAME. Checking the name would reject every correct declaration
// the platform ships: App Studio composes `infrastructure.railgrid.ai` and
// `code.railgrid.ai`, while those providers' exports are named
// `infrastructure.providers.railgrid.ai` and `code.providers.railgrid.ai`.
//
// A composition on a group somebody else serves would be a consent prompt that
// reads "App Studio manages infrastructure Instances" while pointing at a
// different provider's API, so it is refused outright.
//
// When the dependency is not in the registry yet — or is there but its API
// groups have not been read yet — the group check is SKIPPED rather than
// failed. Provider CatalogEntries arrive in no particular order and the hub
// must not make a provider's readiness depend on which of two charts
// reconciled first; nothing is granted by the gap, because the identity policy
// resolves the group's owner again at mint time and refuses a composition
// whose group the dependency does not serve.
func (r *CatalogReconciler) validateCompositionDeclaration(orgUUID string, entry *providersv1alpha1.CatalogEntry) error {
	if err := providersv1alpha1.ValidateProviderCompositions(entry.Spec.Dependencies); err != nil {
		return err
	}
	for _, dep := range entry.Spec.Dependencies {
		if len(dep.Composes) == 0 {
			continue
		}
		if entry.Spec.APIExport == nil || strings.TrimSpace(entry.Spec.APIExport.Name) == "" {
			return fmt.Errorf("dependencies[%s].composes requires spec.apiExport: only a provider with its own API surface reconciles objects in a tenant workspace", dep.Name)
		}
		if r.reg == nil {
			continue
		}
		dependency, found := r.reg.GetForOrg(orgUUID, dep.Name)
		if !found || len(dependency.APIGroups) == 0 {
			continue
		}
		for _, composition := range dep.Composes {
			if !containsString(dependency.APIGroups, composition.Group) {
				return fmt.Errorf("dependencies[%s].composes: %s is not served by %s (it serves %s)",
					dep.Name, composition.Group, dep.Name, strings.Join(dependency.APIGroups, ", "))
			}
		}
	}
	return nil
}

// containsString reports whether values holds want.
func containsString(values []string, want string) bool {
	for _, value := range values {
		if value == want {
			return true
		}
	}
	return false
}

// dataPlaneVerbsFor projects the declaration into the registry's flat form.
func dataPlaneVerbsFor(dataPlane *providersv1alpha1.ProviderDataPlane) []ProviderDataPlaneVerb {
	if dataPlane == nil || len(dataPlane.Verbs) == 0 {
		return nil
	}
	verbs := make([]ProviderDataPlaneVerb, 0, len(dataPlane.Verbs))
	for _, verb := range dataPlane.Verbs {
		verbs = append(verbs, ProviderDataPlaneVerb{
			Resource: verb.Resource, Verb: verb.Verb,
			Description: verb.Description, Stream: verb.Stream, ReadOnly: verb.ReadOnly,
		})
	}
	return verbs
}
