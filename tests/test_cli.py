import contextlib
import io
import tempfile
import unittest
from pathlib import Path
from unittest.mock import patch

from llm_eval import cli


class CommandTests(unittest.TestCase):
    def test_help_never_resolves_checkout_or_dispatches(self):
        commands = [[], ['demo'], ['demo', 'offline'], ['data'], ['data', 'setup'], ['generate'], ['generate', 'local'], ['generate', 'cloud'],
                    ['queue'], ['warmup'], ['judge'], ['judge', 'batch'],
                    ['judge', 'candidate'], ['validate'], ['diagnose'],
                    ['diagnose', 'response'], ['diagnose', 'generation-limit'],
                    ['evaluate'], ['evaluate', 'prepare'], ['evaluate', 'run'], ['evaluate', 'report']]
        for command in commands:
            with self.subTest(command=command), patch.object(cli, 'project_root') as root, \
                    patch.object(cli, 'dispatch') as dispatch, \
                    contextlib.redirect_stdout(io.StringIO()), self.assertRaises(SystemExit) as exit:
                cli.main([*command, '--help'])
            self.assertEqual(exit.exception.code, 0)
            root.assert_not_called()
            dispatch.assert_not_called()

    def test_evaluation_arguments(self):
        args = cli.parse_args(['evaluate', 'prepare', '--baseline', 'b1'])
        self.assertEqual((args.command, args.evaluation_action, args.baseline), ('evaluate', 'prepare', 'b1'))
        args = cli.parse_args(['evaluate', 'run', '--evaluation', 'e1', '--kind', 'repairs'])
        self.assertEqual((args.evaluation, args.kind), ('e1', 'repairs'))
        for argv in (['evaluate'], ['evaluate', 'prepare'],
                     ['evaluate', 'run', '--evaluation', 'e1'],
                     ['evaluate', 'run', '--evaluation', 'e1', '--kind', 'all'],
                     ['evaluate', 'report']):
            with self.subTest(argv=argv), contextlib.redirect_stderr(io.StringIO()), self.assertRaises(SystemExit):
                cli.parse_args(argv)

    def test_evaluation_dispatch(self):
        for args, target, expected in (
            (['prepare', '--baseline', 'b1'], 'llm_eval.judging.evaluation.prepare_evaluation', ('b1',)),
            (['run', '--evaluation', 'e1', '--kind', 'limits'], 'llm_eval.judging.evaluation.run_evaluation', ('e1', 'limits')),
            (['report', '--evaluation', 'e1'], 'llm_eval.judging.reporting.report_evaluation', ('e1',)),
        ):
            with self.subTest(args=args), patch(target) as call, contextlib.redirect_stdout(io.StringIO()):
                cli.dispatch(Path('/checkout'), cli.parse_args(['evaluate', *args]))
                call.assert_called_once_with(Path('/checkout'), *expected)

    def test_argument_contracts(self):
        cloud = cli.parse_args(['generate', 'cloud', '--model', 'luna', '--problems', 'all'])
        self.assertEqual((cloud.round, cloud.model), (None, 'luna'))
        for provider, model in [('local', 'qwen36'), ('cloud', 'motif3')]:
            command = ['generate', provider, '--model', model, '--problems', 'all']
            self.assertIsNone(cli.parse_args(command).round)
            for number in (1, 2):
                self.assertEqual(cli.parse_args([*command, '--round', str(number)]).round, number)
        self.assertEqual(cli.parse_args(['queue']).startup_timeout_seconds, 900)
        batch = cli.parse_args(['judge', 'batch'])
        self.assertEqual((batch.problems, batch.models, batch.rounds), ('all', 'all', 'all'))
        for args in [[], ['generate', 'local', '--model', 'gemma4', '--problems', 'all', '--round', '0'],
                     ['generate', 'cloud', '--model', 'luna', '--problems', 'all', '--round', '3'],
                     ['generate', 'cloud', '--problems', 'all'],
                     ['generate', 'cloud', '--model', 'gpt-luna', '--problems', 'all'],
                     ['warmup', '--model', 'unknown'], ['judge', 'candidate']]:
            with self.subTest(args=args), contextlib.redirect_stderr(io.StringIO()), \
                    self.assertRaises(SystemExit) as exit:
                cli.parse_args(args)
            self.assertEqual(exit.exception.code, 2)

    def test_wrong_checkout_rejected_before_dispatch(self):
        with tempfile.TemporaryDirectory() as folder, patch.object(cli.Path, 'cwd', return_value=Path(folder)), \
                patch.object(cli, 'dispatch') as dispatch, self.assertRaisesRegex(SystemExit, '저장소 루트'):
            cli.main(['generate', 'cloud', '--model', 'luna', '--problems', 'all'])
        dispatch.assert_not_called()

    def test_root_is_callers_checkout_not_package_location(self):
        with tempfile.TemporaryDirectory() as folder:
            root = Path(folder)
            (root / 'pyproject.toml').write_text('[project]\nname="local-llm-evaluation"\n')
            (root / 'src/llm_eval').mkdir(parents=True)
            (root / 'data/coci').mkdir(parents=True)
            (root / 'data/coci/problems.json').write_text('[]')
            with patch.object(cli.Path, 'cwd', return_value=root):
                self.assertEqual(cli.project_root(), root)

    def test_dispatch_preserves_selection_and_round(self):
        cases = [
            (['data', 'setup'], 'llm_eval.data_setup.setup_dataset', (None,)),
            (['data', 'setup', '--archives-dir', '/tmp/archives'],
             'llm_eval.data_setup.setup_dataset', (Path('/tmp/archives'),)),
            (['demo', 'offline', '--output', '/tmp/demo-fixture'],
             'llm_eval.offline_demo.run_offline_demo', (Path('/tmp/demo-fixture'),)),
            (['demo', 'offline'],
             'llm_eval.offline_demo.run_offline_demo', (None,)),
            (['generate','local','--model','qwen36','--problems','p1'],
             'llm_eval.local.generation.run_selected', ('qwen36','p1',None)),
            (['generate','cloud','--model','luna','--problems','p1'],
             'llm_eval.cloud.generation.run_selected', ('luna','p1',None)),
            (['generate','local','--model','gemma4','--problems','p1','--round','2'],
             'llm_eval.local.generation.run_selected', ('gemma4','p1',2)),
            (['generate','cloud','--model','motif3','--problems','p1','--round','2'],
             'llm_eval.cloud.generation.run_selected', ('motif3','p1',2)),
            (['queue'], 'llm_eval.local.queue.run_queue', (900,)),
            (['warmup','--model','gemma4'], 'llm_eval.local.client.run_warmup', ('gemma4',)),
            (['judge','batch'], 'llm_eval.judging.workflow.run_batch_judging', ('all','all','all')),
            (['judge','candidate','--code','answer.py','--problem','p1'],
             'llm_eval.judging.workflow.run_candidate_check', (Path('answer.py'),'p1')),
            (['diagnose','response'], 'llm_eval.diagnostics.run_response_probe', ()),
            (['diagnose','generation-limit','--model','gemma4'],
             'llm_eval.diagnostics.run_generation_limit_probe', ('gemma4',)),
        ]
        for command, target, expected in cases:
            with self.subTest(command=command), patch(target) as workflow:
                cli.dispatch(Path('/fixture'), cli.parse_args(command))
                workflow.assert_called_once_with(Path('/fixture'), *expected)

class WorkflowBoundaryTests(unittest.TestCase):
    def test_demo_generation_cannot_read_or_replace_before_lock(self):
        from llm_eval.local import generation as local
        from llm_eval.cloud import generation as cloud

        for runner, model in [(local, 'qwen36'), (cloud, 'luna')]:
            with self.subTest(model=model), \
                    patch.object(runner, 'workload', side_effect=RuntimeError('busy')), \
                    patch.object(runner, 'load_problems') as load, \
                    patch.object(runner, 'run_problem') as generate, \
                    patch.object(runner, 'create_client') as client:
                with self.assertRaisesRegex(RuntimeError, 'busy'):
                    runner.run_selected(Path('/fixture'), model, 'p')
            load.assert_not_called()
            generate.assert_not_called()
            client.assert_not_called()

    def test_diagnostics_cannot_call_server_when_local_lock_is_refused(self):
        from llm_eval import diagnostics
        for function, arguments, target in [
            (diagnostics.run_response_probe, (), '_response_probe'),
            (diagnostics.run_generation_limit_probe, ('gemma4',), '_generation_limit_probe'),
        ]:
            with self.subTest(function=function.__name__), \
                    patch.object(diagnostics, 'workload', side_effect=RuntimeError('busy')), \
                    patch.object(diagnostics, target) as probe, self.assertRaisesRegex(RuntimeError, 'busy'):
                function(Path('/fixture'), *arguments)
            probe.assert_not_called()

    def test_judging_does_not_collect_or_execute_before_lock(self):
        from llm_eval.judging import workflow
        with patch.object(workflow, 'workload', side_effect=RuntimeError('busy')), \
                patch.object(workflow, '_run_batch') as batch, \
                patch.object(workflow, 'load_problems') as load:
            with self.assertRaisesRegex(RuntimeError, 'busy'):
                workflow.run_batch_judging(Path('/fixture'))
            with self.assertRaisesRegex(RuntimeError, 'busy'):
                workflow.run_candidate_check(Path('/fixture'), Path('answer.py'), 'p')
        batch.assert_not_called()
        load.assert_not_called()
