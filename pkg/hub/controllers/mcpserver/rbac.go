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

package mcpserver

import (
	"context"
	"fmt"
	"regexp"
	"slices"
	"sort"
	"strings"
	"sync"
	"time"

	apisv1alpha2 "github.com/kcp-dev/sdk/apis/apis/v1alpha2"
	kcpclientset "github.com/kcp-dev/sdk/client/clientset/versioned"
	rbacv1 "k8s.io/api/rbac/v1"
	"k8s.io/apimachinery/pkg/api/equality"
	apierrors "k8s.io/apimachinery/pkg/api/errors"
	metav1 "k8s.io/apimachinery/pkg/apis/meta/v1"
	"k8s.io/apimachinery/pkg/runtime"
	"k8s.io/apimachinery/pkg/runtime/schema"
	"k8s.io/client-go/dynamic"
	"k8s.io/client-go/kubernetes"
	"k8s.io/client-go/rest"
	"k8s.io/klog/v2"

	providersv1alpha1 "github.com/railgrid/railgrid/apis/providers/v1alpha1"
	railgridv1alpha1 "github.com/railgrid/railgrid/apis/railgrid/v1alpha1"
	"github.com/railgrid/railgrid/pkg/apiurl"
	"github.com/railgrid/railgrid/pkg/kcppaths"
)

// roleNamePrefix prefixes the generated per-server ClusterRole name:
// railgrid:mcpserver:<MCPServer name>.
const roleNamePrefix = "railgrid:mcpserver:"

var (
	// readVerbs is granted on every bound provider resource.
	readVerbs = []string{"get", "list", "watch"}
	// writeVerbs is granted on every bound provider resource unless the server
	// is spec.readOnly.
	writeVerbs = []string{"create", "update", "patch", "delete"}
)

// dataPlaneGrant describes RBAC coordinates a provider data plane checks with
// a SubjectAccessReview as the caller instead of serving through the API
// server. They exist purely as authorization coordinates, so the tenant's
// APIBindings never list them and they have to be spelled out here.
type dataPlaneGrant struct {
	// resources, when non-empty, restricts the grant to those resources
	// (intersected with what the tenant actually bound). Empty means every
	// bound resource in the group, which is only correct when the data plane
	// really does serve all of them. Anything narrower must be listed, or the
	// grant widens itself as new resources join the group's APIExport.
	resources []string
	// verbs are extra verbs granted on the bound resources themselves. They
	// gate access to a data plane rather than a mutation of the object, and
	// they are dropped for readOnly servers: the data planes behind them do
	// not distinguish reads from writes (the edges tunnel serves kubectl
	// delete, exec and an SSH shell under the one "proxy" verb), so keeping
	// the verb would make a read-only token a full operator of every bound
	// edge. Read-only servers therefore lose data-plane access until a data
	// plane offers a read-only mode of its own; that is the safe direction.
	verbs []string
	// subresources are virtual subresources granted with "create". They
	// invoke something (a shell, a job) and are dropped for readOnly servers.
	subresources []string
}

// dataPlaneGrants is keyed by API group of the bound resources.
var dataPlaneGrants = map[string]dataPlaneGrant{
	// The edges tunnel authorizes verb "proxy" on the edge object before
	// serving its k8s/ssh/mcp subresources (providers/edges/internal/tunnel).
	// Every edge kind the group exports is proxyable, so no resource filter.
	// The tunnel checks "proxy" for every HTTP method on the k8s subresource
	// and for ssh sessions alike, so this is never granted to readOnly
	// servers (see dataPlaneGrant.verbs).
	"edges.railgrid.ai": {verbs: []string{"proxy"}},
	// The infrastructure data plane authorizes "create" on <instance>/exec
	// before running a command in a dev instance
	// (providers/infrastructure/dataplane/authorizer.go). instances is the
	// only resource the data plane serves — the handler rejects anything else
	// — so exec is granted on instances alone and never on, say, templates.
	"infrastructure.railgrid.ai": {resources: []string{"instances"}, subresources: []string{"exec"}},
}

// privilegedResources are bound resources a generated MCPServer role NEVER
// grants, in any verb, read or write. The rule above widens itself as a
// provider's APIExport grows, which is right for ordinary provider objects and
// wrong for the few whose creation IS the privilege escalation.
//
// edges.railgrid.ai/addons is the first such resource: creating an Addon asks a
// specific machine to become a host for arbitrary code execution. That decision
// belongs to a human with workspace admin rights (whose wildcard still covers
// it) and to the machine's owner, who must independently have started the agent
// with --allow-addon. Handing it to every MCPServer token in the workspace —
// which is what "the tenant bound this resource" would otherwise mean — would
// let an AI client turn a developer's laptop into a code-execution host as a
// side effect of a tool call. See docs/edge-addons.md.
var privilegedResources = map[string]map[string]bool{
	"edges.railgrid.ai": {"addons": true},
}

// dropPrivilegedResources removes the never-granted resources of one group.
func dropPrivilegedResources(group string, resources []string) []string {
	denied := privilegedResources[group]
	if len(denied) == 0 {
		return resources
	}
	out := make([]string, 0, len(resources))
	for _, r := range resources {
		if !denied[r] {
			out = append(out, r)
		}
	}
	return out
}

// ActionGrant is one provider action from the platform catalog, expressed as
// the RBAC coordinate a provider checks before invoking it: "create" on
// <Resource>/<Name> in Group (e.g. tables/query_table).
type ActionGrant struct {
	Group    string
	Resource string
	// Name is the action name without its version suffix — the subresource
	// the provider's SelfSubjectAccessReview names.
	Name string
	// ReadOnly mirrors the catalog's declaration; read-only actions stay
	// granted on readOnly servers.
	ReadOnly bool
}

// ActionGrantSource lists the action grants declared by platform providers.
type ActionGrantSource func(ctx context.Context) ([]ActionGrant, error)

// buildRules derives the ClusterRole rules for one server: every resource the
// tenant has bound gets read (and, unless readOnly, write) verbs; data-plane
// coordinates (never for readOnly) and catalog actions are added for bound
// resources only; plus the read-only kcp/authz plumbing every tool path
// needs. Output is deterministic so reconcile-time comparison is stable.
func buildRules(bound []apisv1alpha2.BoundAPIResource, actions []ActionGrant, readOnly bool) []rbacv1.PolicyRule {
	byGroup := map[string]map[string]struct{}{}
	for _, b := range bound {
		if b.Resource == "" {
			continue
		}
		if byGroup[b.Group] == nil {
			byGroup[b.Group] = map[string]struct{}{}
		}
		byGroup[b.Group][b.Resource] = struct{}{}
	}

	// Action coordinates, keyed by group, only for resources that are bound.
	actionSubs := map[string]map[string]struct{}{}
	for _, a := range actions {
		if a.Name == "" || a.Resource == "" {
			continue
		}
		if _, ok := byGroup[a.Group][a.Resource]; !ok {
			continue
		}
		// A catalog action must not become a back door into a resource the
		// generated role refuses outright.
		if privilegedResources[a.Group][a.Resource] {
			continue
		}
		if readOnly && !a.ReadOnly {
			continue
		}
		if actionSubs[a.Group] == nil {
			actionSubs[a.Group] = map[string]struct{}{}
		}
		actionSubs[a.Group][a.Resource+"/"+a.Name] = struct{}{}
	}

	groups := make([]string, 0, len(byGroup))
	for g := range byGroup {
		groups = append(groups, g)
	}
	sort.Strings(groups)

	verbs := append([]string{}, readVerbs...)
	if !readOnly {
		verbs = append(verbs, writeVerbs...)
	}

	var rules []rbacv1.PolicyRule
	for _, g := range groups {
		// Privileged resources are dropped before anything else keys off the
		// list, so they cannot come back through a data-plane or action grant.
		resources := dropPrivilegedResources(g, sortedKeys(byGroup[g]))
		if len(resources) == 0 {
			continue
		}
		rules = append(rules, rbacv1.PolicyRule{APIGroups: []string{g}, Resources: resources, Verbs: verbs})

		if dp, ok := dataPlaneGrants[g]; ok {
			// Scope the grant to the resources the data plane actually serves,
			// so binding an unrelated resource in the same group never widens
			// it (e.g. templates must not get templates/exec).
			targets := filterResources(resources, dp.resources)
			// Data-plane verbs and subresources are both invocation rights,
			// not reads; neither survives readOnly.
			if !readOnly && len(dp.verbs) > 0 && len(targets) > 0 {
				rules = append(rules, rbacv1.PolicyRule{APIGroups: []string{g}, Resources: targets, Verbs: dp.verbs})
			}
			if !readOnly && len(dp.subresources) > 0 && len(targets) > 0 {
				subs := make([]string, 0, len(targets)*len(dp.subresources))
				for _, r := range targets {
					for _, s := range dp.subresources {
						subs = append(subs, r+"/"+s)
					}
				}
				rules = append(rules, rbacv1.PolicyRule{APIGroups: []string{g}, Resources: subs, Verbs: []string{"create"}})
			}
		}
		if subs := actionSubs[g]; len(subs) > 0 {
			rules = append(rules, rbacv1.PolicyRule{APIGroups: []string{g}, Resources: sortedKeys(subs), Verbs: []string{"create"}})
		}
	}

	// Path lookup: tools resolve the workspace path from the LogicalCluster.
	rules = append(rules, rbacv1.PolicyRule{
		APIGroups: []string{"core.kcp.io"}, Resources: []string{"logicalclusters"}, Verbs: readVerbs,
	})
	// Provider data planes and action gates run a SelfSubjectAccessReview as
	// the caller; the review only ever answers for the token itself.
	rules = append(rules, rbacv1.PolicyRule{
		APIGroups: []string{"authorization.k8s.io"}, Resources: []string{"selfsubjectaccessreviews"}, Verbs: []string{"create"},
	})
	return rules
}

// filterResources keeps the bound resources an allow-list names, preserving
// order. An empty allow-list means "all of them".
func filterResources(bound, allowed []string) []string {
	if len(allowed) == 0 {
		return bound
	}
	out := make([]string, 0, len(bound))
	for _, r := range bound {
		if slices.Contains(allowed, r) {
			out = append(out, r)
		}
	}
	return out
}

func sortedKeys(m map[string]struct{}) []string {
	out := make([]string, 0, len(m))
	for k := range m {
		out = append(out, k)
	}
	sort.Strings(out)
	return out
}

// listBoundResources collects status.boundResources across the tenant's
// APIBindings. Bindings still being bound contribute nothing yet; the next
// reconcile picks them up.
func listBoundResources(ctx context.Context, kcp kcpclientset.Interface) ([]apisv1alpha2.BoundAPIResource, error) {
	list, err := kcp.ApisV1alpha2().APIBindings().List(ctx, metav1.ListOptions{})
	if err != nil {
		return nil, err
	}
	var out []apisv1alpha2.BoundAPIResource
	for i := range list.Items {
		out = append(out, list.Items[i].Status.BoundResources...)
	}
	return out, nil
}

// ensureMCPRBAC converges the generated ClusterRole and the ClusterRoleBinding
// pointing at it. RoleRef is immutable, so a binding left over from the
// cluster-admin era (or any other role) is deleted and recreated.
func ensureMCPRBAC(ctx context.Context, cs kubernetes.Interface, srv *railgridv1alpha1.MCPServer, owner metav1.OwnerReference, saName string, rules []rbacv1.PolicyRule) error {
	roleName := roleNamePrefix + srv.Name
	if rules == nil {
		rules = []rbacv1.PolicyRule{}
	}

	role := &rbacv1.ClusterRole{
		ObjectMeta: metav1.ObjectMeta{Name: roleName, OwnerReferences: []metav1.OwnerReference{owner}},
		Rules:      rules,
	}
	existing, err := cs.RbacV1().ClusterRoles().Get(ctx, roleName, metav1.GetOptions{})
	switch {
	case apierrors.IsNotFound(err):
		if _, err := cs.RbacV1().ClusterRoles().Create(ctx, role, metav1.CreateOptions{}); err != nil && !apierrors.IsAlreadyExists(err) {
			return fmt.Errorf("ensuring ClusterRole %s: %w", roleName, err)
		}
	case err != nil:
		return fmt.Errorf("getting ClusterRole %s: %w", roleName, err)
	default:
		// Ownership is reconciled alongside the rules: a role whose owner
		// reference drifted or was stripped outlives its MCPServer, because
		// nothing else ever deletes it.
		changed := false
		if !equality.Semantic.DeepEqual(existing.Rules, rules) {
			existing.Rules = rules
			changed = true
		}
		if !equality.Semantic.DeepEqual(existing.OwnerReferences, role.OwnerReferences) {
			existing.OwnerReferences = role.OwnerReferences
			changed = true
		}
		if changed {
			if _, err := cs.RbacV1().ClusterRoles().Update(ctx, existing, metav1.UpdateOptions{}); err != nil {
				return fmt.Errorf("updating ClusterRole %s: %w", roleName, err)
			}
		}
	}

	roleRef := rbacv1.RoleRef{APIGroup: rbacv1.GroupName, Kind: "ClusterRole", Name: roleName}
	crb := &rbacv1.ClusterRoleBinding{
		ObjectMeta: metav1.ObjectMeta{Name: saName, OwnerReferences: []metav1.OwnerReference{owner}},
		Subjects:   []rbacv1.Subject{{Kind: "ServiceAccount", Name: saName, Namespace: mcpIdentityNamespace}},
		RoleRef:    roleRef,
	}
	got, err := cs.RbacV1().ClusterRoleBindings().Get(ctx, saName, metav1.GetOptions{})
	switch {
	case apierrors.IsNotFound(err):
	case err != nil:
		return fmt.Errorf("getting ClusterRoleBinding %s: %w", saName, err)
	case got.RoleRef == roleRef:
		// RoleRef already points at the generated role, so the binding stays
		// and its mutable fields are converged in place. Subjects matter for
		// security — an extra subject left on the binding would hold the
		// MCPServer's permissions, and a wrong one silently breaks the token —
		// and the owner reference is what garbage-collects the binding.
		changed := false
		if !equality.Semantic.DeepEqual(got.Subjects, crb.Subjects) {
			got.Subjects = crb.Subjects
			changed = true
		}
		if !equality.Semantic.DeepEqual(got.OwnerReferences, crb.OwnerReferences) {
			got.OwnerReferences = crb.OwnerReferences
			changed = true
		}
		if changed {
			if _, err := cs.RbacV1().ClusterRoleBindings().Update(ctx, got, metav1.UpdateOptions{}); err != nil {
				return fmt.Errorf("updating ClusterRoleBinding %s: %w", saName, err)
			}
		}
		return nil
	default:
		// RoleRef is immutable, so a binding pointing anywhere else (the
		// cluster-admin era, say) can only be replaced.
		klog.FromContext(ctx).Info("replacing MCPServer ClusterRoleBinding with a different roleRef", "binding", saName, "from", got.RoleRef.Name, "to", roleName)
		if err := cs.RbacV1().ClusterRoleBindings().Delete(ctx, saName, metav1.DeleteOptions{}); err != nil && !apierrors.IsNotFound(err) {
			return fmt.Errorf("deleting stale ClusterRoleBinding %s: %w", saName, err)
		}
	}
	if _, err := cs.RbacV1().ClusterRoleBindings().Create(ctx, crb, metav1.CreateOptions{}); err != nil && !apierrors.IsAlreadyExists(err) {
		return fmt.Errorf("ensuring ClusterRoleBinding %s: %w", saName, err)
	}
	return nil
}

// actionGrantCacheTTL bounds how stale the cached catalog action grants may
// be. The platform catalog changes only when a provider ships, while every
// MCPServer re-derives its role on each reconcile plus every 60s tools
// refresh, so a short memo removes almost all of the listing without
// meaningfully delaying a new action: worst case a server picks it up one TTL
// later than it would have.
const actionGrantCacheTTL = 30 * time.Second

// cachedActionGrants memoizes an ActionGrantSource for ttl. The lock is held
// across the refresh on purpose: concurrent reconciles then collapse into one
// list of the system providers workspace instead of a stampede. Errors are not
// cached, so a transient failure retries on the next reconcile, and the
// returned slice is shared — callers must treat it as read-only.
func cachedActionGrants(src ActionGrantSource, ttl time.Duration) ActionGrantSource {
	if src == nil {
		return nil
	}
	var (
		mu      sync.Mutex
		grants  []ActionGrant
		expires time.Time
	)
	return func(ctx context.Context) ([]ActionGrant, error) {
		mu.Lock()
		defer mu.Unlock()
		if time.Now().Before(expires) {
			return grants, nil
		}
		out, err := src(ctx)
		if err != nil {
			return nil, err
		}
		grants, expires = out, time.Now().Add(ttl)
		return grants, nil
	}
}

var catalogEntryGVR = schema.GroupVersionResource{
	Group: providersv1alpha1.GroupName, Version: providersv1alpha1.Version, Resource: "catalogentries",
}

// catalogActionGrants returns an ActionGrantSource that reads the platform
// providers' CatalogEntries from the system providers workspace. Only platform
// providers federate into the aggregate (see the enumerator in server.go), so
// org-owned catalogs are not consulted.
// The dynamic client is built once and reused: it is stateless and its
// construction was repeated on every reconcile.
func catalogActionGrants(kcpConfig *rest.Config) ActionGrantSource {
	if kcpConfig == nil {
		return func(context.Context) ([]ActionGrant, error) { return nil, nil }
	}
	cfg := rest.CopyConfig(kcpConfig)
	cfg.Host = apiurl.KCPClusterURL(kcpConfig.Host, kcppaths.SystemProviders)
	dyn, dynErr := dynamic.NewForConfig(cfg)
	return func(ctx context.Context) ([]ActionGrant, error) {
		if dynErr != nil {
			return nil, fmt.Errorf("building system providers client: %w", dynErr)
		}
		list, err := dyn.Resource(catalogEntryGVR).List(ctx, metav1.ListOptions{})
		if err != nil {
			return nil, fmt.Errorf("listing CatalogEntries in %s: %w", kcppaths.SystemProviders, err)
		}
		var out []ActionGrant
		for i := range list.Items {
			var entry providersv1alpha1.CatalogEntry
			if err := runtime.DefaultUnstructuredConverter.FromUnstructured(list.Items[i].Object, &entry); err != nil {
				return nil, fmt.Errorf("decoding CatalogEntry %s: %w", list.Items[i].GetName(), err)
			}
			out = append(out, actionGrantsFromSpec(entry.Spec.Actions)...)
		}
		return out, nil
	}
}

// actionIDPattern is the documented action ID shape, "<name>/vN". It mirrors
// the kubebuilder Pattern on ProviderActionSpec.ID character for character;
// keep the two in step. The CRD rejects new objects that break it, but pattern
// validation never retro-validates objects that predate the marker, so the
// parser enforces the shape itself rather than trusting what is in storage.
var actionIDPattern = regexp.MustCompile(`^([a-z][a-z0-9_-]{0,62})/v[1-9][0-9]{0,7}$`)

// actionGrantsFromSpec maps catalog action declarations to RBAC coordinates.
// Action IDs are "<name>/vN"; the provider reviews the unversioned name as the
// subresource. An ID that does not match the documented shape is skipped
// rather than granted: a malformed catalog entry must not widen the role, and
// "has a slash" is not the documented shape.
func actionGrantsFromSpec(actions []providersv1alpha1.ProviderActionSpec) []ActionGrant {
	out := make([]ActionGrant, 0, len(actions))
	for _, a := range actions {
		m := actionIDPattern.FindStringSubmatch(strings.TrimSpace(a.ID))
		if m == nil {
			continue
		}
		name := m[1]
		if a.BoundResource.Resource == "" {
			continue
		}
		gv, err := schema.ParseGroupVersion(a.BoundResource.APIVersion)
		if err != nil {
			continue
		}
		out = append(out, ActionGrant{
			Group:    gv.Group,
			Resource: a.BoundResource.Resource,
			Name:     name,
			ReadOnly: a.ReadOnly,
		})
	}
	return out
}
