package stark.dataworks.coderaider.genericagent.core.playground;

import io.github.cdimascio.dotenv.Dotenv;
import org.junit.jupiter.api.Assertions;
import org.junit.jupiter.api.Test;
import stark.dataworks.coderaider.genericagent.core.agent.AgentDefinition;
import stark.dataworks.coderaider.genericagent.core.agent.AgentRegistry;
import stark.dataworks.coderaider.genericagent.core.context.ContextResult;
import stark.dataworks.coderaider.genericagent.core.editor.ApplyPatchOperation;
import stark.dataworks.coderaider.genericagent.core.editor.ApplyPatchResult;
import stark.dataworks.coderaider.genericagent.core.editor.IApplyPatchEditor;
import stark.dataworks.coderaider.genericagent.core.examples.ExampleStreamingPublishers;
import stark.dataworks.coderaider.genericagent.core.examples.ExampleSupport;
import stark.dataworks.coderaider.genericagent.core.llmspi.adapter.ModelScopeLlmClient;
import stark.dataworks.coderaider.genericagent.core.runner.AgentRunner;
import stark.dataworks.coderaider.genericagent.core.runner.RunConfiguration;
import stark.dataworks.coderaider.genericagent.core.tool.ToolDefinition;
import stark.dataworks.coderaider.genericagent.core.tool.ToolParameterSchema;
import stark.dataworks.coderaider.genericagent.core.tool.ToolRegistry;
import stark.dataworks.coderaider.genericagent.core.tool.builtin.ApplyPatchTool;
import stark.dataworks.coderaider.genericagent.core.tool.builtin.LocalShellTool;

import java.io.IOException;
import java.nio.file.Files;
import java.nio.file.Path;
import java.util.List;
import java.util.Locale;
import java.util.Map;

/**
 * 33) Planner-first ReAct debug workflow with 3 agents: planner -> executor -> summarizer.
 * 
 * Inspired by Trae, Cursor, Antigravity design:
 * - Planner: Creates a high-level execution plan (2-8 steps), does NOT identify bugs
 * - Executor: Follows the plan, analyzes code, identifies bugs, generates patches, verifies
 * - Summarizer: Summarizes what was done (files modified, changes made, outcome)
 * 
 * Key design principles:
 * - Planner gives coarse-grained guidance, not specific bug locations
 * - Executor does the actual work: read, analyze, fix, verify
 * - Summarizer reports actions taken, not just results
 */
public class StepByStepRunnerTest
{
    private static final String MODEL = "Qwen/Qwen3-4B";
    private static final Path INPUT_FILE_1 = Path.of("src", "test", "resources", "inputs", "FinancialCalculator.py");
    private static final Path INPUT_FILE_2 = Path.of("src", "test", "resources", "inputs", "OrderProcessor.py");
    private static final RunConfiguration EXAMPLE_RUN_CONFIGURATION =
        new RunConfiguration(4, null, 0.0, 900, "auto", "text", Map.of());

    @Test
    public void run() throws IOException
    {
        long startedAt = System.nanoTime();
        Dotenv env = Dotenv.configure().filename(".env.local").ignoreIfMalformed().ignoreIfMissing().load();
        String apiKey = env.get("MODEL_SCOPE_API_KEY", System.getenv("MODEL_SCOPE_API_KEY"));
        if (apiKey == null || apiKey.isBlank())
        {
            System.out.println("Skipping test: MODEL_SCOPE_API_KEY not set");
            return;
        }

        RuntimeOs runtimeOs = detectRuntimeOs();
        Path workspace = Path.of("src", "test", "resources", "outputs", "react-agent", "example33");
        resetWorkspace(workspace);

        ToolRegistry toolRegistry = new ToolRegistry();
        toolRegistry.register(createShellTool());
        toolRegistry.register(new ApplyPatchTool(new FileSystemEditor(workspace), false));

        AgentRegistry agentRegistry = new AgentRegistry();
        agentRegistry.register(createPlannerAgent(runtimeOs, workspace));
        agentRegistry.register(createExecutorAgent(runtimeOs, workspace));
        agentRegistry.register(createSummarizerAgent(runtimeOs, workspace));

        AgentRunner runner = AgentRunner.builder()
            .llmClient(new ModelScopeLlmClient(apiKey, MODEL))
            .toolRegistry(toolRegistry)
            .agentRegistry(agentRegistry)
            .eventPublisher(ExampleStreamingPublishers.textWithToolLifecycle("ReAct33 "))
            .build();

        // TODO: Need to describe the bugs in detail, otherwise, the agent will not even understand the problem.
        String userRequest = "Fix both Python files quickly and provide a short summary at the end.";
        
        ContextResult planning = runner.chatClient("react30-planner").prompt().stream(true).user(userRequest)
            .runConfiguration(EXAMPLE_RUN_CONFIGURATION).runHooks(ExampleSupport.noopHooks()).call().contextResult();

        String verifyOutput = runBehaviorVerification(runtimeOs, workspace);
        ContextResult execution = null;
        for (int attempt = 1; attempt <= 6; attempt++)
        {
            execution = runner.chatClient("react30-executor").prompt().stream(true)
                .user(buildExecutorPrompt(runtimeOs, workspace, planning.getFinalOutput(), verifyOutput, attempt))
                .runConfiguration(EXAMPLE_RUN_CONFIGURATION).runHooks(ExampleSupport.noopHooks()).call().contextResult();
            verifyOutput = runBehaviorVerification(runtimeOs, workspace);
            if (verifyOutput.contains("BEHAVIOR_OK"))
            {
                break;
            }
        }

        ContextResult summary = null;
        if (!userRequest.toLowerCase(Locale.ROOT).contains("no summary"))
        {
            summary = runner.chatClient("react30-summarizer").prompt().stream(true)
                .user("Plan:\n" + planning.getFinalOutput() + "\nExecution:\n" + execution.getFinalOutput() + "\nVerify:\n" + verifyOutput)
                .runConfiguration(EXAMPLE_RUN_CONFIGURATION).runHooks(ExampleSupport.noopHooks()).call().contextResult();
        }

        Assertions.assertTrue(verifyOutput.contains("BEHAVIOR_OK"),
            "Agent must fix the bugs successfully. Verification output: " + verifyOutput);
        Assertions.assertNotNull(planning.getFinalOutput());
        Assertions.assertNotNull(execution.getFinalOutput());

        if (summary != null)
        {
            String summaryText = summary.getFinalOutput();
            Assertions.assertFalse(summaryText.isBlank());
            Assertions.assertTrue(summaryText.contains("Files") || summaryText.contains("Changes") || summaryText.contains("Outcome"),
                "Expected summary with relevant sections. Got: " + summaryText);
        }

        long elapsedSeconds = (System.nanoTime() - startedAt) / 1_000_000_000L;
        Assertions.assertTrue(elapsedSeconds <= 150, "Expected runtime (<=150s) but took " + elapsedSeconds + "s");
    }

    private static String buildExecutorPrompt(RuntimeOs runtimeOs, Path workspace, String executionPlan, String verifyOutput, int attempt)
    {
        return """
            Attempt %d to fix the bugs.
            
            Execution plan from planner:
            %s
            
            Current verification status:
            %s
            
            Your task:
            1. Follow the execution plan
            2. Read and analyze the code to identify bugs
            3. Generate and apply patches
            4. Verify with: %s
            5. Target: output should contain BEHAVIOR_OK
            
            OS: %s
            Workspace: %s
            """.formatted(attempt, executionPlan, verifyOutput.trim(), runtimeOs.verifyCommand(workspace),
            runtimeOs.displayName, workspace);
    }

    private static AgentDefinition createPlannerAgent(RuntimeOs runtimeOs, Path workspace)
    {
        AgentDefinition def = new AgentDefinition();
        def.setId("react30-planner");
        def.setName("Planning Agent");
        def.setModel(MODEL);
        def.setReactEnabled(true);
        def.setSystemPrompt("""
            You are a debugging planner. Create a high-level execution plan (2-8 steps).
            
            Your plan should be COARSE-GRAINED, like:
            1. Read FinancialCalculator.py to understand the calculation logic
            2. Read OrderProcessor.py to understand the order processing flow
            3. Run the verification to see the current error
            4. Analyze the percentage calculation in FinancialCalculator
            5. Analyze the tax calculation in OrderProcessor
            6. Fix the bugs and verify
            
            DO NOT:
            - Identify specific bugs or line numbers
            - Generate patches
            - Provide exact code fixes
            
            Just give a rough plan of what steps to take.
            
            OS: %s
            Workspace: %s
            Files: FinancialCalculator.py, OrderProcessor.py
            Verify command: python OrderProcessor.py
            """.formatted(runtimeOs.displayName, workspace));
        def.setReactInstructions("""
            Create a simple execution plan with 2-8 steps.
            
            Format:
            ## Execution Plan
            1. [Step description]
            2. [Step description]
            ...
            
            Keep it simple and high-level.
            """);
        def.setToolNames(List.of("local_shell"));
        def.setModelProviderOptions(Map.of("working_directory", workspace.toString()));
        def.setModelReasoning(Map.of("effort", "low"));
        return def;
    }

    private static AgentDefinition createExecutorAgent(RuntimeOs runtimeOs, Path workspace)
    {
        AgentDefinition def = new AgentDefinition();
        def.setId("react30-executor");
        def.setName("Executor Agent");
        def.setModel(MODEL);
        def.setReactEnabled(true);
        def.setSystemPrompt("""
            You are a code executor. Follow the planner's execution plan and fix the bugs.
            
            Your responsibilities:
            1. Follow the execution plan from the planner
            2. Read and analyze the code to identify bugs
            3. Generate patches to fix the bugs
            4. Apply patches using apply_patch tool
            5. Verify the fixes work
            6. Iterate if verification fails
            
            EXECUTION LOOP:
            Read code → Identify bugs → Generate patches → Apply → Verify → If fails, retry
            
            IMPORTANT:
            - You are responsible for analyzing code and identifying bugs
            - You are responsible for generating patches
            - You are responsible for verification
            - The planner only gives a rough plan, you do the actual work
            
            OS: %s
            Workspace: %s
            Verify command: %s
            Target: output should contain BEHAVIOR_OK
            """.formatted(runtimeOs.displayName, workspace, runtimeOs.verifyCommand(workspace)));
        def.setReactInstructions("""
            Execute the plan step by step:
            1. Read the files mentioned in the plan
            2. Analyze the code to find bugs
            3. For each bug, generate a patch:
               - file: the file path
               - old_content: exact current code (must match file exactly)
               - new_content: the fixed code
            4. Apply patches using apply_patch tool
            5. Run verification: python OrderProcessor.py
            6. If BEHAVIOR_BAD, analyze the error and retry
            7. Continue until BEHAVIOR_OK
            """);
        def.setToolNames(List.of("apply_patch", "local_shell"));
        def.setModelProviderOptions(Map.of("working_directory", workspace.toString()));
        def.setModelReasoning(Map.of("effort", "low"));
        return def;
    }

    private static AgentDefinition createSummarizerAgent(RuntimeOs runtimeOs, Path workspace)
    {
        AgentDefinition def = new AgentDefinition();
        def.setId("react30-summarizer");
        def.setName("Summary Agent");
        def.setModel(MODEL);
        def.setReactEnabled(true);
        def.setSystemPrompt("""
            You are a task summarizer. Summarize what was done during the debugging process.
            
            Your summary should include:
            1. What files were modified
            2. What changes were made
            3. What the outcome was
            
            Keep it concise and informative.
            
            OS: %s
            Workspace: %s
            """.formatted(runtimeOs.displayName, workspace));
        def.setReactInstructions("""
            Summarize the work done:
            
            ## Summary
            - Files modified: [list files]
            - Changes made: [brief description of changes]
            - Outcome: [success/failure and final result]
            """);
        def.setToolNames(List.of("local_shell"));
        def.setModelProviderOptions(Map.of("working_directory", workspace.toString()));
        def.setModelReasoning(Map.of("effort", "low"));
        return def;
    }

    private static void resetWorkspace(Path workspace) throws IOException
    {
        if (Files.exists(workspace))
        {
            Files.walk(workspace)
                .sorted((a, b) -> b.getNameCount() - a.getNameCount())
                .forEach(path ->
                {
                    try
                    {
                        Files.delete(path);
                    }
                    catch (IOException ex)
                    {
                        throw new RuntimeException(ex);
                    }
                });
        }
        Files.createDirectories(workspace);
        Files.writeString(workspace.resolve("FinancialCalculator.py"), Files.readString(INPUT_FILE_1));
        Files.writeString(workspace.resolve("OrderProcessor.py"), Files.readString(INPUT_FILE_2));
    }

    private static LocalShellTool createShellTool()
    {
        return new LocalShellTool(new ToolDefinition(
            "local_shell",
            "Execute a local shell command and return stdout/stderr.",
            List.of(new ToolParameterSchema("command", "string", true, "Shell command to execute"))));
    }

    private static String runBehaviorVerification(RuntimeOs runtimeOs, Path workspace)
    {
        ProcessBuilder builder = switch (runtimeOs)
        {
            case WINDOWS -> new ProcessBuilder("cmd", "/c",
                "cd /d \"" + workspace + "\" && python OrderProcessor.py");
            case MACOS, LINUX -> new ProcessBuilder("bash", "-lc",
                "cd '" + workspace + "' && python OrderProcessor.py");
        };
        builder.redirectErrorStream(true);
        try
        {
            Process process = builder.start();
            String output = new String(process.getInputStream().readAllBytes());
            process.waitFor();
            return output;
        }
        catch (Exception ex)
        {
            return "VERIFY_ERROR: " + ex.getMessage();
        }
    }

    private static RuntimeOs detectRuntimeOs()
    {
        String osName = System.getProperty("os.name", "").toLowerCase(Locale.ROOT);
        if (osName.contains("win"))
        {
            return RuntimeOs.WINDOWS;
        }
        if (osName.contains("mac"))
        {
            return RuntimeOs.MACOS;
        }
        return RuntimeOs.LINUX;
    }

    private enum RuntimeOs
    {
        WINDOWS("Windows"),
        MACOS("macOS"),
        LINUX("Linux");

        private final String displayName;

        RuntimeOs(String displayName)
        {
            this.displayName = displayName;
        }

        private String verifyCommand(Path workspace)
        {
            return "python OrderProcessor.py";
        }
    }

    private static final class FileSystemEditor implements IApplyPatchEditor
    {
        private final Path workspaceRoot;

        private FileSystemEditor(Path workspaceRoot)
        {
            this.workspaceRoot = workspaceRoot.toAbsolutePath().normalize();
        }

        @Override
        public ApplyPatchResult createFile(ApplyPatchOperation operation)
        {
            return upsert(operation, true);
        }

        @Override
        public ApplyPatchResult updateFile(ApplyPatchOperation operation)
        {
            return upsert(operation, false);
        }

        @Override
        public ApplyPatchResult deleteFile(ApplyPatchOperation operation)
        {
            if (operation == null || operation.getPath() == null)
            {
                return ApplyPatchResult.failed("Invalid operation");
            }
            Path target = workspaceRoot.resolve(operation.getPath()).normalize();
            if (!target.startsWith(workspaceRoot))
            {
                return ApplyPatchResult.failed("Path escapes workspace");
            }
            try
            {
                Files.deleteIfExists(target);
                return ApplyPatchResult.completed("Deleted " + operation.getPath());
            }
            catch (IOException ex)
            {
                return ApplyPatchResult.failed("Delete failed: " + ex.getMessage());
            }
        }

        private ApplyPatchResult upsert(ApplyPatchOperation operation, boolean createMode)
        {
            if (operation == null || operation.getPath() == null)
            {
                return ApplyPatchResult.failed("Invalid operation");
            }
            Path target = workspaceRoot.resolve(operation.getPath()).normalize();
            if (!target.startsWith(workspaceRoot))
            {
                return ApplyPatchResult.failed("Path escapes workspace");
            }
            try
            {
                Files.createDirectories(target.getParent());
                if (createMode)
                {
                    String content = ApplyPatchTool.applyCreateDiff(operation.getDiff());
                    Files.writeString(target, content);
                    return ApplyPatchResult.completed("Created " + operation.getPath());
                }
                String source = Files.exists(target) ? Files.readString(target) : "";
                String patched = ApplyPatchTool.applyDiff(source, operation.getDiff());

                // Check if any actual changes were applied
                if (patched.equals(source))
                {
                    return ApplyPatchResult.failed(buildDiffNotMatchError(operation.getDiff()));
                }

                Files.writeString(target, patched);
                return ApplyPatchResult.completed("Updated " + operation.getPath());
            }
            catch (Exception ex)
            {
                return ApplyPatchResult.failed("Patch failed: " + ex.getMessage());
            }
        }

        private static String buildDiffNotMatchError(String diff)
        {
            StringBuilder errorMsg = new StringBuilder();
            errorMsg.append("Diff failed: content not found in file. No changes were applied.\n\n");
            errorMsg.append("The diff you provided:\n");
            if (diff != null)
            {
                String[] lines = diff.split("\\R", -1);
                int shown = 0;
                for (String line : lines)
                {
                    if (shown >= 5) break;
                    if (line.startsWith("-") || line.startsWith("+"))
                    {
                        String display = line.length() > 100 ? line.substring(0, 100) + "..." : line;
                        errorMsg.append("  ").append(display).append("\n");
                        shown++;
                    }
                }
            }
            errorMsg.append("\nTo fix this:\n");
            errorMsg.append("1. Read the file again to get its CURRENT content.\n");
            errorMsg.append("2. Compare your diff with the actual file content.\n");
            errorMsg.append("3. Provide a new diff that matches EXACTLY what's in the file (including whitespace).\n");
            return errorMsg.toString();
        }
    }
}
