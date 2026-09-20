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
	"bytes"
	"context"
	"crypto/sha256"
	"encoding/hex"
	"errors"
	"io/fs"
	"mime"
	"net/http"
	"net/http/httputil"
	"net/url"
	"path"
	"strings"
	"time"

	"github.com/go-logr/logr"

	"github.com/railgrid/provider-sdk/dataplane"

	"github.com/railgrid/railgrid/pkg/apiurl"
	"github.com/railgrid/railgrid/pkg/hub/serviceaccounts"
)

// NewUIProxy returns an http.Handler serving /ui/providers/{name}/* by reverse
// proxying to the provider's spec.ui.url. The handler is mounted in the hub
// router WITHOUT http.StripPrefix; this proxy strips the /ui/providers/{name}
// segment itself so it can inject X-Railgrid-Base-Path before forwarding.
//
// Routing nuance: the portal SPA also lives at /ui/, with Vue Router serving
// /providers/{name} (and arbitrary sub-paths) as in-app routes that mount
// ProviderFrame. The proxy therefore only handles requests whose last path
// segment looks like a file (contains a "."): main.js, icon.svg, etc. Bare
// names like /ui/providers/quickstart or /ui/providers/quickstart/some-page
// are SPA routes — the proxy calls SetFallback() to dispatch them back to
// the portal SPA so a hard refresh preserves portal chrome.
//
// Unknown name → 404. Provider not Ready → 503. Provider without a UI → 404.
func NewUIProxy(reg *Registry, log logr.Logger) *ProviderProxy {
	return &ProviderProxy{
		reg:        reg,
		log:        log.WithName("ui-proxy"),
		pathPrefix: apiurl.PathPrefixProvidersUI,
		pick:       func(p Provider) *url.URL { return p.UIURL },
		setHeaders: func(req *http.Request, name, base string) {
			req.Header.Set("X-Railgrid-Base-Path", base)
		},
		// UI proxy reserves only asset-shaped paths; portal SPA routes fall
		// through (see SetFallback). Backend proxy keeps the default "always
		// proxy" behaviour by leaving fallbackForSPA false.
		fallbackForSPA: true,
	}
}

// TenantResolver resolves the caller's identity (User CR name) and
// tenant workspace path (e.g. root:railgrid:orgs:{orgUUID}) from an HTTP
// request's bearer token. Implementations typically wrap
// proxy.KCPProxy.IdentifyUser plus a User → Organization → WorkspacePath
// lookup; see pkg/hub/server.go for the canonical wiring. Returns an
// error when the caller can't be resolved — the proxy treats that as
// "no headers to inject" (best effort), it does NOT 401, so anonymous
// reads of provider /healthz keep working.
type TenantResolver interface {
	Resolve(r *http.Request) (user, tenantPath string, err error)
}

// TenantResolverFunc adapts a plain function to the TenantResolver
// interface. Lets callers compose the lookup inline without declaring a
// type.
type TenantResolverFunc func(r *http.Request) (string, string, error)

// Resolve satisfies TenantResolver.
func (f TenantResolverFunc) Resolve(r *http.Request) (string, string, error) {
	return f(r)
}

// NewBackendProxy returns an http.Handler serving /services/providers/{name}/*
// by reverse proxying to the provider's spec.backend.url. An org-owned
// provider always has the user's Authorization header replaced with a
// short-lived delegated token (see serveOverEdge and SetDelegatedTokenIssuer);
// a platform provider gets the same treatment when the DelegationPolicy
// selects it (SetDelegationPolicy) and the caller's bearer as-is otherwise.
// If a TenantResolver is
// installed via SetTenantResolver (and a cluster resolver via
// SetClusterResolver), the proxy resolves the caller's identity and injects
// X-Railgrid-User plus a kcp logical-cluster ID as both
// X-Railgrid-Tenant and X-Railgrid-Cluster, so the provider can scope work without
// re-parsing the bearer token. Which cluster depends on the route: a
// data-plane route names one in its path (/{root}/clusters/{id}/…) and that
// one is used, after the caller is authorized for it; any other route falls
// back to the workspace the resolver picks for the caller. Incoming
// X-Railgrid-User / X-Railgrid-Tenant /
// X-Railgrid-Cluster headers are ALWAYS stripped before the request is
// forwarded — a third-party caller can't forge identity by setting those
// headers directly.
func NewBackendProxy(reg *Registry, log logr.Logger) *ProviderProxy {
	p := &ProviderProxy{
		reg:                  reg,
		log:                  log.WithName("backend-proxy"),
		pathPrefix:           apiurl.PathPrefixProvidersProxy,
		pick:                 func(p Provider) *url.URL { return p.BackendURL },
		denyHubOnlyEndpoints: true,
	}
	// setHeaders runs after the Director's URL rewrite. Always strip
	// inbound X-Railgrid-* identity headers (defense in depth — a client
	// must not be able to spoof identity by setting them at the front
	// door); if a TenantResolver is installed, populate them from the
	// resolver. Reading p.tenantResolver via the closure is safe
	// because SetTenantResolver writes it before the first proxied
	// request lands in practice; if the wiring ever needs hot-swap,
	// switch the field to atomic.Pointer[TenantResolver].
	p.setHeaders = func(req *http.Request, name, _ string) {
		req.Header.Del("X-Railgrid-User")
		req.Header.Del("X-Railgrid-Tenant")
		req.Header.Del("X-Railgrid-Cluster")
		if p.tenantResolver == nil {
			// V(2) so tests / non-bootstrapper hubs don't spam, but
			// devs can flip on verbosity to see the dropped path.
			p.log.V(2).Info("no tenant resolver wired; forwarding without X-Railgrid-* headers", "provider", name)
			return
		}
		user, tenantPath, err := p.resolveCaller(req)
		if err != nil {
			// Anonymous (no bearer) is common on /healthz probes
			// and isn't worth screaming about — keep at V(2). Real
			// resolve failures (auth verify error, kcp lookup
			// failure) come through at default verbosity so a
			// TenantMissing error in a provider has a corresponding
			// hub log line a dev can grep for.
			if err.Error() == "anonymous caller" {
				p.log.V(2).Info("anonymous caller — forwarding without X-Railgrid-* headers", "provider", name, "path", req.URL.Path)
			} else {
				p.log.Info("tenant resolve failed — forwarding without X-Railgrid-* headers", "provider", name, "path", req.URL.Path, "err", err.Error())
			}
			// Still inject user when the resolver returned a name
			// but errored later in the chain. Lets the provider at
			// least attribute the call even when tenant scoping
			// isn't available.
			if user != "" {
				req.Header.Set("X-Railgrid-User", user)
			}
			return
		}
		if user != "" {
			req.Header.Set("X-Railgrid-User", user)
		}
		// A data-plane route names its own workspace: /{root}/clusters/{id}/…
		// The path is authoritative there (provider-sdk/dataplane.Gate refuses
		// a request whose cluster header disagrees with it), and ServeHTTP has
		// already authorized this caller for that cluster — so the addressed
		// cluster goes out, not the caller's default workspace.
		if clusterID, ok := pathClusterFrom(req.Context()); ok {
			req.Header.Set("X-Railgrid-Tenant", clusterID)
			req.Header.Set("X-Railgrid-Cluster", clusterID)
			return
		}
		if tenantPath == "" {
			p.log.Info("tenant resolved but tenantPath empty — forwarding without X-Railgrid-Tenant / X-Railgrid-Cluster", "provider", name, "user", user, "hint", "user may not have a personal Organization workspace bootstrapped yet")
			return
		}
		// Tenant identity between the hub and a provider is the workspace's
		// kcp logical-cluster ID, carried in BOTH X-Railgrid-Tenant and
		// X-Railgrid-Cluster (the MCP aggregate's federation client sends the
		// same pair). The workspace path resolved above stays hub-internal:
		// it is never forwarded, so a provider cannot come to depend on it.
		// Without an ID — no resolver wired, or the lookup failed — both
		// headers are omitted rather than degraded to the path; a provider
		// then reports the tenant as missing, which is the honest state.
		clusterID, err := p.resolveClusterID(req.Context(), tenantPath)
		if err != nil {
			p.log.Info("cluster-id resolve failed — forwarding without X-Railgrid-Tenant / X-Railgrid-Cluster", "provider", name, "tenant", tenantPath, "err", err.Error())
			return
		}
		req.Header.Set("X-Railgrid-Tenant", clusterID)
		req.Header.Set("X-Railgrid-Cluster", clusterID)
	}
	return p
}

// resolveClusterID maps a resolved tenant workspace path to the
// logical-cluster ID the provider is told about. It is an error, not a
// fallback, to have no resolver: the path must not stand in for the ID.
func (p *ProviderProxy) resolveClusterID(ctx context.Context, tenantPath string) (string, error) {
	if p.clusterResolver == nil {
		return "", errors.New("no cluster resolver wired")
	}
	clusterID, err := p.clusterResolver(ctx, tenantPath)
	if err != nil {
		return "", err
	}
	if clusterID == "" {
		return "", errors.New("resolver returned an empty cluster ID")
	}
	return clusterID, nil
}

// resolvedCallerKey memoizes one tenant resolution per request in its context.
// The backend proxy needs the caller's identity at three points on the
// org-provider path — scope resolution, delegated-token issuance, and header
// injection — and each resolution costs a token verify plus an apiserver
// round-trip, so it is done once in ServeHTTP and read back here.
type resolvedCallerKey struct{}

type resolvedCaller struct {
	user, tenantPath string
	err              error
}

// resolveCaller returns the caller's identity for req, from the request
// context when ServeHTTP already resolved it and from the tenant resolver
// otherwise. httputil.ReverseProxy clones the outbound request with the
// inbound context, so the Director sees the same memo.
func (p *ProviderProxy) resolveCaller(req *http.Request) (string, string, error) {
	if memo, ok := req.Context().Value(resolvedCallerKey{}).(resolvedCaller); ok {
		return memo.user, memo.tenantPath, memo.err
	}
	if p.tenantResolver == nil {
		return "", "", errors.New("tenant resolver unavailable")
	}
	return p.tenantResolver.Resolve(req)
}

// withResolvedCaller resolves the caller once and stores the outcome — error
// included, so a failed resolution is not retried per consumer — on r.
func (p *ProviderProxy) withResolvedCaller(r *http.Request) *http.Request {
	if p.tenantResolver == nil {
		return r
	}
	user, tenantPath, err := p.tenantResolver.Resolve(r)
	return r.WithContext(context.WithValue(r.Context(), resolvedCallerKey{}, resolvedCaller{user: user, tenantPath: tenantPath, err: err}))
}

// SetTenantResolver installs the resolver used to populate X-Railgrid-User on
// proxied requests and to find the caller's workspace, whose logical-cluster
// ID then goes out as X-Railgrid-Tenant / X-Railgrid-Cluster (see
// SetClusterResolver). Wire after the kcpProxy and railgridClient are built (see
// pkg/hub/server.go around the providerRegistry setup). Calling with nil
// disables injection but the inbound-header stripping below still runs.
func (p *ProviderProxy) SetTenantResolver(r TenantResolver) {
	p.tenantResolver = r
	// The resolver is already the component that knows the caller's
	// memberships, so it is also the natural authority on which clusters a
	// caller may address. Adopting it here keeps the hub's wiring to one call
	// and keeps the two answers consistent; an explicit SetClusterAuthorizer
	// still wins.
	if a, ok := r.(ClusterAuthorizer); ok && p.clusterAuth == nil {
		p.clusterAuth = a
	}
}

// ClusterAuthorizer answers the question the backend proxy has to settle
// before it tells a provider which workspace a data-plane request is for: may
// this caller address this logical cluster? It is the same membership question
// the hub's kcp proxy answers for /clusters/{id} (pkg/server/proxy), asked of
// the same implementation, so the set of workspaces a caller can reach with
// kubectl and the set they can reach through a provider cannot drift apart.
//
// Failure is closed: an implementation that cannot decide reports false.
type ClusterAuthorizer interface {
	AuthorizeCluster(ctx context.Context, user, clusterID string) bool
}

// ClusterAuthorizerFunc adapts a plain function to ClusterAuthorizer.
type ClusterAuthorizerFunc func(ctx context.Context, user, clusterID string) bool

// AuthorizeCluster satisfies ClusterAuthorizer.
func (f ClusterAuthorizerFunc) AuthorizeCluster(ctx context.Context, user, clusterID string) bool {
	return f(ctx, user, clusterID)
}

// SetClusterAuthorizer installs the membership check applied to the cluster a
// data-plane path names. Optional: SetTenantResolver already adopts a resolver
// that implements ClusterAuthorizer, which is how the hub wires it. Without
// one, a path-addressed cluster that is not the caller's own resolved tenant
// is left alone — the request keeps the pre-existing default-workspace
// headers rather than being refused, and the provider's own gates answer it.
func (p *ProviderProxy) SetClusterAuthorizer(a ClusterAuthorizer) {
	p.clusterAuth = a
}

// SetClusterResolver installs the resolver mapping a tenant workspace path to
// its kcp logical-cluster ID, injected as both X-Railgrid-Tenant and
// X-Railgrid-Cluster on backend-proxied requests. Wire alongside
// SetTenantResolver; without it neither tenant header is sent (the workspace
// path is never used in their place) and any inbound value is still stripped.
func (p *ProviderProxy) SetClusterResolver(f func(ctx context.Context, tenantPath string) (string, error)) {
	p.clusterResolver = f
}

// ProviderProxy is the shared implementation backing both proxies. Exported
// so the server can call SetFallback on the UI proxy after the portal SPA
// handler is built (the two are constructed at different points in Server.Run).
type ProviderProxy struct {
	reg        *Registry
	log        logr.Logger
	pathPrefix string // "/ui/providers" or "/services/providers"
	pick       func(Provider) *url.URL
	setHeaders func(req *http.Request, name, base string)

	// fallbackForSPA, when true, makes ServeHTTP route requests whose path
	// doesn't look like a static asset (no "." in the last segment) to the
	// fallback handler instead of proxying them. Set by NewUIProxy so that
	// /ui/providers/{name} and /ui/providers/{name}/some-route reach the
	// Vue SPA on hard refresh.
	fallbackForSPA bool
	// fallback is invoked for portal-SPA-shaped paths when fallbackForSPA
	// is true. Nil until SetFallback is called; while nil, those paths 404.
	fallback http.Handler

	// tenantResolver, when set, populates X-Railgrid-User and finds the
	// caller's workspace on backend-proxied requests. Used only by the
	// backend proxy; the UI proxy serves static assets and has no use for
	// caller identity. See SetTenantResolver.
	tenantResolver TenantResolver

	// clusterResolver maps the resolved tenant workspace path to its kcp
	// logical-cluster ID, injected as X-Railgrid-Tenant and X-Railgrid-Cluster.
	// The ID is the tenant's identity towards providers: it is what the
	// hub's kcp proxy at /clusters/{id} authorizes by (workspace paths are
	// rejected there), and what every provider keys its tenant scope on.
	// See SetClusterResolver.
	clusterResolver func(ctx context.Context, tenantPath string) (string, error)

	// clusterAuth authorizes the caller for the cluster a data-plane path
	// names, before that cluster is injected as the tenant headers. Nil
	// leaves such a path on the default-workspace resolution (see
	// SetClusterAuthorizer).
	clusterAuth ClusterAuthorizer

	// delegatedIssuer mints the token that replaces the caller's bearer on
	// requests to org-owned providers, and to platform providers when
	// delegation selects them. Nil means those paths fail closed: the hub
	// never forwards a user's hub token where a delegated one was required.
	// See SetDelegatedTokenIssuer, serveOverEdge, and delegatedAuthorization.
	delegatedIssuer DelegatedTokenIssuer

	// delegation decides which platform providers have the caller's bearer
	// swapped for a delegated token. Zero value is DelegationOff. See
	// SetDelegationPolicy.
	delegation DelegationPolicy

	// uiGrantKeys opens the grants that let the UI proxy serve an org-owned
	// provider's bundle over its edge (ui_grant.go). Only the UI proxy sets
	// it; nil means grant-bearing requests are refused.
	uiGrantKeys serviceaccounts.ProofKeySource

	// denyHubOnlyEndpoints reserves the hub-only path prefixes on a
	// provider's backend origin. Provider action routes (/actions/*) are a
	// public data-plane surface and ride this proxy like any other verb —
	// authorization is delegated to the provider's caller-scoped SSAR gates.
	// The attestation endpoint (/workload-identities/*), by contrast, is a
	// hub→provider internal call: it must never be reachable with a caller's
	// bearer through /services/providers/{name}, where it would act as a
	// TokenReview oracle against the provider's runtime cluster.
	denyHubOnlyEndpoints bool
}

// SetFallback installs the portal SPA handler invoked for non-asset paths
// under /ui/providers/{name}. See NewUIProxy for the rationale.
func (p *ProviderProxy) SetFallback(h http.Handler) {
	p.fallback = h
}

func (p *ProviderProxy) ServeHTTP(w http.ResponseWriter, r *http.Request) {
	name, rest, ok := splitProviderPath(r.URL.Path, p.pathPrefix)
	if !ok {
		// In UI-proxy mode, /ui/providers/ (trailing slash, no provider
		// name) is a portal SPA route — the catalog page — not an error.
		// Fall through to the SPA fallback when one is wired up. Backend
		// proxy mode keeps the strict 404 since /services/providers/ has
		// no SPA meaning.
		if p.fallbackForSPA && p.fallback != nil {
			p.fallback.ServeHTTP(w, r)
			return
		}
		http.NotFound(w, r)
		return
	}

	if p.denyHubOnlyEndpoints && isHubOnlyProviderPath(rest) {
		http.NotFound(w, r)
		return
	}

	// UI-proxy mode: portal SPA owns any path that doesn't look like a
	// static asset (no "." in the last segment). Without this fallback, a
	// browser refresh of /ui/providers/quickstart/anything would serve the
	// provider's raw HTML and the portal chrome would be lost.
	if p.fallbackForSPA && !isAssetPath(rest) {
		if p.fallback != nil {
			p.fallback.ServeHTTP(w, r)
			return
		}
		http.NotFound(w, r)
		return
	}

	// Resolve in the caller's Org first, so an Org running its own copy of a
	// provider reaches THAT copy. Platform-only resolution here was not a
	// missing feature but a wrong answer: it silently served the platform
	// provider to a tenant who had deliberately replaced it.
	//
	// The UI proxy cannot resolve by caller: a <script src> carries no
	// bearer. An org-owned bundle is instead addressed by a grant the portal
	// obtained while authenticated (ui_grant.go), which names the org; a
	// request without one is platform-scoped, as before.
	//
	// Resolve the caller once here; resolveProvider, the delegated-token
	// path, and setHeaders all read the memo (see resolveCaller).
	if p.fallbackForSPA {
		if grant := r.URL.Query().Get(UIGrantQueryParam); grant != "" {
			p.serveOrgUIAsset(w, r, name, rest, grant)
			return
		}
	} else {
		r = p.withResolvedCaller(r)
		var allowed bool
		if r, allowed = p.authorizePathCluster(w, r, name, rest); !allowed {
			return
		}
	}
	prov, found := p.resolveProvider(r, name)
	if !found {
		http.Error(w, "provider not found: "+name, http.StatusNotFound)
		return
	}
	if !prov.Ready() {
		http.Error(w, "provider not ready: "+name, http.StatusServiceUnavailable)
		return
	}

	// An org-owned provider runs in the tenant's own cluster, so its backend is
	// reached over the edge tunnel. Do this before pick(): BackendURL for such
	// a provider is an address inside that cluster, and dialling it from here
	// would either fail or — worse, if it happened to resolve — reach something
	// else entirely.
	if prov.OrgUUID != "" {
		p.serveOverEdge(w, r, prov, rest)
		return
	}

	// First-party providers ship their pre-built micro-frontend embedded
	// into the hub binary; serve those assets directly from the in-memory
	// FS rather than reverse-proxying anywhere. Only applies to the UI
	// proxy (fallbackForSPA implies p is the UI proxy); the backend proxy
	// keeps its existing UIURL/BackendURL semantics.
	if p.fallbackForSPA && prov.LocalUIAssets != nil {
		serveLocalAsset(w, r, prov.LocalUIAssets, rest, p.log)
		return
	}

	target := p.pick(prov)
	if target == nil {
		http.Error(w, "provider has no endpoint for this route: "+name, http.StatusNotFound)
		return
	}

	// A platform provider is dialled directly, and historically received the
	// caller's own bearer. Under a delegating policy it gets the same
	// workspace-scoped token an org-owned provider does; the decision to
	// substitute is made here, before the proxy is built, so every failure
	// refuses the request rather than falling back to the bearer. The UI
	// proxy never enters this branch: it serves assets, and its requests
	// carry no credential to protect.
	substitute := !p.fallbackForSPA && p.delegation.DelegatesPlatform(prov.Name)
	delegated := ""
	if substitute {
		var ok bool
		if delegated, ok = p.delegatedAuthorization(w, r, prov); !ok {
			return
		}
	}

	basePath := p.pathPrefix + "/" + name

	rp := &httputil.ReverseProxy{
		// Flush every write immediately (no response buffering). Required for
		// provider responses that stream: log-follow, and — once edge
		// connectivity moves out-of-process behind this proxy — the reverse
		// tunnel's chunked pickup streams. Harmless for plain JSON/asset
		// responses. WebSocket/SPDY 101 upgrades are handled separately by
		// ReverseProxy and don't depend on this. Edge-agnostic: the proxy
		// stays a generic forwarder.
		FlushInterval: -1,
		Director: func(req *http.Request) {
			req.URL.Scheme = target.Scheme
			req.URL.Host = target.Host
			// Forward only the path AFTER /{prefix}/{name}. The target URL's
			// own path (typically empty for a Service URL) is preserved as a
			// base; we append the remaining request path.
			req.URL.Path = singleJoiningSlash(target.Path, rest)
			req.URL.RawPath = "" // let net/url re-encode from Path
			req.Host = target.Host
			p.setHeaders(req, name, basePath)
			if substitute {
				// Same boundary as serveOverEdge: the caller's hub token
				// stops here. The provider receives the delegated token,
				// or nothing for an anonymous probe.
				setDelegatedAuthorization(req.Header, delegated)
			}
		},
		ErrorHandler: func(w http.ResponseWriter, r *http.Request, err error) {
			p.log.Error(err, "upstream error", "provider", name, "target", target.String())
			http.Error(w, "provider upstream error", http.StatusBadGateway)
		},
	}
	rp.ServeHTTP(w, r)
}

// pathClusterKey carries the logical cluster a data-plane route names, from
// ServeHTTP (which authorized the caller for it) to the Director (which sends
// it). It is set only after authorization, so its presence in a request
// context IS the permission to inject it.
type pathClusterKey struct{}

func withPathCluster(r *http.Request, clusterID string) *http.Request {
	return r.WithContext(context.WithValue(r.Context(), pathClusterKey{}, clusterID))
}

func pathClusterFrom(ctx context.Context) (string, bool) {
	clusterID, ok := ctx.Value(pathClusterKey{}).(string)
	return clusterID, ok && clusterID != ""
}

// pathClusterID reports the logical-cluster ID a provider path addresses, for
// the data-plane routes that name one:
//
//	/{root}/clusters/{clusterID}/…
//
// It matches the ADDRESSING PREFIX of provider-sdk/dataplane.ParsePath rather
// than the full grammar. The prefix is the part the hub and the provider must
// agree on — dataplane.Gate refuses a request whose X-Railgrid-Cluster
// disagrees with the path it was sent to — while everything after it is the
// provider's own business, and includes dialects ParsePath deliberately
// refuses (the edges provider's .../clusters/{id}/apis/... form, which carries
// kubectl through the tunnel). Matching only the prefix keeps those on the
// same footing instead of leaving them with a header that contradicts them.
//
// Anything else — MCP, OAuth callbacks, webhooks, /healthz — is not a
// data-plane route and comes back false, so those keep the caller's
// default-workspace resolution.
func pathClusterID(rest string) (string, bool) {
	// Cleaned first, like isHubOnlyProviderPath: a provider's own mux cleans
	// the path before it parses it, so ".." and "//" must not let the prefix
	// this reads and the prefix the provider reads come apart.
	clean := path.Clean("/" + strings.TrimPrefix(rest, "/"))
	root, after, ok := strings.Cut(strings.TrimPrefix(clean, "/"), "/")
	if !ok || root == "" {
		return "", false
	}
	after, ok = strings.CutPrefix(after, "clusters/")
	if !ok {
		return "", false
	}
	clusterID, _, _ := strings.Cut(after, "/")
	if !dataplane.IsClusterID(clusterID) {
		// A workspace path (it contains ":") or a malformed segment. The hub
		// proxy will not serve those either; leave the route alone.
		return "", false
	}
	return clusterID, true
}

// authorizePathCluster settles which workspace a request is for when its path
// names one, and refuses the request when the caller may not address it.
//
// The path wins over everything else on a data-plane route — over the
// caller's default workspace, and over an X-Railgrid-Org/Workspace selection
// that says something different — because the provider at the far end reads
// the path, and a header that disagrees is a 400 (dataplane.ErrClusterMismatch)
// rather than a quietly different answer. Winning is not the same as being
// trusted, so the caller is authorized for that cluster here, with the
// membership check the hub's kcp proxy applies to /clusters/{id}.
//
// Returns the request to continue with (carrying the authorized cluster) and
// whether to proceed; when it returns false the response has been written.
func (p *ProviderProxy) authorizePathCluster(w http.ResponseWriter, r *http.Request, name, rest string) (*http.Request, bool) {
	clusterID, ok := pathClusterID(rest)
	if !ok {
		return r, true
	}
	user, tenantPath, err := p.resolveCaller(r)
	if err != nil || user == "" {
		// Anonymous probes and callers the resolver cannot name keep today's
		// behaviour exactly: no identity headers at all, and the provider's
		// own gates decide. There is nothing to authorize and nothing to
		// inject.
		return r, true
	}
	// The caller's own resolved tenant IS the addressed cluster: they were
	// authorized for it when it was resolved (workload tokens are verified
	// against it; a header selection is membership-checked by the resolver),
	// so no second lookup is needed. This is also the path a workload
	// ServiceAccount takes, which has no UserMembershipIndex to check.
	if p.callerClusterMatches(r.Context(), tenantPath, clusterID) {
		return withPathCluster(r, clusterID), true
	}
	if p.clusterAuth == nil {
		p.log.V(2).Info("no cluster authorizer wired; leaving a path-addressed cluster on default-workspace resolution",
			"provider", name, "cluster", clusterID, "path", r.URL.Path)
		return r, true
	}
	if !p.clusterAuth.AuthorizeCluster(r.Context(), user, clusterID) {
		p.log.Info("refusing provider request: caller is not a member of the addressed workspace",
			"provider", name, "user", user, "cluster", clusterID, "path", r.URL.Path)
		http.Error(w, "caller is not a member of workspace: "+clusterID, http.StatusForbidden)
		return r, false
	}
	return withPathCluster(r, clusterID), true
}

// callerClusterMatches reports whether the caller's resolved tenant workspace
// is the cluster the path names. False whenever that cannot be established —
// no resolver, no tenant, a lookup failure — which sends the decision to the
// membership check rather than granting on a missing answer.
func (p *ProviderProxy) callerClusterMatches(ctx context.Context, tenantPath, clusterID string) bool {
	if tenantPath == "" || p.clusterResolver == nil {
		return false
	}
	resolved, err := p.clusterResolver(ctx, tenantPath)
	return err == nil && resolved != "" && resolved == clusterID
}

// hubOnlyProviderPrefixes are backend paths only the hub itself may dial.
// Matching is case-insensitive on a cleaned path so segment tricks
// (/x/../workload-identities, /Workload-Identities) cannot slip through.
var hubOnlyProviderPrefixes = []string{"/workload-identities"}

func isHubOnlyProviderPath(rest string) bool {
	clean := strings.ToLower(path.Clean("/" + strings.TrimPrefix(rest, "/")))
	for _, prefix := range hubOnlyProviderPrefixes {
		if clean == prefix || strings.HasPrefix(clean, prefix+"/") {
			return true
		}
	}
	return false
}

// localAssetCacheControl is what we serve on embedded provider assets.
// `Cache-Control: no-cache` (the old value) is silently ignored by
// Cloudflare for .js/.css under "Standard" caching — it falls back to
// its 4h default, which once cached a 404 across every browser session
// for hours after a fix shipped. An explicit short max-age is honored,
// and the ETag below makes the post-expiry revalidation a cheap 304.
const localAssetCacheControl = "public, max-age=60, must-revalidate"

// serveLocalAsset writes the file at rest from the provider's embedded
// LocalUIAssets FS to w. rest is the path after /ui/providers/{name} (so
// "/main.js", "/icon.svg", "/assets/foo-abc.js"). 404s when the file
// isn't present — the SPA-fallback branch upstream of this function
// already handled non-asset paths, so 404 here is the right behavior:
// the provider's bundle is missing an asset the portal asked for.
func serveLocalAsset(w http.ResponseWriter, r *http.Request, assets fs.FS, rest string, log logr.Logger) {
	name := strings.TrimPrefix(rest, "/")
	if name == "" {
		name = "index.html"
	}
	data, err := fs.ReadFile(assets, name)
	if err != nil {
		if !errors.Is(err, fs.ErrNotExist) {
			log.Error(err, "open local asset", "name", name)
		}
		http.NotFound(w, nil)
		return
	}

	ct := mime.TypeByExtension(path.Ext(name))
	if ct == "" {
		ct = "application/octet-stream"
	}
	sum := sha256.Sum256(data)
	etag := `"` + hex.EncodeToString(sum[:16]) + `"`

	w.Header().Set("Content-Type", ct)
	w.Header().Set("Cache-Control", localAssetCacheControl)
	w.Header().Set("ETag", etag)
	// ServeContent handles If-None-Match -> 304 and Content-Length for us.
	// Zero ModTime skips Last-Modified so ETag alone drives revalidation.
	http.ServeContent(w, r, name, time.Time{}, bytes.NewReader(data))
}

// splitProviderPath parses "/ui/providers/foo/bar" given prefix
// "/ui/providers" into name="foo", rest="/bar". A bare "/ui/providers/foo"
// (no trailing slash) returns name="foo", rest="/".
func splitProviderPath(reqPath, prefix string) (name, rest string, ok bool) {
	if !strings.HasPrefix(reqPath, prefix+"/") {
		return "", "", false
	}
	tail := strings.TrimPrefix(reqPath, prefix+"/")
	slash := strings.IndexByte(tail, '/')
	if slash < 0 {
		if tail == "" {
			return "", "", false
		}
		return tail, "/", true
	}
	name = tail[:slash]
	if name == "" {
		return "", "", false
	}
	return name, tail[slash:], true
}

// isAssetPath reports whether the request looks like a static asset the
// provider's UI server should serve (main.js, icon.svg, foo/bar.css) as
// opposed to a portal SPA route (/, /workloads, /foo/bar). The heuristic is
// "does the last path segment contain a dot?" — file extensions are the
// only durable signal we have without coupling to a per-provider asset
// manifest. Edge case: a SPA route ending in a dotted segment (e.g.
// /providers/foo/v1.2) would be misclassified, but that is unusual and
// providers can avoid it.
func isAssetPath(rest string) bool {
	last := strings.TrimPrefix(rest, "/")
	if i := strings.LastIndexByte(last, '/'); i >= 0 {
		last = last[i+1:]
	}
	return strings.Contains(last, ".")
}

// singleJoiningSlash mirrors net/http/httputil's unexported helper.
func singleJoiningSlash(a, b string) string {
	aslash := strings.HasSuffix(a, "/")
	bslash := strings.HasPrefix(b, "/")
	switch {
	case aslash && bslash:
		return a + b[1:]
	case !aslash && !bslash:
		return a + "/" + b
	}
	return a + b
}
