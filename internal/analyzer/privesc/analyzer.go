// Package privesc builds a privilege-escalation graph from the snapshot and
// searches for paths that reach sensitive sinks like cluster-admin, kube-system
// secrets, or node escape, turning each viable path into a Finding.
package privesc

import (
	"context"
	"encoding/json"
	"fmt"

	"github.com/0hardik1/kubesplaining/internal/models"
	"github.com/0hardik1/kubesplaining/internal/remediation"
)

// DefaultMaxDepth is the fallback BFS depth used when no explicit MaxDepth is configured.
const DefaultMaxDepth = 5

// Analyzer produces privilege-escalation path findings from a snapshot.
type Analyzer struct {
	MaxDepth int // BFS depth cap for path search; non-positive falls back to DefaultMaxDepth
}

// New returns a new privesc analyzer at the default depth.
func New() *Analyzer {
	return &Analyzer{MaxDepth: DefaultMaxDepth}
}

// Name returns the module identifier used by the engine.
func (a *Analyzer) Name() string {
	return "privesc"
}

// Analyze builds the escalation graph, finds paths to any sensitive sink, and emits one Finding per unique source→target pair.
//
// Each finding is enriched with a structured RemediationHint (Wave 1 slot #17):
// the per-path remediation generator picks the minimal binding edit that breaks
// the chain (drop the subject from the first hop's binding) and emits a unified
// diff + kubectl edit command. Synthetic-edge paths (pod escapes, token mints)
// fall back to an advisory comment-only diff.
func (a *Analyzer) Analyze(_ context.Context, snapshot models.Snapshot) ([]models.Finding, error) {
	depth := a.MaxDepth
	if depth <= 0 {
		depth = DefaultMaxDepth
	}

	graph := BuildGraph(snapshot)
	paths := FindPaths(graph, depth)

	findings := make([]models.Finding, 0, len(paths))
	seen := map[string]struct{}{}
	for _, path := range paths {
		finding := findingFromPath(path)
		if _, ok := seen[finding.ID]; ok {
			continue
		}
		finding.RemediationHint = remediation.ForPrivescPath(finding, snapshot)
		seen[finding.ID] = struct{}{}
		findings = append(findings, finding)
	}
	return findings, nil
}

// findingFromPath converts an EscalationPath into a Finding describing the chain, its target, and scoring.
func findingFromPath(path models.EscalationPath) models.Finding {
	target := path.Target
	severity, score, ruleID := targetScoring(target, path.Hops)
	// Confused-deputy chains get their own rule ID so operators can triage the
	// "a controller acted on my behalf" class separately from direct RBAC paths.
	// This is a technique overlay on the first hop, not a distinct sink: the chain
	// still terminates at whatever the controller itself reaches.
	if firstAction(path.Hops) == "operator_reconcile" {
		ruleID = "KUBE-CONFUSED-DEPUTY-001"
	}
	category := models.CategoryPrivilegeEscalation
	switch target {
	case models.TargetKubeSystemSecrets:
		category = models.CategoryDataExfiltration
	case models.TargetTrafficIntercept:
		// Redirecting Service traffic is a position on the wire, not a new identity:
		// what it yields is whatever the Service's clients send.
		category = models.CategoryLateralMovement
	}

	content := contentForTarget(path.Source, target, path.TargetNamespace, path.Hops)

	evidence, _ := json.Marshal(map[string]any{
		"target":           string(target),
		"target_namespace": path.TargetNamespace,
		"hop_count":        len(path.Hops),
		"techniques":       uniqueTechniques(path.Hops),
		"first_action":     firstAction(path.Hops),
		"chain_summary":    chainSummary(path.Hops),
	})

	id := fmt.Sprintf("%s:%s:%s", ruleID, path.Source.Key(), target)
	if path.TargetNamespace != "" {
		// Namespace-admin paths to different namespaces from the same source must be distinct
		// findings, so keep the namespace in the deterministic finding ID.
		id = fmt.Sprintf("%s:%s", id, path.TargetNamespace)
	}
	if target == models.TargetAWSIAMRole {
		// Every external AWS IAM role gets its own graph node (cloud_edges.go's
		// externalAWSIAMNodeID keys on the ARN), but Target and TargetNamespace above
		// are identical for all of them, so two different roles reached from the same
		// source would otherwise collide on this ID, exactly like two namespace-admin
		// sinks would without the suffix three lines above. Distinguish by the ARN
		// itself rather than the sanitized node ID: it is what an operator greps for,
		// and it needs no further plumbing, since buildPath already sets the terminal
		// hop's ToSubject to the external node's Subject (Name = the raw ARN; see
		// ensureExternalAWSIAMNode). Fall back to TargetID, the sanitized node ID, only
		// if a path somehow carries no hops, which should not happen since the source
		// itself is never a sink.
		suffix := path.TargetID
		if n := len(path.Hops); n > 0 && path.Hops[n-1].ToSubject.Name != "" {
			suffix = path.Hops[n-1].ToSubject.Name
		}
		id = fmt.Sprintf("%s:%s", id, suffix)
	}
	references := make([]string, 0, len(content.LearnMore))
	for _, ref := range content.LearnMore {
		references = append(references, ref.URL)
	}

	subject := path.Source
	tags := []string{"module:privesc", "target:" + string(target)}
	remediation := content.Remediation
	if len(path.AlternateHops) > 0 {
		// The recommended fix cuts hop 1's binding, and this path reaches the same
		// sink without it. Tagged so report, exclusions, and CI consumers can filter
		// on it without parsing the chain. SARIF surfaces this tag next to
		// Remediation prose in the same Properties object, so without naming the
		// evaluated cut here too, a reader can misattribute the tag to whichever
		// hop hopsRemediation happened to recommend instead. CSV carries no tag
		// column at all, so this sentence is the only signal a CSV reader has
		// that an alternate route exists in the first place.
		tags = append(tags, "privesc:survives-first-cut")
		remediation += alternateCutNote(path.Hops)
	}
	finding := models.Finding{
		ID:                      id,
		RuleID:                  ruleID,
		Severity:                severity,
		Score:                   score,
		Category:                category,
		Title:                   content.Title,
		Description:             content.Description,
		Subject:                 &subject,
		Scope:                   content.Scope,
		Impact:                  content.Impact,
		AttackScenario:          content.AttackScenario,
		Evidence:                evidence,
		Remediation:             remediation,
		RemediationSteps:        content.RemediationSteps,
		References:              references,
		LearnMore:               content.LearnMore,
		MitreTechniques:         content.MitreTechniques,
		EscalationPath:          path.Hops,
		AlternateEscalationPath: path.AlternateHops,
		Tags:                    tags,
	}
	if target == models.TargetNamespaceAdmin && path.TargetNamespace != "" {
		// Anchor the finding to the namespace it compromises so the report's resource column,
		// the dedupe key (RuleID + SubjectKey + ResourceKey), and SARIF physical-location all
		// surface which namespace is at risk.
		finding.Resource = &models.ResourceRef{Kind: "Namespace", Name: path.TargetNamespace, Namespace: path.TargetNamespace}
		finding.Namespace = path.TargetNamespace
	}
	return finding
}

// contentForTarget dispatches to the matching content builder based on the path's terminal sink.
func contentForTarget(source models.SubjectRef, target models.EscalationTarget, targetNamespace string, hops []models.EscalationHop) ruleContent {
	switch target {
	case models.TargetClusterAdmin:
		return contentClusterAdminPath(source, hops)
	case models.TargetNamespaceAdmin:
		return contentNamespaceAdminPath(source, targetNamespace, hops)
	case models.TargetNodeEscape:
		return contentNodeEscapePath(source, hops)
	case models.TargetKubeSystemSecrets:
		return contentKubeSystemSecretsPath(source, hops)
	case models.TargetSystemMasters:
		return contentSystemMastersPath(source, hops)
	case models.TargetAWSIAMRole:
		return contentAWSIAMRolePath(source, hops)
	case models.TargetTrafficIntercept:
		return contentTrafficInterceptPath(source, hops)
	case models.TargetNodeIdentity:
		return contentNodeIdentityPath(source, hops)
	default:
		return contentGenericPath(source, target, hops)
	}
}

// difficultyCost is the score penalty each hop contributes, by difficulty rating.
// See models.EscalationEdge.Difficulty for what each rating means.
var difficultyCost = map[string]float64{
	"easy":     0.15,
	"moderate": 0.4,
	"hard":     0.9,
}

// targetScoring returns the base severity, score, and rule ID for a target,
// attenuated by how hard the chain is to walk rather than by how long it is.
//
// Each hop costs according to its difficulty, so a five-hop chain of ordinary RBAC
// grants (0.75 total) outranks a two-hop chain that needs a race window (1.8). A
// chain is downgraded one severity bucket when it contains at least one hard hop,
// because that is the step an operator can most realistically bet against. Length
// still matters, but through the summed cost rather than as the primary signal.
//
// This replaced a flat "0.5 per hop, downgrade at 3+ hops" model, which ranked a
// long chain of trivial grants below a short chain needing attacker-controlled
// infrastructure. Scores stay in [1, 10] so even a deeply attenuated path is still
// reported rather than disappearing under the threshold.
func targetScoring(target models.EscalationTarget, hops []models.EscalationHop) (models.Severity, float64, string) {
	var base float64
	var severity models.Severity
	var ruleID string
	switch target {
	case models.TargetClusterAdmin:
		base, severity, ruleID = 9.8, models.SeverityCritical, "KUBE-PRIVESC-PATH-CLUSTER-ADMIN"
	case models.TargetNodeEscape:
		base, severity, ruleID = 9.4, models.SeverityCritical, "KUBE-PRIVESC-PATH-NODE-ESCAPE"
	case models.TargetKubeSystemSecrets:
		base, severity, ruleID = 8.6, models.SeverityHigh, "KUBE-PRIVESC-PATH-KUBE-SYSTEM-SECRETS"
	case models.TargetSystemMasters:
		base, severity, ruleID = 9.6, models.SeverityCritical, "KUBE-PRIVESC-PATH-SYSTEM-MASTERS"
	case models.TargetNamespaceAdmin:
		// Namespace-admin is a real privesc but bounded to a single namespace, so it scores
		// below cluster-admin but above the generic fallback.
		base, severity, ruleID = 7.6, models.SeverityHigh, "KUBE-PRIVESC-PATH-NAMESPACE-ADMIN"
	case models.TargetAWSIAMRole:
		// Cluster SA can reach an external AWS IAM role. Severity reflects that the
		// blast radius is the IAM role's policies, not the Kubernetes cluster itself,
		// but the role is still real cloud-account access so it sits at High / 8.0.
		base, severity, ruleID = 8.0, models.SeverityHigh, "KUBE-PRIVESC-PATH-AWS-IAM-ROLE"
	case models.TargetTrafficIntercept:
		// A position on the wire for one or more Services. The clients' bearer tokens
		// and request bodies are the prize, which is real but bounded by what those
		// clients send, so it sits with kube-system secrets rather than cluster-admin.
		base, severity, ruleID = 7.8, models.SeverityHigh, "KUBE-PRIVESC-PATH-TRAFFIC-INTERCEPT"
	case models.TargetNodeIdentity:
		// A node identity for any node name reaches the ServiceAccount tokens and
		// referenced Secrets of every pod in the cluster. Below node_escape because
		// it is API access through the Node authorizer, not code on the host.
		base, severity, ruleID = 8.4, models.SeverityHigh, "KUBE-PRIVESC-PATH-NODE-IDENTITY"
	default:
		base, severity, ruleID = 7.0, models.SeverityHigh, "KUBE-PRIVESC-PATH-GENERIC"
	}
	penalty := 0.0
	hasHardHop := false
	for _, hop := range hops {
		cost, ok := difficultyCost[hop.Difficulty]
		if !ok {
			cost = difficultyCost[difficultyModerate]
		}
		penalty += cost
		if hop.Difficulty == difficultyHard {
			hasHardHop = true
		}
	}

	score := base - penalty
	if score < 1 {
		score = 1
	}
	if score > 10 {
		score = 10
	}
	if hasHardHop {
		severity = downgrade(severity)
	}
	return severity, score, ruleID
}

// downgrade steps a severity down one bucket; used to soften long multi-hop chains.
func downgrade(s models.Severity) models.Severity {
	switch s {
	case models.SeverityCritical:
		return models.SeverityHigh
	case models.SeverityHigh:
		return models.SeverityMedium
	default:
		return s
	}
}

// targetLabel returns a human-readable label for the escalation target.
func targetLabel(target models.EscalationTarget) string {
	switch target {
	case models.TargetClusterAdmin:
		return "cluster-admin equivalent"
	case models.TargetNodeEscape:
		return "node escape"
	case models.TargetKubeSystemSecrets:
		return "kube-system secrets"
	case models.TargetSystemMasters:
		return "system:masters"
	case models.TargetNamespaceAdmin:
		return "namespace-admin"
	case models.TargetAWSIAMRole:
		return "AWS IAM role"
	case models.TargetTrafficIntercept:
		return "Service traffic interception"
	case models.TargetNodeIdentity:
		return "node identity"
	default:
		return string(target)
	}
}

// uniqueTechniques returns the deduplicated list of hop Actions along the path for evidence summaries.
func uniqueTechniques(hops []models.EscalationHop) []string {
	seen := map[string]struct{}{}
	var out []string
	for _, hop := range hops {
		if hop.Action == "" {
			continue
		}
		if _, ok := seen[hop.Action]; ok {
			continue
		}
		seen[hop.Action] = struct{}{}
		out = append(out, hop.Action)
	}
	return out
}

// firstAction returns the Action of the first hop or empty when there are none.
func firstAction(hops []models.EscalationHop) string {
	if len(hops) == 0 {
		return ""
	}
	return hops[0].Action
}

// chainSummary returns a numbered list of "Action [Permission]" strings for evidence output.
func chainSummary(hops []models.EscalationHop) []string {
	summary := make([]string, 0, len(hops))
	for _, hop := range hops {
		summary = append(summary, fmt.Sprintf("%d. %s [%s]", hop.Step, hop.Action, hop.Permission))
	}
	return summary
}
