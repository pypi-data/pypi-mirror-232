import os
import re
import shutil

from weathon.dl.utils.constants import ModelFile
from weathon.dl.utils.constants import Pipelines
from weathon.dl.utils.checkpoint import (load_checkpoint, save_checkpoint,
                                         save_configuration)
from weathon.dl.utils.logger import get_logger
from weathon.dl.utils.torch_utils import is_master
logger = get_logger("deeplearning")

class CheckpointProcessor:
    TRAINER_STATE_SUFFIX = '_trainer_state.pth'

    MODEL_STATE_SUFFIX = '.pth'

    def prepare_output(self, trainer, output_dir):
        """准备输出到目标目录

        This is a strategic function which can be registered by other hook's function.

        Args:
            trainer: The trainers instance.
            output_dir: The target folder used in inference.
        """
        model = trainer.unwrap_module(trainer.model)
        config = trainer.cfg

        # override pipeline by tasks name after finetune done,
        # avoid case like fill mask pipeline with a text cls task
        if config['task'] in [
            getattr(Pipelines, attr) for attr in dir(Pipelines)
            if not attr.startswith('__')
        ]:
            # TODO a temp fix to avoid pipeline_name and task mismatch
            config['pipeline'] = {'type': config['task']}

        self.copy_files_and_dump_config(trainer, output_dir, config, self._bin_file(model))

    @staticmethod
    def copy_files_and_dump_config(trainer, output_dir, config, bin_file):
        """Copy useful files to target output folder and dumps the target configuration.json.
        """
        model = trainer.unwrap_module(trainer.model)

        class SaveConfig:

            def __init__(self, output_dir, config):
                self.output_dir = output_dir
                self.config = config

            def __call__(self, _output_dir, _config):
                self.config = _config

            def save_config(self):
                save_configuration(self.output_dir, self.config)

        save_config_fn = SaveConfig(output_dir, config)

        if hasattr(model, 'save_pretrained'):
            # Save pretrained of model, skip saving checkpoint
            model.save_pretrained(output_dir,
                                  bin_file,
                                  save_function=lambda *args, **kwargs: None,
                                  config=save_config_fn.config,
                                  save_config_function=save_config_fn)

        if trainer.train_preprocessor is not None:
            trainer.train_preprocessor.save_pretrained(output_dir, save_config_fn.config, save_config_function=save_config_fn)
        if trainer.eval_preprocessor is not None:
            trainer.eval_preprocessor.save_pretrained(output_dir, save_config_fn.config, save_config_function=save_config_fn)
        save_config_fn.save_config()

    @staticmethod
    def _bin_file(model):
        """Get bin file path.
        """
        default_bin_file = ModelFile.TORCH_MODEL_BIN_FILE
        if hasattr(model, 'model_dir') and ModelFile.TORCH_MODEL_FILE in os.listdir(model.model_dir):
            default_bin_file = ModelFile.TORCH_MODEL_FILE
        return default_bin_file

    def save_checkpoints(self,
                         trainer,
                         checkpoint_path_prefix,
                         output_dir,
                         meta=None):
        """Save the state dict for trainers and model.

        This is a strategic function which can be registered by other hook's function.

        Args:
            trainer(`EpochBasedTrainer`): The trainers instance.
            checkpoint_path_prefix(`str`): The saving dir with a prefix.
                like: /tmp/test/epoch_0
            output_dir(`str`): The output dir for inference.
            meta: (`dict`): The meta info needed to be saved into files.
        """
        model = trainer.unwrap_module(trainer.model)
        _model_file, _train_state_file = self._get_state_file_name(checkpoint_path_prefix)

        # Save pth file without model state_dict
        self.save_trainer_state(trainer, model, _train_state_file, meta)
        self.save_model_state(model, _model_file)
        self.link(model, _model_file, output_dir)

    def remove_checkpoints(self, trainer, checkpoint_path_prefix):
        """Remove obsolete checkpoint files.

        This is a strategic function which can be registered by other hook's function.

        Args:
            trainer(`EpochBasedTrainer`): The trainers instance.
            checkpoint_path_prefix(`str`): The saving dir with a prefix.
                like: /tmp/test/epoch_0
        """
        _model_file, _train_state_file = self._get_state_file_name(checkpoint_path_prefix)
        if os.path.isfile(_train_state_file):
            os.remove(_train_state_file)
        if os.path.isfile(_model_file):
            os.remove(_model_file)

    def should_save_on_rank(self, trainer):
        """Used in ddp or other distributed training scenario, returns whether do saving in current rank.

        This is a strategic function which can be registered by other hook's function.

        Args:
            trainer(`EpochBasedTrainer`): The trainers instance.
        """
        return is_master()

    def link(self, model, src_file, output_dir):
        """Links the src bin file to the output folder.

        Args:
            model: The model instance.
            src_file: The src bin file path.
            output_dir: The target folder used in inference.
        """

        bin_file = self._bin_file(model)
        dest_file = os.path.join(output_dir, bin_file)
        if os.path.isfile(dest_file) and os.path.islink(dest_file):
            os.unlink(dest_file)

        try:
            os.link(src_file, dest_file)
        except OSError as e:
            logger.error(
                f'Link {src_file} to {dest_file} error: {e}, '
                'changing to copy the bin file, this may use more disk space.')
            shutil.copyfile(src_file, dest_file)

    def save_trainer_state(self, trainer, model, train_state_file, meta):
        """Save the trainers state, including optimizer/lr_scheduler's state dict, random states etc.

        Args:
            trainer: The trainers instance.
            model: The model instance.
            train_state_file: The target file name for saving trainers states.
            meta: Some extra meta info.
        """
        save_checkpoint(model,train_state_file,trainer.optimizer, trainer.lr_scheduler, meta=meta, with_model=False)

    def save_model_state(self, model, model_file):
        """Save the model state.

        Args:
            model: The model instance.
            model_file: The target file name for saving model states.
        """
        save_checkpoint(model, model_file, None, None, meta=None, with_meta=False)

    def load_checkpoints(self, checkpoint_path_prefix, trainer, load_all_state,
                         strict):
        """Load checkpoint files of trainers state and model state.

        This is a strategic function which can be registered by other hook's function.

        Args:
            checkpoint_path_prefix(str): The checkpoint dir with prefix or a model state file.
                Example: '/tmp/test/epoch_0' or '/tmp/test/epoch_0.pth'
            trainer(`EpochBasedTrainer`): The trainers instance.
            load_all_state(`boolean`): Load all states (else load only module states).
            strict(`boolean`): If strict, any unmatched keys will cause an error.

        Returns:
            The meta info in json.
        """
        _model_file, _train_state_file = self._get_state_file_name(checkpoint_path_prefix)
        meta = {}
        if os.path.isfile(_train_state_file):
            meta = self.load_trainer_state(trainer, _train_state_file, load_all_state)
        else:
            print(f'No trainers state file {_train_state_file} found, skip.')
        self.load_model_state(trainer, _model_file, strict)
        return meta

    @staticmethod
    def load_trainer_state(trainer, train_state_file, load_all_state):
        """Load trainers state file.
        """

        optimizer = getattr(trainer, 'optimizer', None) if load_all_state else None
        lr_scheduler = getattr(trainer, 'lr_scheduler', None) if load_all_state else None
        return load_checkpoint(train_state_file, None, optimizer, lr_scheduler)

    def load_model_state(self, trainer, model_file, strict):
        """加载模型state文件
        """
        return load_checkpoint(model_file, trainer.unwrap_module(trainer.model), None, None)

    @staticmethod
    def _get_state_file_name(checkpoint_path_prefix):
        """
        获取state文件默认的文件名称

        If the input is a checkpoint dir with prefix, this function will append suffix for both checkpoint files.
        If the input is an absolute file name, this function will return it as the model file name, and append
            suffix for the trainers file name.

        NOTE: a best checkpoint filename with float or int metric value inside
            will not be judged as having a extension file name. like: '/tmp/test/epoch_0_accuracy0.85'

        Args:
            checkpoint_path_prefix(`str`): The checkpoint dir with prefix or a model state file
            with extension file name. like: '/tmp/test/epoch_0'

        Returns:
              A tuple of model state file name and trainers state file name.
        """
        base, ext = os.path.splitext(checkpoint_path_prefix)
        if len(ext) == 0 or re.match(r'^\d+$', ext[1:]):
            return checkpoint_path_prefix + CheckpointProcessor.MODEL_STATE_SUFFIX, \
                   checkpoint_path_prefix + CheckpointProcessor.TRAINER_STATE_SUFFIX  # noqa
        else:
            return checkpoint_path_prefix, base + CheckpointProcessor.TRAINER_STATE_SUFFIX.split('.')[0] + '.' + ext[1:]
