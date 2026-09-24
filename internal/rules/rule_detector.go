package rules

import (
	"errors"
	"io/fs"

	"github.com/trustabl/trustabl/internal/analysis"
	"github.com/trustabl/trustabl/internal/analysis/detectors"
	"github.com/trustabl/trustabl/internal/models"
)

// ErrNoRulesInPack signals that the resolved, schema-compatible rule pack
// contains zero rules. The engine must never run rule-less — a clean report
// produced from no rules is worse than no report — so callers map this to a
// hard exit 2, the same outcome as no-pack / incompatible-pack.
var ErrNoRulesInPack = errors.New("rule pack contains no rules")

// ErrAllRulesIncompatible signals that the resolved pack contained rules but
// every one was dropped as forward-incompatible — each references a predicate
// this engine build does not understand (a rules repo wholly newer than the
// binary). Distinct from ErrNoRulesInPack (a genuinely empty/truncated pack):
// the remedy is to upgrade Trustabl, not to refresh the pack. Callers map it to
// a hard exit 2 with an upgrade hint.
var ErrAllRulesIncompatible = errors.New("all rules require a newer engine schema")

// languageGateOK reports whether a rule typed for ruleLang should run against a
// def whose language is defLang. An untyped rule (ruleLang == "") matches any
// language; otherwise it matches the same language OR any other member of the
// TypeScript/JavaScript family — JS-sourced defs are audited by the TypeScript
// rule packs because they share the grammar, discovery, and body facts (see
// models.IsTSOrJS). Used by the tool, agent, and repo language gates so all
// three stay consistent.
func languageGateOK(ruleLang, defLang models.Language) bool {
	if ruleLang == "" || ruleLang == defLang {
		return true
	}
	return models.IsTSOrJS(ruleLang) && models.IsTSOrJS(defLang)
}

// toolRuleDetector adapts a tool-scoped RuleDef into a ToolDetector.
type toolRuleDetector struct{ rule RuleDef }

func (d toolRuleDetector) RuleID() string                    { return d.rule.ID }
func (d toolRuleDetector) Category() models.DetectorCategory { return d.rule.Category }
func (d toolRuleDetector) Applies(t models.ToolDef) bool {
	if !languageGateOK(d.rule.Language, t.Language) {
		return false
	}
	for _, k := range d.rule.AppliesTo {
		if string(t.Kind) == k {
			return true
		}
	}
	return false
}
func (d toolRuleDetector) Detect(t models.ToolDef, pf analysis.ParsedFile, inv models.RepoInventory) []models.Finding {
	if !d.rule.Match.EvaluateTool(t, pf) {
		return nil
	}
	return []models.Finding{findingFromRule(d.rule, models.ScopeTool, t.FilePath, t.Line, t.EndLine, t.Name)}
}

// agentRuleDetector adapts an agent-scoped RuleDef into an AgentDetector.
type agentRuleDetector struct{ rule RuleDef }

func (d agentRuleDetector) RuleID() string                    { return d.rule.ID }
func (d agentRuleDetector) Category() models.DetectorCategory { return d.rule.Category }
func (d agentRuleDetector) Applies(a models.AgentDef) bool {
	if !languageGateOK(d.rule.Language, a.Language) {
		return false
	}
	for _, k := range d.rule.AppliesTo {
		if agentKindMatches(k, a) {
			return true
		}
	}
	return false
}
func (d agentRuleDetector) Detect(a models.AgentDef, inv models.RepoInventory) []models.Finding {
	if !d.rule.Match.EvaluateAgent(a, inv) {
		return nil
	}
	return []models.Finding{findingFromRule(d.rule, models.ScopeAgent, a.FilePath, a.Line, a.EndLine, a.Name)}
}

// repoRuleDetector adapts a repo-scoped RuleDef into a RepoDetector.
type repoRuleDetector struct{ rule RuleDef }

func (d repoRuleDetector) RuleID() string                    { return d.rule.ID }
func (d repoRuleDetector) Category() models.DetectorCategory { return d.rule.Category }
func (d repoRuleDetector) Applies(p models.RepoProfile, inv models.RepoInventory) bool {
	// Language gate at repo scope: a language-typed rule fires only when the
	// inventory observes that language. Matches the gate enforced by
	// toolRuleDetector and agentRuleDetector. Without this, a rule with
	// `language: python` would silently fire on a TS-only repo where the
	// rule's predicates have no Python code to evaluate against (e.g.
	// OAI-201's repo_uses_default_tracing trivially holds on a Python-free
	// repo since the tracing-config call never appears).
	if d.rule.Language != "" {
		var hasLang bool
		for _, l := range p.Languages {
			if languageGateOK(d.rule.Language, l) {
				hasLang = true
				break
			}
		}
		if !hasLang {
			return false
		}
	}
	for _, k := range d.rule.AppliesTo {
		// "openshell" is a risk-surface label, not an SDK — route it to
		// HasShellInvocations instead of looking it up in SDKsDetected.
		if k == "openshell" {
			if inv.HasShellInvocations {
				return true
			}
			continue
		}
		// The repo-scope applies_to tokens are category labels, which equal
		// their SDK enum string for every SDK EXCEPT Claude: the token is
		// `claude_sdk` while the enum is `claude_agent_sdk`. Bridge that one
		// mismatch so a Claude repo rule actually fires (it would otherwise
		// load but never match). See validAppliesToForScope (loader.go) and
		// LoadFor's pack-gate mapping for the two other places this bridge
		// is made.
		want := models.SDK(k)
		if k == "claude_sdk" {
			want = models.SDKClaudeAgentSDK
		}
		for _, sdk := range inv.SDKsDetected {
			if sdk == want {
				return true
			}
		}
	}
	return false
}
func (d repoRuleDetector) Detect(p models.RepoProfile, inv models.RepoInventory) []models.Finding {
	if !d.rule.Match.EvaluateRepo(p, inv) {
		return nil
	}
	return []models.Finding{findingFromRule(d.rule, models.ScopeRepo, "", 0, 0, "")}
}

func agentKindMatches(kind string, a models.AgentDef) bool {
	switch kind {
	case "openai_agent":
		return a.SDK == models.SDKOpenAIAgents && a.Class == "Agent"
	case "openai_sandbox_agent":
		return a.SDK == models.SDKOpenAIAgents && a.Class == "SandboxAgent"
	case "claude_agent_definition":
		return a.SDK == models.SDKClaudeAgentSDK && a.Class == "AgentDefinition"
	case "claude_query_main":
		return a.SDK == models.SDKClaudeAgentSDK && a.Class == "QueryMainAgent"
	case "adk_llm_agent":
		return a.SDK == models.SDKGoogleADK && a.Class == "LlmAgent"
	case "adk_sequential_agent":
		return a.SDK == models.SDKGoogleADK && a.Class == "SequentialAgent"
	case "adk_parallel_agent":
		return a.SDK == models.SDKGoogleADK && a.Class == "ParallelAgent"
	case "adk_loop_agent":
		return a.SDK == models.SDKGoogleADK && a.Class == "LoopAgent"
	case "adk_langgraph_agent":
		return a.SDK == models.SDKGoogleADK && a.Class == "LanggraphAgent"
	// LangChain / LangGraph. Class values are normalized canonical names
	// (language-agnostic): "ReactAgent" (create_react_agent / createReactAgent),
	// "CreateAgent" (create_agent / createAgent), "AgentExecutor", "StateGraph".
	// The a.Language field distinguishes the Python vs TypeScript shapes.
	case "langchain_agent":
		return a.SDK == models.SDKLangChain && (a.Class == "ReactAgent" || a.Class == "CreateAgent")
	case "langchain_agent_executor":
		return a.SDK == models.SDKLangChain && a.Class == "AgentExecutor"
	case "langchain_state_graph":
		return a.SDK == models.SDKLangChain && a.Class == "StateGraph"
	// CrewAI: the single Agent(...) constructor, SDK-stamped at discovery to
	// disambiguate from the identically-named OpenAI and ADK Agent classes.
	case "crewai_agent":
		return a.SDK == models.SDKCrewAI && a.Class == "Agent"
	// Pydantic AI: the lone Agent(...) constructor, normalized Class "PydanticAgent".
	case "pydantic_ai_agent":
		return a.SDK == models.SDKPydanticAI && a.Class == "PydanticAgent"
	// Vercel AI SDK: one token spans every call/class agent shape
	// (generateText / streamText / generateObject / streamObject / ToolLoopAgent);
	// the SDK stamp is the disambiguator, so no per-Class gate is needed.
	case "vercel_ai_agent":
		return a.SDK == models.SDKVercelAI
	// AutoGen / AG2: distinct tokens per class so a rule can target the executor
	// presets (UserProxy/ConversableAgent/CodeExecutorAgent) without firing on the
	// LLM-only AssistantAgent, and vice-versa.
	case "autogen_conversable_agent":
		return a.SDK == models.SDKAutoGen && a.Class == "ConversableAgent"
	case "autogen_user_proxy_agent":
		return a.SDK == models.SDKAutoGen && a.Class == "UserProxyAgent"
	case "autogen_assistant_agent":
		return a.SDK == models.SDKAutoGen && a.Class == "AssistantAgent"
	case "autogen_group_chat_manager":
		return a.SDK == models.SDKAutoGen && (a.Class == "GroupChatManager" || a.Class == "GroupChat")
	case "autogen_code_executor_agent":
		return a.SDK == models.SDKAutoGen && a.Class == "CodeExecutorAgent"
	}
	return false
}

// subagentRuleDetector adapts a subagent-scoped RuleDef into a SubagentDetector.
type subagentRuleDetector struct{ rule RuleDef }

func (d subagentRuleDetector) RuleID() string                    { return d.rule.ID }
func (d subagentRuleDetector) Category() models.DetectorCategory { return d.rule.Category }
func (d subagentRuleDetector) Applies(s models.SubagentDef) bool {
	// No language gate: SubagentDef has no Language (markdown frontmatter is
	// not Python/TS). Subagents are inherently Claude Code artifacts.
	for _, k := range d.rule.AppliesTo {
		if k == "claude_subagent" {
			return true
		}
	}
	return false
}
func (d subagentRuleDetector) Detect(s models.SubagentDef, inv models.RepoInventory) []models.Finding {
	if !d.rule.Match.EvaluateSubagent(s, inv) {
		return nil
	}
	// SubagentDef embeds Location: Line = the opening "---" of the frontmatter
	// (usually 1), EndLine = the closing "---". Attribute to the opening so
	// the user lands at the start of the declaration when jumping from a
	// finding.
	return []models.Finding{findingFromRule(d.rule, models.ScopeSubagent, s.FilePath, s.Line, s.EndLine, s.Name)}
}

// skillRuleDetector adapts a skill-scoped RuleDef into a SkillDetector.
type skillRuleDetector struct{ rule RuleDef }

func (d skillRuleDetector) RuleID() string                    { return d.rule.ID }
func (d skillRuleDetector) Category() models.DetectorCategory { return d.rule.Category }
func (d skillRuleDetector) Applies(s models.SkillDef) bool {
	// No language gate: SkillDef has no Language (SKILL.md frontmatter is not
	// Python/TS). Skills are inherently Claude Code artifacts.
	for _, k := range d.rule.AppliesTo {
		if k == "claude_skill" {
			return true
		}
	}
	return false
}
func (d skillRuleDetector) Detect(s models.SkillDef, inv models.RepoInventory) []models.Finding {
	if !d.rule.Match.EvaluateSkill(s, inv) {
		return nil
	}
	// SkillDef embeds Location: Line = the opening "---" of the frontmatter.
	// Attribute to the opening so a finding jumps to the start of the skill.
	return []models.Finding{findingFromRule(d.rule, models.ScopeSkill, s.FilePath, s.Line, s.EndLine, s.Name)}
}

// NewToolRuleDetector wraps a RuleDef as a ToolDetector. Exported for test packages.
func NewToolRuleDetector(r RuleDef) detectors.ToolDetector { return toolRuleDetector{r} }

// NewAgentRuleDetector wraps a RuleDef as an AgentDetector. Exported for test packages.
func NewAgentRuleDetector(r RuleDef) detectors.AgentDetector { return agentRuleDetector{r} }

// NewRepoRuleDetector wraps a RuleDef as a RepoDetector. Exported for test packages.
func NewRepoRuleDetector(r RuleDef) detectors.RepoDetector { return repoRuleDetector{r} }

// NewSubagentRuleDetector wraps a RuleDef as a SubagentDetector. Exported for test packages.
func NewSubagentRuleDetector(r RuleDef) detectors.SubagentDetector { return subagentRuleDetector{r} }

// NewSkillRuleDetector wraps a RuleDef as a SkillDetector. Exported for test packages.
func NewSkillRuleDetector(r RuleDef) detectors.SkillDetector { return skillRuleDetector{r} }

func findingFromRule(r RuleDef, scope models.Scope, filePath string, startLine, endLine int, toolName string) models.Finding {
	return models.Finding{
		RuleID:       r.ID,
		Category:     r.Category,
		Scope:        scope,
		Severity:     r.Severity,
		ToolName:     toolName,
		FilePath:     filePath,
		StartLine:    startLine,
		EndLine:      endLine,
		Title:        r.Title,
		Explanation:  r.Explanation,
		SuggestedFix: r.Fix,
		Confidence:   r.Confidence,
	}
}

// LoadFor returns a Registry containing only policy packs whose category matches
// one of the observed SDKs, plus the categories that are not SDK-gated at all.
// If sdks is empty, only those ungated categories are returned.
func LoadFor(fsys fs.FS, sdks []models.SDK) (*detectors.Registry, []string, error) {
	wanted := map[string]bool{
		"openshell": true,
		// Skills are a Claude Code artifact, not an SDK import, so the
		// claude_skill pack loads unconditionally (like openshell). Its rules
		// only fire when the repo actually declares skills.
		"claude_skill": true,
		// Observability is a cross-SDK category, not an SDK: its rules are
		// vendor-framed (Langfuse, OpenTelemetry) and list every SDK token in
		// applies_to. Gating it on SDKsDetected would drop the pack entirely and
		// OBS-001..003 could never fire. Loading it unconditionally is safe —
		// each rule still gates on its own applies_to and on observability
		// predicates that are false in a repo with no signals.
		"observability": true,
	}
	for _, sdk := range sdks {
		switch sdk {
		case models.SDKClaudeAgentSDK:
			wanted["claude_sdk"] = true
		case models.SDKOpenAIAgents:
			wanted["openai_sdk"] = true
		case models.SDKMCP:
			wanted["mcp"] = true
		case models.SDKGoogleADK:
			wanted["google_adk"] = true
		case models.SDKLangChain:
			wanted["langchain"] = true
		case models.SDKCrewAI:
			wanted["crewai"] = true
		case models.SDKPydanticAI:
			wanted["pydantic_ai"] = true
		case models.SDKVercelAI:
			wanted["vercel_ai"] = true
		case models.SDKAutoGen:
			wanted["autogen"] = true
		}
	}
	all, skipped, err := LoadLenient(fsys)
	if err != nil {
		return nil, nil, err
	}
	// Guard the "engine never runs rule-less" contract at the pack level. A
	// pack that resolves and is schema-compatible but carries zero rules (an
	// empty or truncated checkout) must hard-fail rather than silently report a
	// clean bill of health. This counts the UNFILTERED rule total, so it stays
	// distinct from the legitimate "repo's SDKs have no matching pack" case
	// below — there `all` is non-empty and the SDK filter narrows it (possibly
	// to just openshell), which must still succeed.
	totalRules := 0
	for _, p := range all {
		totalRules += len(p.Rules)
	}
	if totalRules == 0 {
		// Distinguish a genuinely empty/truncated pack from one whose every rule
		// was dropped as forward-incompatible (a rules repo entirely newer than
		// this build). The latter is fixed by upgrading Trustabl, not by
		// refreshing the pack, so it carries a distinct error.
		if len(skipped) > 0 {
			return nil, skipped, ErrAllRulesIncompatible
		}
		return nil, skipped, ErrNoRulesInPack
	}
	var tool []detectors.ToolDetector
	var agent []detectors.AgentDetector
	var repo []detectors.RepoDetector
	var subagent []detectors.SubagentDetector
	var skill []detectors.SkillDetector
	for _, p := range all {
		if !wanted[string(p.Policy.Category)] {
			continue
		}
		for _, r := range p.Rules {
			switch r.Scope {
			case models.ScopeTool:
				tool = append(tool, toolRuleDetector{r})
			case models.ScopeAgent:
				agent = append(agent, agentRuleDetector{r})
			case models.ScopeRepo:
				repo = append(repo, repoRuleDetector{r})
			case models.ScopeSubagent:
				subagent = append(subagent, subagentRuleDetector{r})
			case models.ScopeSkill:
				skill = append(skill, skillRuleDetector{r})
			}
		}
	}
	return detectors.New(tool, agent, repo, subagent, skill), skipped, nil
}

// LoadRegistry loads policies from fsys and returns a populated detector Registry.
func LoadRegistry(fsys fs.FS) (*detectors.Registry, error) {
	policies, err := Load(fsys)
	if err != nil {
		return nil, err
	}
	var tool []detectors.ToolDetector
	var agent []detectors.AgentDetector
	var repo []detectors.RepoDetector
	var subagent []detectors.SubagentDetector
	var skill []detectors.SkillDetector
	for _, p := range policies {
		for _, r := range p.Rules {
			switch r.Scope {
			case models.ScopeTool:
				tool = append(tool, toolRuleDetector{r})
			case models.ScopeAgent:
				agent = append(agent, agentRuleDetector{r})
			case models.ScopeRepo:
				repo = append(repo, repoRuleDetector{r})
			case models.ScopeSubagent:
				subagent = append(subagent, subagentRuleDetector{r})
			case models.ScopeSkill:
				skill = append(skill, skillRuleDetector{r})
			}
		}
	}
	return detectors.New(tool, agent, repo, subagent, skill), nil
}
