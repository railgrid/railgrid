// Copyright 2026 The Railgrid Authors.
//
// Licensed under the Apache License, Version 2.0 (the "License");
// you may not use this file except in compliance with the License.
// You may obtain a copy of the License at
//
//     http://www.apache.org/licenses/LICENSE-2.0

package mcpserver

import (
	"context"
	"encoding/json"
	"fmt"
	"net/http"
	"strings"

	"github.com/modelcontextprotocol/go-sdk/mcp"

	"github.com/railgrid/kuery/apis/query/v1alpha1"
	"github.com/railgrid/kuery/pkg/engine"

	"k8s.io/apimachinery/pkg/runtime"

	"github.com/railgrid/provider-kuery/index"
)

// The MCP tools do not talk to the engine. They go through
// queryapi.RunHandler.RunSavedView, which is the same gated executor the REST
// verb uses: the caller's bearer builds the client, a GET of the addressed
// SavedView proves they can see it, and a SelfSubjectAccessReview for create
// on savedviews/run proves they were granted the verb. Before this, these two
// tools read the tenant out of a header and queried the store directly, which
// meant an agent's grant on the kuery MCP endpoint was the only thing between
// it and the whole fleet.
//
// An agent that has not been given a view to run gets its caller's scratch
// view, created on first use with the caller's own credential — the same
// object the portal playground uses, so one grant covers both.

// queryInput is the kuery_query tool input: a raw kuery QuerySpec. Kept as
// a generic JSON object (not a typed mirror) so the tool tracks kuery's spec
// without a copy — the description carries the shape the model needs.
//
// It is a map, NOT json.RawMessage: the SDK's schema reflector renders a
// RawMessage ([]byte) as {"type":["null","array"],"items":{"type":"integer"}},
// so the aggregate's input validation rejected every real (object) spec and
// a byte array failed to unmarshal — the tool was unusable. A map reflects
// to {"type":"object"} and round-trips to the QuerySpec through json.
type queryInput struct {
	// SavedView names the SavedView to run the query as. Omitted, the caller's
	// own scratch view is used (created on first use). Either way the query
	// runs as a verb on a named object the caller must be granted.
	SavedView string         `json:"savedView,omitempty" jsonschema:"optional: the SavedView to run this query as. Omit to use your own scratch view. The name must be one you are granted the 'run' verb on."`
	Spec      map[string]any `json:"spec" jsonschema:"kuery QuerySpec as a JSON object. Key fields: filter.objects[] (groupKind{apiGroup,kind}, namespace, name, labels, categories), cluster.name (an EDGE name to restrict to one edge; omit for the whole fleet), limit, objects.object (sparse projection, e.g. {metadata:{name:true},spec:{replicas:true}}), objects.relations{} (owners, owners+, descendants, descendants+, references, selects, selected-by, linked, linked+, grouped), maxDepth."`
}

// querySpecFromInput converts the tool's generic spec object into kuery's
// typed QuerySpec. A nil/empty spec is a valid "everything in scope" query.
func querySpecFromInput(in map[string]any) (*v1alpha1.QuerySpec, error) {
	var spec v1alpha1.QuerySpec
	if len(in) == 0 {
		return &spec, nil
	}
	raw, err := json.Marshal(in)
	if err != nil {
		return nil, fmt.Errorf("invalid QuerySpec: %w", err)
	}
	if err := json.Unmarshal(raw, &spec); err != nil {
		return nil, fmt.Errorf("invalid QuerySpec: %w", err)
	}
	return &spec, nil
}

// queryOutput is the kuery_query result. It is returned as the handler's
// structured output, but the tool is registered with Out=any (see the handler
// signature in registerTools) so the SDK does NOT infer a JSON output schema
// from this type. v1alpha1.ObjectResult is self-recursive (its Relations field
// is map[string][]ObjectResult), and the SDK's schema reflector panics with
// "cycle detected for type v1alpha1.ObjectResult" on recursive types — which
// previously crashed every kuery /mcp request. With Out=any the schema is
// omitted while StructuredOutput and JSON content are still populated.
type queryOutput struct {
	Status *v1alpha1.QueryStatus `json:"status"`
}

// impactInput identifies one object to expand the declared blast radius of.
type impactInput struct {
	SavedView string `json:"savedView,omitempty" jsonschema:"optional: the SavedView to run this query as. Omit to use your own scratch view."`
	Edge      string `json:"edge,omitempty" jsonschema:"edge (cluster) name the object lives on; omit if unique fleet-wide"`
	Group     string `json:"group,omitempty" jsonschema:"API group, empty for core"`
	Kind      string `json:"kind" jsonschema:"object kind, e.g. ConfigMap"`
	Namespace string `json:"namespace,omitempty"`
	Name      string `json:"name" jsonschema:"object name"`
	MaxDepth  int32  `json:"maxDepth,omitempty" jsonschema:"transitive traversal depth (default 5, max 20)"`
}

// impactRef identifies one related object and the relation that links it to
// the queried object.
type impactRef struct {
	Edge      string `json:"edge,omitempty"`
	Group     string `json:"group,omitempty"`
	Kind      string `json:"kind"`
	Namespace string `json:"namespace,omitempty"`
	Name      string `json:"name"`
	Relation  string `json:"relation" jsonschema:"the relation that links this object to the target (owners, references, descendants, namespace, …)"`
}

// impactOutput splits the target's declared coupling into the two impact
// directions plus lateral peers, so the model can answer the right question
// from the right list.
type impactOutput struct {
	Object impactRef `json:"object" jsonschema:"the object whose impact was mapped"`
	Found  bool      `json:"found" jsonschema:"false if the object isn't in the store yet (sync may be catching up)"`
	// ImpactedBy: UPSTREAM dependencies — deleting/breaking any of these breaks
	// the target. Answers 'why is X broken?' / 'what does X need?'.
	ImpactedBy []impactRef `json:"impactedBy"`
	// Impacts: DOWNSTREAM blast radius — these break if the target is
	// changed/deleted. Answers 'is it safe to change/delete X?'.
	Impacts []impactRef `json:"impacts"`
	// Associated: lateral peers (kuery.io/relates-to links, shared group label).
	Associated []impactRef `json:"associated"`
	Summary    string      `json:"summary" jsonschema:"one-line human-readable count of each direction"`
}

// impactRelations is the relation set the impact tool expands: everything that
// DECLARES coupling to the object, in both impact directions. Events excluded
// by default — they are blacklisted from sync.
var impactRelations = []string{"descendants+", "references", "selects", "selected-by", "owners", "linked+", "grouped", "namespace", "namespaced"}

// edgeName strips the "{clusterID}/" prefix kuery records on a cluster key, so
// the model sees the bare edge name it knows.
func edgeName(cluster string) string { return index.EdgeOf(cluster) }

// refOf flattens one related ObjectResult (projected with cluster + kind +
// apiVersion + metadata) into an impactRef tagged with its relation.
func refOf(it v1alpha1.ObjectResult, rel string) impactRef {
	var o struct {
		APIVersion string `json:"apiVersion"`
		Kind       string `json:"kind"`
		Metadata   struct {
			Name      string `json:"name"`
			Namespace string `json:"namespace"`
		} `json:"metadata"`
	}
	if it.Object != nil {
		_ = json.Unmarshal(it.Object.Raw, &o)
	}
	group := ""
	if i := strings.Index(o.APIVersion, "/"); i >= 0 {
		group = o.APIVersion[:i]
	}
	return impactRef{
		Edge:      edgeName(it.Cluster),
		Group:     group,
		Kind:      o.Kind,
		Namespace: o.Metadata.Namespace,
		Name:      o.Metadata.Name,
		Relation:  engine.BaseRelation(rel),
	}
}

// classifyImpact buckets the anchor's relations by impact direction, using the
// engine's canonical RelationDirections as the source of truth.
func classifyImpact(anchor *v1alpha1.ObjectResult) (impactedBy, impacts, associated []impactRef) {
	for rel, items := range anchor.Relations {
		for i := range items {
			ref := refOf(items[i], rel)
			switch engine.DirectionOf(rel) {
			case engine.DirectionUpstream:
				impactedBy = append(impactedBy, ref)
			case engine.DirectionDownstream:
				impacts = append(impacts, ref)
			default:
				associated = append(associated, ref)
			}
		}
	}
	return
}

func registerTools(srv *mcp.Server, deps Deps, r *http.Request) {
	// Authorization failures surface per call, never at registration:
	// registration also serves tools/list, which must keep working for a
	// caller who cannot run anything — only a tools/call is gated.
	run := func(ctx context.Context, savedView string, spec *v1alpha1.QuerySpec) (*v1alpha1.QueryStatus, error) {
		if deps.Runner == nil {
			return nil, fmt.Errorf("kuery query surface is unavailable")
		}
		var query json.RawMessage
		if spec != nil {
			encoded, err := json.Marshal(spec)
			if err != nil {
				return nil, fmt.Errorf("encoding the query: %w", err)
			}
			query = encoded
		}
		return deps.Runner.RunSavedView(ctx, r, savedView, query)
	}

	safeRegister("kuery_query", func() {
		mcp.AddTool(srv, &mcp.Tool{
			Name:        "kuery_query",
			Title:       "Query objects across the edge fleet",
			Description: "Run one kuery query over every edge cluster connected to this workspace: filter by kind/namespace/labels, project sparse fields, and expand relations. Use instead of per-edge kubectl when the question spans edges.",
			Annotations: &mcp.ToolAnnotations{ReadOnlyHint: true, IdempotentHint: true},
			// Out is 'any', not queryOutput, on purpose — see the queryOutput doc
			// comment: a typed Out makes the SDK infer an output schema from the
			// recursive v1alpha1.ObjectResult and panic. 'any' keeps the structured
			// output without the schema.
		}, func(ctx context.Context, _ *mcp.CallToolRequest, in queryInput) (*mcp.CallToolResult, any, error) {
			spec, err := querySpecFromInput(in.Spec)
			if err != nil {
				return nil, nil, err
			}
			status, err := run(ctx, in.SavedView, spec)
			if err != nil {
				return nil, nil, fmt.Errorf("query failed: %w", err)
			}
			return nil, queryOutput{Status: status}, nil
		})
	})

	safeRegister("kuery_impact", func() {
		mcp.AddTool(srv, &mcp.Tool{
			Name:  "kuery_impact",
			Title: "Impact of one object (upstream deps + downstream blast radius)",
			Description: "Map one object's DECLARED coupling across the edge fleet, split by impact direction so you query the right list:\n" +
				"- impactedBy (UPSTREAM dependencies): deleting/breaking any of these breaks the target — its owners, the ConfigMaps/Secrets/ServiceAccounts it references, the Namespace it lives in, the selectors that target it. Use for 'why is X failing?' or 'what does X depend on?'.\n" +
				"- impacts (DOWNSTREAM blast radius): what breaks if you change/delete the target — objects it owns (transitively), Services/endpoints that select it, and (for a Namespace) every object inside it. Use for 'is it safe to change/delete X?'.\n" +
				"- associated: lateral peers (kuery.io/relates-to links, shared group label).\n" +
				"Coupling is DECLARED — ownerRefs, spec field references, label selectors, namespace membership — NOT runtime traffic or network policy, so a clean result is not proof nothing else depends on it at runtime. Each related object is returned with its kind/namespace/name/edge and the relation that linked it. Prefer this over per-edge kubectl for change-safety and root-cause questions that span edges.",
			Annotations: &mcp.ToolAnnotations{ReadOnlyHint: true, IdempotentHint: true},
		}, func(ctx context.Context, _ *mcp.CallToolRequest, in impactInput) (*mcp.CallToolResult, impactOutput, error) {
			out, err := runImpact(ctx, run, in)
			if err != nil {
				return nil, impactOutput{}, err
			}
			return nil, out, nil
		})
	})
}

// impactSpec builds the kuery query the impact tool runs: the one target
// object (by group/kind/namespace/name, optionally pinned to an edge) with
// every impact relation expanded one level and projected to identity only.
func impactSpec(in impactInput) *v1alpha1.QuerySpec {
	maxDepth := in.MaxDepth
	if maxDepth == 0 {
		maxDepth = 5
	}

	// Project just enough on related objects to identify them.
	relProj, _ := json.Marshal(map[string]any{
		"kind":       true,
		"apiVersion": true,
		"metadata":   map[string]any{"name": true, "namespace": true},
	})
	relObjects := &v1alpha1.ObjectsSpec{Cluster: true, Object: &runtime.RawExtension{Raw: relProj}}
	relations := map[string]v1alpha1.RelationSpec{}
	for _, rel := range impactRelations {
		rs := v1alpha1.RelationSpec{Objects: relObjects}
		if rel == "namespaced" {
			rs.Limit = 200 // a Namespace's membership can be large
		}
		relations[rel] = rs
	}
	spec := &v1alpha1.QuerySpec{
		MaxDepth: maxDepth,
		Filter: &v1alpha1.QueryFilter{
			Objects: []v1alpha1.ObjectFilter{{
				GroupKind: &v1alpha1.GroupKindFilter{APIGroup: in.Group, Kind: in.Kind},
				Namespace: in.Namespace,
				Name:      in.Name,
			}},
		},
		Objects: &v1alpha1.ObjectsSpec{
			ID:        true,
			Cluster:   true,
			Relations: relations,
		},
	}
	if in.Edge != "" {
		spec.Cluster = &v1alpha1.ClusterFilter{Name: in.Edge}
	}
	return spec
}

// queryRunner is the gated executor the tools run through — the same one the
// REST verb uses. Taken as a function so the impact tool is testable without a
// kcp API behind it.
type queryRunner func(ctx context.Context, savedView string, spec *v1alpha1.QuerySpec) (*v1alpha1.QueryStatus, error)

// runImpact executes the impact query for one object and buckets the result by
// impact direction. Tenant scoping is the runner's job, not this function's:
// it happens after the gates, from the caller's engaged-edge set.
func runImpact(ctx context.Context, run queryRunner, in impactInput) (impactOutput, error) {
	if in.Kind == "" || in.Name == "" {
		return impactOutput{}, fmt.Errorf("kind and name are required")
	}
	status, err := run(ctx, in.SavedView, impactSpec(in))
	if err != nil {
		return impactOutput{}, fmt.Errorf("impact query failed: %w", err)
	}

	target := impactRef{Edge: in.Edge, Group: in.Group, Kind: in.Kind, Namespace: in.Namespace, Name: in.Name}
	if len(status.Objects) == 0 {
		return impactOutput{
			Object:  target,
			Found:   false,
			Summary: fmt.Sprintf("%s/%s not found in the kuery store (sync may be catching up)", in.Kind, in.Name),
		}, nil
	}
	impactedBy, impacts, associated := classifyImpact(&status.Objects[0])
	return impactOutput{
		Object:     target,
		Found:      true,
		ImpactedBy: impactedBy,
		Impacts:    impacts,
		Associated: associated,
		Summary: fmt.Sprintf("%s %s/%s: %d upstream dependency(ies) that can break it, %d downstream object(s) in its blast radius, %d associated.",
			in.Kind, in.Namespace, in.Name, len(impactedBy), len(impacts), len(associated)),
	}, nil
}
