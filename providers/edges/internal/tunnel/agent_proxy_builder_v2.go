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

package tunnel

import (
	"context"
	"crypto/subtle"
	"encoding/base64"
	"fmt"
	"net/http"
	"net/url"
	"strings"
	"time"

	"github.com/function61/holepunch-server/pkg/wsconnadapter"
	"github.com/gorilla/websocket"
	metav1 "k8s.io/apimachinery/pkg/apis/meta/v1"
	"k8s.io/apimachinery/pkg/apis/meta/v1/unstructured"
	"k8s.io/apimachinery/pkg/runtime/schema"
	"k8s.io/client-go/dynamic"
	"k8s.io/client-go/tools/clientcmd"
	clientcmdapi "k8s.io/client-go/tools/clientcmd/api"

	edgesv1alpha1 "github.com/railgrid/provider-edges/apis/v1alpha1"
	utilhttp "github.com/railgrid/provider-edges/internal/wsutil"
	"github.com/railgrid/provider-sdk/revdial"
)

// edgeHeartbeatInterval is how often the hub stamps status.lastHeartbeatTime
// for a connected Edge using the revdial Dialer's LastPong timestamp.
const edgeHeartbeatInterval = 30 * time.Second

var secretGVR = schema.GroupVersionResource{Group: "", Version: "v1", Resource: "secrets"}

// buildEdgeAgentProxyHandler creates the HTTP handler for Edge agent tunnel
// registration (the agent-facing side of the new Edge workflow).
//
// Agents connect via WebSocket to:
//
//	/services/agent-proxy/{cluster}/apis/edges.railgrid.ai/v1alpha1/edges/{name}/proxy
//
// The hub upgrades the connection, wraps it in a revdial.Dialer, and stores
// it in p.edgeConnManager keyed by "edges/{cluster}/{name}". Subsequent
// user-facing requests (buildEdgesProxyHandler) look up that dialer to open
// back-connections to the agent.
//
// A separate /proxy endpoint (relative to the mount point) handles revdial
// pick-up connections initiated by the agent side.
func (p *Server) buildEdgeAgentProxyHandler() http.Handler {
	upgrader := websocket.Upgrader{
		CheckOrigin: func(r *http.Request) bool {
			return utilhttp.CheckSameOrAllowedOrigin(r, []url.URL{})
		},
	}

	mux := http.NewServeMux()

	// /proxy — revdial pick-up endpoint.
	// When the hub dials the agent (Dialer.Dial), it sends a "conn-ready"
	// message to the agent telling it to open a new WebSocket to this path.
	// The path passed to revdial.NewDialer below must match the absolute URL
	// path where this handler is mounted.
	//
	// Kept for single-replica mode and for dialers created before replica
	// routing was enabled; replica-addressed pickups go through /proxy/{id}.
	mux.Handle("/proxy", revdial.ConnHandler(upgrader))

	// /proxy/{replicaID} — replica-addressed pick-up. With replica routing
	// enabled, each dialer's advertised pickup path names the replica whose
	// process holds it (the revdial dialer map is process-global and the
	// dialer closes over the accepted socket), so a pickup the Service hands
	// to any OTHER replica is forwarded — as a WebSocket upgrade — to the
	// owner's internal listener. The agent treats the pickup path as opaque,
	// so this needs no agent changes and each agent keeps ONE control
	// connection no matter how many replicas run.
	mux.Handle("/proxy/", p.pickupRouter(revdial.ConnHandler(upgrader)))

	// / — initial agent connection handler.
	// Path (after mount-prefix stripping):
	//   /{cluster}/apis/edges.railgrid.ai/v1alpha1/edges/{name}/proxy
	mux.HandleFunc("/", func(w http.ResponseWriter, r *http.Request) {
		// Dispatch MCP requests before agent auth — MCP handler has its own auth.
		if strings.HasSuffix(strings.TrimRight(r.URL.Path, "/"), "/mcp") {
			cluster, resource, name, ok := p.parseEdgeMCPPath(r.URL.Path)
			if !ok {
				http.Error(w, "invalid path: expected /{cluster}/apis/edges.railgrid.ai/v1alpha1/{resource}/{name}/mcp", http.StatusBadRequest)
				return
			}
			p.buildMCPHandler(cluster, resource, name).ServeHTTP(w, r)
			return
		}

		// 1. Authenticate: require a valid bearer token.
		token := extractBearerToken(r)
		if token == "" {
			http.Error(w, "Unauthorized", http.StatusUnauthorized)
			return
		}

		// 2. Parse cluster, resource, and name from the URL path, and confirm the
		// resource matches the single kind this tunnel serves.
		cluster, resource, name, ok := p.parseEdgeAgentPath(r.URL.Path)
		if !ok {
			http.Error(w, "invalid path: expected /{cluster}/apis/"+p.group+"/"+p.version+"/{kubernetesclusters|linuxservers|macosservers}/{name}/proxy", http.StatusBadRequest)
			return
		}
		gvr, _, _ := p.gvrForResource(resource)

		// 3. Authentication: SA tokens go through kcp delegated authorization;
		//    bootstrap join tokens are accepted if they match edge.Status.JoinToken.
		//    The test-only static-token set only stands in for an agent credential
		//    when there is no kcp config at all (see Config.AllowStaticTokenBypass);
		//    with kcp configured every token is validated by kcp.
		isStaticToken := false
		if p.kcpConfig == nil {
			_, isStaticToken = p.staticTokens[token]
		}
		// authenticatedByJoinToken tracks whether the agent was authenticated via a
		// bootstrap join token. When true, the hub echoes the token back in the
		// X-Railgrid-Agent-Token upgrade response header so the agent can persist it
		// as its durable credential (token-exchange flow).
		authenticatedByJoinToken := false
		if !isStaticToken {
			if _, ok := parseServiceAccountToken(token); !ok {
				// Not a SA token — check if it's a valid bootstrap join token for this edge.
				if p.kcpConfig == nil {
					p.logger.Info("Rejected edge agent tunnel: invalid or missing SA token (no kcp configured)",
						"cluster", cluster, "name", name)
					http.Error(w, "Unauthorized", http.StatusUnauthorized)
					return
				}
				if err := p.authorizeByJoinToken(r.Context(), gvr, token, cluster, name); err != nil {
					p.logger.Info("Rejected edge agent tunnel: invalid join token",
						"cluster", cluster, "name", name, "err", err)
					http.Error(w, "Unauthorized", http.StatusUnauthorized)
					return
				}
				authenticatedByJoinToken = true
			} else {
				// SA token: this is a post-exchange reconnect. Validate it with a
				// delegated TokenReview + SubjectAccessReview against the consumer
				// workspace, served on the provider's APIExport virtual workspace
				// (kcp#4279 / kcp#4280). The agent SA authenticates natively where
				// it was minted, and the per-edge "proxy" grant the RBAC reconciler
				// created (ensureEdgeProxyGrant) authorizes it for THIS edge only.
				if err := p.authorizeByIssuedToken(r.Context(), gvr, cluster, name, token); err != nil {
					p.logger.Info("Rejected edge agent tunnel: SA token failed delegated authorization",
						"cluster", cluster, "name", name, "err", err)
					http.Error(w, "Unauthorized", http.StatusUnauthorized)
					return
				}
			}
		}

		// 4. Upgrade to WebSocket.
		// When the agent authenticated via a bootstrap join token, build a minimal
		// kubeconfig and include it in the upgrade response so the agent can save it
		// as its durable credential and reconnect without the join token on restart.
		var upgradeHeaders http.Header
		kubeconfigDelivered := false
		if authenticatedByJoinToken {
			kubeconfigHeader := p.buildAgentKubeconfigHeader(cluster, resource, name, token)
			upgradeHeaders = http.Header{}
			if kubeconfigHeader != "" {
				upgradeHeaders.Set("X-Railgrid-Agent-Kubeconfig", kubeconfigHeader)
				kubeconfigDelivered = true
			}
		}
		wsConn, err := upgrader.Upgrade(w, r, upgradeHeaders)
		if err != nil {
			p.logger.Error(err, "failed to upgrade WebSocket connection",
				"cluster", cluster, "name", name)
			return
		}

		// 5. Register the revdial tunnel.
		// The pick-up path must match the absolute path at which the /proxy
		// endpoint is reachable (i.e. the mount point + /proxy).
		key := edgeConnKey(resource, cluster, name)
		p.logger.Info("Edge agent connecting", "key", key)

		conn := wsconnadapter.New(wsConn)
		// With replica routing enabled the pickup path is replica-addressed so
		// pickups reach THIS process (the dialer closes over the socket) no
		// matter which replica the Service hands them to.
		pickupPath := p.agentPickupPath
		if p.replicaID != "" {
			pickupPath += "/" + p.replicaID
		}
		dialer := revdial.NewDialer(conn, pickupPath)
		p.edgeConnManager.Store(key, dialer)
		p.logger.Info("Edge agent tunnel established", "key", key)

		// The hub is authoritative for edge connectivity state regardless of how
		// the agent authenticated.  In the join-token flow the agent's
		// edge_reporter cannot reach the kcp API directly (the join token is not
		// a valid kcp credential).  In the kubeconfig flow (e.g. after an
		// in-cluster pod restart where the agent loads its saved kubeconfig from
		// a Secret) the edge_reporter may fail due to RBAC propagation lag.
		// Marking the edge Ready here on every tunnel open is safe and ensures
		// the hub view is always up-to-date.
		// SSH credentials are passed via headers for server-type edges.
		//
		// clearJoinToken: only clear the bootstrap join token if we successfully
		// delivered a kubeconfig to the agent. If the RBAC controller hasn't
		// provisioned the SA secret yet, the agent won't have a durable credential
		// and needs the join token to remain valid for the next reconnect attempt.
		clearJoinToken := !authenticatedByJoinToken || kubeconfigDelivered
		// MacOSServer is Service-only, so ignore SSH headers for it and preserve
		// the existing LinuxServer/KubernetesCluster handling.
		var sshCreds *sshCredsFromAgent
		if resource != macOSServerResource {
			sshCreds = extractSSHCredsFromHeaders(r)
		}
		hostname := agentHostnameFromHeader(r)
		go p.markEdgeConnected(context.Background(), gvr, cluster, name, sshCreds, hostname, clearJoinToken)

		// Stamp status.lastHeartbeatTime from the dialer's LastPong while the
		// tunnel is alive. revdial's keep-alive/pong loop already detects dead
		// tunnels within ~60s; LastPong gives us a positive liveness signal
		// that we can surface on the Edge resource so the LifecycleReconciler
		// (and CLI/UI) can spot a stalled connection.
		heartbeatCtx, cancelHeartbeat := context.WithCancel(context.Background())
		go p.runEdgeHeartbeatLoop(heartbeatCtx, gvr, cluster, name, dialer)

		// Block until the tunnel closes, then clean up the entry so stale
		// look-ups don't succeed.
		<-dialer.Done()
		cancelHeartbeat()

		// Identity-checked: the key is stable across reconnects, so if the agent
		// has already dialled a replacement tunnel it — not us — owns this entry
		// and the edge's status. Deleting unconditionally here erased a live
		// registration and left a healthy agent unroutable until it restarted.
		if !p.edgeConnManager.DeleteIf(key, dialer) {
			p.logger.Info("Superseded edge agent tunnel closed; a newer tunnel owns this edge", "key", key)
			return
		}
		p.logger.Info("Edge agent tunnel closed", "key", key)

		// Proactively mark the Edge as Disconnected in the hub.  Agents may die
		// without sending a clean disconnect heartbeat (e.g. SIGKILL), so the
		// hub must be the authoritative source for connectivity state.
		//
		// Re-check for a live tunnel first: a disconnect immediately followed by
		// a reconnect can otherwise land this write after the new tunnel's
		// markEdgeConnected and flap the edge to Disconnected. The
		// LifecycleReconciler would repair it on its next pass, but not before
		// the UI and CLI have shown a connected edge as down.
		go func() {
			if p.edgeConnManager.HasLocalConnection(key) {
				return
			}
			p.markEdgeDisconnected(context.Background(), gvr, cluster, name)
		}()
	})

	return mux
}

// parseEdgeAgentPath extracts {cluster} and {name} from the path that the
// handler sees after the "/services/agent-proxy" prefix has been stripped.
//
// Expected format:
//
//	/{cluster}/apis/edges.railgrid.ai/v1alpha1/edges/{name}/proxy
//
// parseEdgeAgentPath validates the path against this Server's configured kinds
// and returns (cluster, resource, name). resource is one of the served kinds'
// resources. Format:
//
//	/{cluster}/apis/{group}/{version}/{resource}/{name}/proxy
func (p *Server) parseEdgeAgentPath(path string) (cluster, resource, name string, ok bool) {
	parts := strings.SplitN(strings.TrimPrefix(path, "/"), "/", 8)
	if len(parts) < 7 {
		return "", "", "", false
	}
	if _, _, known := p.gvrForResource(parts[4]); !known {
		return "", "", "", false
	}
	if parts[1] != "apis" || parts[2] != p.group || parts[3] != p.version ||
		parts[6] != "proxy" {
		return "", "", "", false
	}
	return parts[0], parts[4], parts[5], true
}

// parseEdgeMCPPath extracts {cluster} and {name} for per-edge MCP requests.
// Format: /{cluster}/apis/{group}/{version}/{resource}/{name}/mcp
func (p *Server) parseEdgeMCPPath(path string) (cluster, resource, name string, ok bool) {
	parts := strings.SplitN(strings.TrimPrefix(path, "/"), "/", 8)
	if len(parts) < 7 {
		return "", "", "", false
	}
	if _, _, known := p.gvrForResource(parts[4]); !known {
		return "", "", "", false
	}
	if parts[1] != "apis" || parts[2] != p.group || parts[3] != p.version ||
		parts[6] != "mcp" {
		return "", "", "", false
	}
	return parts[0], parts[4], parts[5], true
}

// edgeConnKey returns the ConnManager key for an Edge tunnel.
// Format: "edges/{cluster}/{name}"
func edgeConnKey(resource, cluster, name string) string {
	return resource + "/" + cluster + "/" + name
}

// buildAgentKubeconfigHeader reads the ServiceAccount token from the kubeconfig
// secret created by the RBAC controller, builds a minimal kubeconfig with it,
// and returns the result base64-encoded for the X-Railgrid-Agent-Kubeconfig header.
// Returns an empty string if the SA token is not yet available.
func (p *Server) buildAgentKubeconfigHeader(cluster, resource, edgeName, _ string) string {
	if p.kcpConfig == nil {
		p.logger.Info("Cannot build agent kubeconfig: no kcp config")
		return ""
	}

	// Read the SA token from the kubeconfig secret created by the RBAC controller.
	// Route through the tenant workspace via the APIExport virtual workspace (the
	// provider SA cannot read tenant Secrets by re-rooting its own config).
	cfg, err := p.tenantConfigFor(context.Background(), cluster)
	if err != nil {
		p.logger.Error(err, "failed to resolve tenant config for SA token lookup", "cluster", cluster)
		return ""
	}
	dynClient, err := dynamic.NewForConfig(cfg)
	if err != nil {
		p.logger.Error(err, "failed to create dynamic client for SA token lookup")
		return ""
	}

	secretName := edgesv1alpha1.EdgeCredentialName(resource, edgeName) + "-kubeconfig"
	secret, err := dynClient.Resource(secretGVR).Namespace("railgrid-system").Get(
		context.Background(), secretName, metav1.GetOptions{})
	if err != nil {
		p.logger.Error(err, "failed to get kubeconfig secret for token-exchange",
			"secret", "railgrid-system/"+secretName)
		return ""
	}

	tokenB64, found, _ := unstructured.NestedString(secret.Object, "data", "token")
	if !found || tokenB64 == "" {
		p.logger.Info("SA token not yet populated in kubeconfig secret", "secret", secretName)
		return ""
	}
	tokenBytes, err := base64.StdEncoding.DecodeString(tokenB64)
	if err != nil {
		p.logger.Error(err, "failed to decode SA token from secret", "secret", secretName)
		return ""
	}
	saToken := string(tokenBytes)

	hubURL := p.hubExternalURL
	if hubURL == "" {
		hubURL = "https://localhost:9443"
	}
	kubecfg := buildAgentKubeconfig(hubURL, cluster, edgeName, saToken)
	data, err := clientcmd.Write(*kubecfg)
	if err != nil {
		p.logger.Error(err, "failed to serialise agent kubeconfig")
		return ""
	}
	return base64.StdEncoding.EncodeToString(data)
}

// buildAgentKubeconfig constructs a minimal kubeconfig that the agent can use
// to authenticate against the hub with a ServiceAccount token.
func buildAgentKubeconfig(hubURL, cluster, edgeName, token string) *clientcmdapi.Config {
	// Include the cluster path in the server URL so the agent reconnects to the
	// correct kcp logical cluster on restart (mirrors how existing agents work).
	serverURL := hubURL
	if cluster != "" && cluster != "default" {
		serverURL = strings.TrimRight(hubURL, "/") + "/clusters/" + cluster
	}
	contextName := "railgrid-" + edgeName
	return &clientcmdapi.Config{
		APIVersion: "v1",
		Kind:       "Config",
		Clusters: map[string]*clientcmdapi.Cluster{
			"railgrid-hub": {Server: serverURL, InsecureSkipTLSVerify: true},
		},
		AuthInfos: map[string]*clientcmdapi.AuthInfo{
			contextName: {Token: token},
		},
		Contexts: map[string]*clientcmdapi.Context{
			"default": {Cluster: "railgrid-hub", AuthInfo: contextName},
		},
		CurrentContext: "default",
	}
}

// authorizeByJoinToken looks up the Edge by cluster+name and performs a
// constant-time comparison of the provided token against edge.Status.JoinToken.
// Returns nil if the token is valid, or an error otherwise.
func (p *Server) authorizeByJoinToken(ctx context.Context, gvr schema.GroupVersionResource, token, cluster, name string) error {
	if p.kcpConfig == nil {
		return fmt.Errorf("kcp config not available")
	}
	if token == "" {
		return fmt.Errorf("empty token")
	}

	// Resolve the Edge in its tenant workspace via the APIExport virtual
	// workspace. Re-rooting the provider's own workspace-scoped SA config would
	// be rejected by kcp, which is what broke join-token registration in prod.
	cfg, err := p.tenantConfigFor(ctx, cluster)
	if err != nil {
		return fmt.Errorf("resolving tenant config: %w", err)
	}

	dynClient, err := dynamic.NewForConfig(cfg)
	if err != nil {
		return fmt.Errorf("creating dynamic client: %w", err)
	}

	u, err := dynClient.Resource(gvr).Get(ctx, name, metav1.GetOptions{})
	if err != nil {
		return fmt.Errorf("getting %s %s/%s: %w", gvr.Resource, cluster, name, err)
	}

	// status.joinToken is a shared ConnectionStatus field present on both kinds,
	// so read it directly from the unstructured object (kind-agnostic).
	joinToken, _, _ := unstructured.NestedString(u.Object, "status", "joinToken")
	if joinToken == "" {
		return fmt.Errorf("%s %s/%s has no join token set", gvr.Resource, cluster, name)
	}

	// Constant-time comparison to prevent timing attacks.
	if subtle.ConstantTimeCompare([]byte(token), []byte(joinToken)) != 1 {
		return fmt.Errorf("join token mismatch for %s %s/%s", gvr.Resource, cluster, name)
	}

	return nil
}

// authorizeByIssuedToken validates a reconnecting agent's ServiceAccount token
// with the standard delegated auth-delegator pattern against the consumer
// workspace, served on the provider's APIExport virtual workspace (kcp#4279 /
// kcp#4280): a TokenReview authenticates the token where it was minted, and a
// SubjectAccessReview authorizes the resolved identity for verb "proxy" on this
// edge object.
//
// The agent SA is provisioned in the consumer workspace by the RBAC reconciler
// (rbac_reconciler.go), which also grants it a per-edge "proxy" ClusterRole
// scoped via resourceNames to this edge alone (ensureEdgeProxyGrant). So the
// review proves both authenticity (a live consumer-workspace credential) and
// that it is the right edge (only this edge's SA is granted "proxy" on this
// name). Revocation is by edge deletion, which GCs the SA and its per-edge
// grant — the same model the earlier issued-token byte-compare had.
func (p *Server) authorizeByIssuedToken(ctx context.Context, gvr schema.GroupVersionResource, cluster, name, token string) error {
	if token == "" {
		return fmt.Errorf("empty token")
	}
	tenantCfg, err := p.tenantConfigFor(ctx, cluster)
	if err != nil {
		return fmt.Errorf("resolving tenant config: %w", err)
	}
	return authorize(ctx, tenantCfg, p.kcpConfig, token, cluster, "proxy", gvr.Group, gvr.Resource, name)
}

// AgentHostnameHeader is the WebSocket upgrade header on which the agent
// reports the hostname of the machine it runs on; the provider records it in
// status.hostname (edgeapi.ConnectionStatus.Hostname) on every tunnel open.
// Absent or empty leaves the recorded value untouched.
const AgentHostnameHeader = "X-Railgrid-Agent-Hostname"

// maxAgentHostnameLen bounds the agent-asserted value stored in status: a
// hostname is at most 253 characters (RFC 1035), and anything longer is not
// one.
const maxAgentHostnameLen = 253

// agentHostnameFromHeader reads the agent's reported hostname, or "" when it
// did not send one (older agents) or sent something that is not a hostname.
func agentHostnameFromHeader(r *http.Request) string {
	h := strings.TrimSpace(r.Header.Get(AgentHostnameHeader))
	if h == "" || len(h) > maxAgentHostnameLen {
		return ""
	}
	for _, c := range h {
		if c > 0x7e || c < 0x21 { // printable ASCII only, no whitespace
			return ""
		}
	}
	return h
}

// sshCredsFromAgent holds SSH credentials passed by the agent via WebSocket
// upgrade headers during join-token registration. HostKey is the agent's
// sshd host public key in authorized_keys format; it is independent of
// authentication credentials and is used by the hub for strict host-key
// verification.
type sshCredsFromAgent struct {
	User       string
	Password   string
	PrivateKey []byte
	HostKey    string
}

// extractSSHCredsFromHeaders reads SSH credential headers set by the agent.
func extractSSHCredsFromHeaders(r *http.Request) *sshCredsFromAgent {
	user := r.Header.Get("X-Railgrid-SSH-User")
	if user == "" {
		return nil
	}
	creds := &sshCredsFromAgent{User: user}
	if pw := r.Header.Get("X-Railgrid-SSH-Password"); pw != "" {
		decoded, err := base64.StdEncoding.DecodeString(pw)
		if err == nil {
			creds.Password = string(decoded)
		}
	}
	if pk := r.Header.Get("X-Railgrid-SSH-PrivateKey"); pk != "" {
		decoded, err := base64.StdEncoding.DecodeString(pk)
		if err == nil {
			creds.PrivateKey = decoded
		}
	}
	if hk := r.Header.Get("X-Railgrid-SSH-HostKey"); hk != "" {
		decoded, err := base64.StdEncoding.DecodeString(hk)
		if err == nil {
			creds.HostKey = string(decoded)
		}
	}
	return creds
}
