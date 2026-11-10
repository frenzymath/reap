module
public meta import Lean.Elab.Task
public meta import OpenAIClient
public meta import Reap.Options
public meta import Reap.PremiseSelection.Syntax
public meta import Reap.Tactic.WallClock

public meta section

open Lean Elab Tactic
open Reap.WallClock

structure TacticGenerator where
  llmClient : OpenAIClient
  valueClient : OpenAIClient
  model : String

def OpenAIChatChoice.computeLogProbability (choice: OpenAIChatChoice) : Float :=
  match choice.logprobs with
  | none => 0.0
  | some choice_logprobs =>
    match choice_logprobs.content with
    | none => 0.0
    | some logProbs => (logProbs.map fun x => x.logprob).sum

namespace TacticGenerator

/-- Strip `<think>...</think>` prefix that some LLMs prepend to their responses. -/
def stripThinkingPrefix (s : String) : String :=
  let s := s.trimAsciiStart.toString
  if s.startsWith "<think>" then
    let parts := s.splitOn "</think>"
    if parts.length > 1 then
      (String.intercalate "</think>" (parts.drop 1)).trimAsciiStart.toString
    else s
  else s

def retryM? {α ε : Type} {m : Type → Type} [Monad m] [MonadExcept ε m]
    (action : m α) (maxRetries : Nat := 3) : m (Option α) := do
  let mut result : Option α := none
  let mut i := 0
  while result.isNone && i < maxRetries do
    i := i + 1
    try
      result := some (← action)
    catch _ =>
      pure ()
  return result

def parseChatResponseOpenAI (res: OpenAIChatResponse) : Array (String × Float) :=
  (res.choices.map fun x => (stripThinkingPrefix x.message.content, x.computeLogProbability)).toArray

def mkRelatedTheorem (ps : PremiseSelectionResult) : String :=
  let formalName := ps.formal_name
  let formalStatement := ps.formal_statement
  "Formal name: " ++ formalName ++ "\n" ++
  "Formal statement: " ++ formalStatement

def mkPrompt (tacticState : String) (relatedTheorems: Array PremiseSelectionResult) : String :=
  "User: Please generate a tactic in lean4 to solve the state.
Here're some theorems that may be helpful:
" ++ (relatedTheorems.map mkRelatedTheorem |>.joinSep "\n") ++
"
STATE:
" ++ tacticState ++ "
TACTIC:

Assistant:"

def getClient : CoreM TacticGenerator := do
  return {
    llmClient := ⟨reap.policy_endpoint.get (← getOptions), reap.llm_api_key.get (← getOptions)⟩
    valueClient := ⟨reap.value_endpoint.get (← getOptions), reap.llm_api_key.get (← getOptions)⟩
    model := reap.model.get (← getOptions)
  }

deriving instance ToJson for OpenAIChatCompletionTokenLogprob, OpenAIChoiceLogprobs, OpenAIChatChoice, OpenAIChatResponse

structure ValueResult where
  score : Float
deriving Inhabited, FromJson, ToJson

def getRelatedTheorems (logConfig : ReapLogConfig) (config : ReapGenerationConfig) (mvarIds : List MVarId) (ppGoal : String) :
    MetaM (Array PremiseSelectionResult) := do
  withLogWallClockTime logConfig "premise_select" (fun result => json%{ goal: $ppGoal, result: $result }) do
    selectPremisesForGoals mvarIds config.numPremises

def mkChatRequest (config : ReapGenerationConfig) (model : String) (prompt : String) (n : Nat) :
    OpenAIChatRequest := {
  model
  messages := [ { role := "user", content := prompt } ]
  n := n
  temperature := config.temperature
  max_tokens := config.maxTokens
  logprobs := true
}

def generatePolicyFromPrompt (generator : TacticGenerator) (logConfig : ReapLogConfig) (config : ReapGenerationConfig)
    (ppGoal : String) (relatedTheorems : Array PremiseSelectionResult) (prompt : String) :
    CoreM (Array (String × Float)) := do
  let req := mkChatRequest config generator.model prompt config.numSamples
  let res ← withLogWallClockTime logConfig "tactic_gen" (fun result => json%{ goal: $ppGoal, ps: $relatedTheorems, result: $result }) <|
    retryM? (generator.llmClient.generateChat req)
  return res.map parseChatResponseOpenAI |>.getD #[]

def generateValueFromPrompt (generator : TacticGenerator) (logConfig : ReapLogConfig) (config : ReapGenerationConfig)
    (ppGoal : String) (relatedTheorems : Array PremiseSelectionResult) (prompt : String) :
    CoreM Float := do
  let req := mkChatRequest config generator.model prompt 1
  let result : Option ValueResult ← withLogWallClockTime logConfig "value" (fun result => json%{ state: $ppGoal, ps: $relatedTheorems, result: $result }) do
    retryM? (maxRetries := 3) do
      let res ← generator.valueClient.generateChat req
      let res := parseChatResponseOpenAI res
      let res := Json.parse res[0]!.1
      if let .ok res := res then
        match fromJson? res with
        | .ok value => return value
        | .error _ => throwError "Failed to decode value response"
      else
        throwError "Failed to parse value response as JSON"
  match result with
  | some result => return -result.score
  | none => return -1000.0

def Meta.ppProofState (mvarIds : List MVarId) : MetaM Format := do
  return Std.Format.joinSep (← mvarIds.mapM (Meta.ppGoal)) "\n".toFormat

def generatePolicyValue (logConfig : ReapLogConfig) (config : ReapGenerationConfig) (mvarIds : List MVarId) :
    MetaM <| Float × Array (String × Array PremiseSelectionResult × Float) := do
  let generator ← getClient
  let ppProofState := toString (← Meta.ppProofState mvarIds)
  let relatedTheorems ← getRelatedTheorems logConfig config mvarIds ppProofState
  let prompt := mkPrompt ppProofState relatedTheorems
  let (_, valueTask) ← Lean.Core.CoreM.asTask <|
    generateValueFromPrompt generator logConfig config ppProofState relatedTheorems prompt
  let (_, policyTask) ← Lean.Core.CoreM.asTask <|
    generatePolicyFromPrompt generator logConfig config ppProofState relatedTheorems prompt
  let value ← valueTask.get
  let tactics ← policyTask.get
  return (value, tactics.map fun (x, y) => (x, relatedTheorems, y))
