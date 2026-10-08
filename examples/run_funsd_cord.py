#!/usr/bin/env python
# coding=utf-8
import logging
import os
import sys
import json
from dataclasses import dataclass, field
from typing import Optional

import numpy as np
from datasets import ClassLabel, load_dataset, load_metric

import transformers

# V4-det: set CUDA/Python runtime flags before PyTorch initializes CUDA.
os.environ.setdefault("CUBLAS_WORKSPACE_CONFIG", ":4096:8")
os.environ.setdefault("TOKENIZERS_PARALLELISM", "false")
import torch
from layoutlmft.data import DataCollatorForKeyValueExtraction
from transformers import (
    AutoConfig,
    AutoModelForTokenClassification,
    AutoTokenizer,
    HfArgumentParser,
    PreTrainedTokenizerFast,
    Trainer,
    TrainingArguments,
    set_seed,
)
from transformers.trainer_utils import get_last_checkpoint, is_main_process
from transformers.utils import check_min_version

# Will error if the minimal version of Transformers is not installed. Remove at your own risks.
check_min_version("4.5.0")

logger = logging.getLogger(__name__)
from layoutlmft.data.image_utils import RandomResizedCropAndInterpolationWithTwoPic, pil_loader, Compose

from timm.data.constants import \
    IMAGENET_DEFAULT_MEAN, IMAGENET_DEFAULT_STD, IMAGENET_INCEPTION_MEAN, IMAGENET_INCEPTION_STD
from torchvision import transforms

@dataclass
class ModelArguments:
    """
    Arguments pertaining to which model/config/tokenizer we are going to fine-tune from.
    """

    model_name_or_path: str = field(
        metadata={"help": "Path to pretrained model or model identifier from huggingface.co/models"}
    )
    config_name: Optional[str] = field(
        default=None, metadata={"help": "Pretrained config name or path if not the same as model_name"}
    )
    tokenizer_name: Optional[str] = field(
        default=None, metadata={"help": "Pretrained tokenizer name or path if not the same as model_name"}
    )
    cache_dir: Optional[str] = field(
        default=None,
        metadata={"help": "Where do you want to store the pretrained models downloaded from huggingface.co"},
    )
    model_revision: str = field(
        default="main",
        metadata={"help": "The specific model version to use (can be a branch name, tag name or commit id)."},
    )
    use_auth_token: bool = field(
        default=False,
        metadata={
            "help": "Will use the token generated when running `transformers-cli login` (necessary to use this script "
            "with private models)."
        },
    )
    use_hierarchical_position_encoding: bool = field(
        default=False,
        metadata={"help": "Enable Hierarchical Position Encoding (HPE)"}
    )
    max_line_position: int = field(
        default=50,
        metadata={"help": "Maximum number of lines in a document for HPE"}
    )
    max_block_position: int = field(
        default=20,
        metadata={"help": "Maximum number of blocks in a document for HPE"}
    )
    use_column_encoding: bool = field(
        default=False,
        metadata={"help": "Enable Column Position Encoding"}
    )
    max_column_position: int = field(
        default=10,
        metadata={"help": "Maximum number of columns in a document"}
    )
    use_intra_line_boundary: bool = field(
        default=False,
        metadata={"help": "Enable Intra-Line Boundary Transition Parsing"}
    )
    lambda_bound_init: float = field(
        default=0.1,
        metadata={"help": "Initial weight for boundary loss"}
    )
    use_semantic_geometry_disentangle: bool = field(
        default=False,
        metadata={"help": "Enable Semantic-Geometry Disentanglement"}
    )
    lambda_geo_init: float = field(
        default=0.1,
        metadata={"help": "Initial weight for geometry loss"}
    )
    lambda_orth_init: float = field(
        default=0.1,
        metadata={"help": "Initial weight for orthogonality loss"}
    )


@dataclass
class DataTrainingArguments:
    """
    Arguments pertaining to what data we are going to input our model for training and eval.
    """

    task_name: Optional[str] = field(default="ner", metadata={"help": "The name of the task (ner, pos...)."})
    dataset_name: Optional[str] = field(
        default='funsd', metadata={"help": "The name of the dataset to use (via the datasets library)."}
    )
    dataset_config_name: Optional[str] = field(
        default=None, metadata={"help": "The configuration name of the dataset to use (via the datasets library)."}
    )
    train_file: Optional[str] = field(
        default=None, metadata={"help": "The input training data file (a csv or JSON file)."}
    )
    validation_file: Optional[str] = field(
        default=None,
        metadata={"help": "An optional input evaluation data file to evaluate on (a csv or JSON file)."},
    )
    test_file: Optional[str] = field(
        default=None,
        metadata={"help": "An optional input test data file to predict on (a csv or JSON file)."},
    )
    overwrite_cache: bool = field(
        default=False, metadata={"help": "Overwrite the cached training and evaluation sets"}
    )
    preprocessing_num_workers: Optional[int] = field(
        default=None,
        metadata={"help": "The number of processes to use for the preprocessing."},
    )
    pad_to_max_length: bool = field(
        default=True,
        metadata={
            "help": "Whether to pad all samples to model maximum sentence length. "
            "If False, will pad the samples dynamically when batching to the maximum length in the batch. More "
            "efficient on GPU but very bad for TPU."
        },
    )
    max_train_samples: Optional[int] = field(
        default=None,
        metadata={
            "help": "For debugging purposes or quicker training, truncate the number of training examples to this "
            "value if set."
        },
    )
    max_val_samples: Optional[int] = field(
        default=None,
        metadata={
            "help": "For debugging purposes or quicker training, truncate the number of validation examples to this "
            "value if set."
        },
    )
    max_test_samples: Optional[int] = field(
        default=None,
        metadata={
            "help": "For debugging purposes or quicker training, truncate the number of test examples to this "
            "value if set."
        },
    )
    label_all_tokens: bool = field(
        default=False,
        metadata={
            "help": "Whether to put the label for one word on all tokens of generated by that word or just on the "
            "one (in which case the other tokens will have a padding index)."
        },
    )
    return_entity_level_metrics: bool = field(
        default=False,
        metadata={"help": "Whether to return all the entity levels during evaluation or just the overall ones."},
    )
    segment_level_layout: bool = field(
        default=False,
        metadata={
            "help": "Legacy compatibility flag. For FUNSD, bbox granularity is controlled by layoutlmft/data/funsd.py; V5 always expects word-level boxes."
        },
    )
    visual_embed: bool = field(default=True)
    use_segment_head: bool = field(
        default=False,
        metadata={
            "help": "Use LayoutLMv3ForSegmentTokenClassification (segment-level pooling + "
            "inter-segment context head) instead of the vanilla per-token classification head."
        },
    )
    segment_train_predictions_dir: Optional[str] = field(
        default=None,
        metadata={
            "help": "Directory containing predicted segments for the FUNSD training split. V5 does NOT use gold form.id segments."
        },
    )
    segment_eval_predictions_dir: Optional[str] = field(
        default=None,
        metadata={
            "help": "Directory containing predicted segments for the FUNSD eval/test split."
        },
    )
    data_dir: Optional[str] = field(default=None)
    input_size: int = field(default=224, metadata={"help": "images input size for backbone"})
    second_input_size: int = field(default=112, metadata={"help": "images input size for discrete vae"})
    train_interpolation: str = field(
        default='bicubic', metadata={"help": "Training interpolation (random, bilinear, bicubic)"})
    second_interpolation: str = field(
        default='lanczos', metadata={"help": "Interpolation for discrete vae (random, bilinear, bicubic)"})
    imagenet_default_mean_and_std: bool = field(default=False, metadata={"help": ""})


def main():
    # See all possible arguments in layoutlmft/transformers/training_args.py
    # or by passing the --help flag to this script.
    # We now keep distinct sets of args, for a cleaner separation of concerns.

    parser = HfArgumentParser((ModelArguments, DataTrainingArguments, TrainingArguments))
    if len(sys.argv) == 2 and sys.argv[1].endswith(".json"):
        # If we pass only one argument to the script and it's the path to a json file,
        # let's parse it to get our arguments.
        model_args, data_args, training_args = parser.parse_json_file(json_file=os.path.abspath(sys.argv[1]))
    else:
        model_args, data_args, training_args = parser.parse_args_into_dataclasses()

    if data_args.use_segment_head:
        if training_args.do_train and not data_args.segment_train_predictions_dir:
            raise ValueError(
                "V5 training requires --segment_train_predictions_dir because "
                "gold FUNSD form.id segments are not used."
            )
        if (training_args.do_eval or training_args.do_predict) and not data_args.segment_eval_predictions_dir:
            raise ValueError(
                "V5 evaluation/prediction requires --segment_eval_predictions_dir."
            )

    # Detecting last checkpoint.
    last_checkpoint = None
    if os.path.isdir(training_args.output_dir) and training_args.do_train and not training_args.overwrite_output_dir:
        last_checkpoint = get_last_checkpoint(training_args.output_dir)
        if last_checkpoint is None and len(os.listdir(training_args.output_dir)) > 0:
            raise ValueError(
                f"Output directory ({training_args.output_dir}) already exists and is not empty. "
                "Use --overwrite_output_dir to overcome."
            )
        elif last_checkpoint is not None:
            logger.info(
                f"Checkpoint detected, resuming training at {last_checkpoint}. To avoid this behavior, change "
                "the `--output_dir` or add `--overwrite_output_dir` to train from scratch."
            )

    # Setup logging
    logging.basicConfig(
        format="%(asctime)s - %(levelname)s - %(name)s -   %(message)s",
        datefmt="%m/%d/%Y %H:%M:%S",
        handlers=[logging.StreamHandler(sys.stdout)],
    )
    logger.setLevel(logging.INFO if is_main_process(training_args.local_rank) else logging.WARN)

    # Log on each process the small summary:
    logger.warning(
        f"Process rank: {training_args.local_rank}, device: {training_args.device}, n_gpu: {training_args.n_gpu}"
        + f"distributed training: {bool(training_args.local_rank != -1)}, 16-bits training: {training_args.fp16}"
    )
    # Set the verbosity to info of the Transformers logger (on main process only):
    if is_main_process(training_args.local_rank):
        transformers.utils.logging.set_verbosity_info()
        transformers.utils.logging.enable_default_handler()
        transformers.utils.logging.enable_explicit_format()
    logger.info(f"Training/evaluation parameters {training_args}")

    # ==================================================================
    # V4-det: strict deterministic runtime.
    # IMPORTANT: PYTHONHASHSEED must also be exported in the shell before
    # Python starts; setting it here is too late to change hash randomization.
    # ==================================================================
    import random
    random.seed(training_args.seed)
    np.random.seed(training_args.seed)
    torch.manual_seed(training_args.seed)
    if torch.cuda.is_available():
        torch.cuda.manual_seed(training_args.seed)
        torch.cuda.manual_seed_all(training_args.seed)
        torch.backends.cudnn.deterministic = True
        torch.backends.cudnn.benchmark = False
        if hasattr(torch.backends.cuda, "matmul"):
            torch.backends.cuda.matmul.allow_tf32 = False
        if hasattr(torch.backends.cudnn, "allow_tf32"):
            torch.backends.cudnn.allow_tf32 = False
    try:
        torch.use_deterministic_algorithms(True)
    except Exception as exc:
        logger.warning("Could not enable deterministic algorithms: %s", exc)
    set_seed(training_args.seed)

    if data_args.dataset_name == 'funsd':
        # datasets = load_dataset("nielsr/funsd")
        import layoutlmft.data.funsd
        datasets = load_dataset(os.path.abspath(layoutlmft.data.funsd.__file__), cache_dir=model_args.cache_dir)
    elif data_args.dataset_name == 'cord':
        import layoutlmft.data.cord
        datasets = load_dataset(os.path.abspath(layoutlmft.data.cord.__file__), cache_dir=model_args.cache_dir)
    else:
        raise NotImplementedError()

    if training_args.do_train:
        column_names = datasets["train"].column_names
        features = datasets["train"].features
    else:
        column_names = datasets["test"].column_names
        features = datasets["test"].features

    text_column_name = "words" if "words" in column_names else "tokens"

    label_column_name = (
        f"{data_args.task_name}_tags" if f"{data_args.task_name}_tags" in column_names else column_names[1]
    )

    remove_columns = column_names

    # In the event the labels are not a `Sequence[ClassLabel]`, we will need to go through the dataset to get the
    # unique labels.
    def get_label_list(labels):
        unique_labels = set()
        for label in labels:
            unique_labels = unique_labels | set(label)
        label_list = list(unique_labels)
        label_list.sort()
        return label_list

    if isinstance(features[label_column_name].feature, ClassLabel):
        label_list = features[label_column_name].feature.names
        # No need to convert the labels since they are already ints.
        label_to_id = {i: i for i in range(len(label_list))}
    else:
        label_list = get_label_list(datasets["train"][label_column_name])
        label_to_id = {l: i for i, l in enumerate(label_list)}
    num_labels = len(label_list)

    # Load pretrained model and tokenizer
    #
    # Distributed training:
    # The .from_pretrained methods guarantee that only one local process can concurrently
    # download model & vocab.
    config = AutoConfig.from_pretrained(
        model_args.config_name if model_args.config_name else model_args.model_name_or_path,
        num_labels=num_labels,
        finetuning_task=data_args.task_name,
        cache_dir=model_args.cache_dir,
        revision=model_args.model_revision,
        input_size=data_args.input_size,
        use_auth_token=True if model_args.use_auth_token else None,
        use_hierarchical_position_encoding=model_args.use_hierarchical_position_encoding,
        max_line_position=model_args.max_line_position,
        max_block_position=model_args.max_block_position,
        use_column_encoding=model_args.use_column_encoding,
        max_column_position=model_args.max_column_position,
        use_intra_line_boundary=model_args.use_intra_line_boundary,
        lambda_bound_init=model_args.lambda_bound_init,
        use_semantic_geometry_disentangle=model_args.use_semantic_geometry_disentangle,
        lambda_geo_init=model_args.lambda_geo_init,
        lambda_orth_init=model_args.lambda_orth_init,
    )
    tokenizer = AutoTokenizer.from_pretrained(
        model_args.tokenizer_name if model_args.tokenizer_name else model_args.model_name_or_path,
        tokenizer_file=None,  # avoid loading from a cached file of the pre-trained model in another machine
        cache_dir=model_args.cache_dir,
        use_fast=True,
        add_prefix_space=True,
        revision=model_args.model_revision,
        use_auth_token=True if model_args.use_auth_token else None,
    )
    if getattr(data_args, "use_segment_head", False):
        # V5: predicted-segment contextual fusion in hidden space.
        from layoutlmft.models.layoutlmv3.modeling_layoutlmv3_segment import (
            LayoutLMv3ForSegmentTokenClassification,
        )
        model = LayoutLMv3ForSegmentTokenClassification.from_pretrained(
            model_args.model_name_or_path,
            from_tf=bool(".ckpt" in model_args.model_name_or_path),
            config=config,
            cache_dir=model_args.cache_dir,
            revision=model_args.model_revision,
            use_auth_token=True if model_args.use_auth_token else None,
        )
    else:
        model = AutoModelForTokenClassification.from_pretrained(
            model_args.model_name_or_path,
            from_tf=bool(".ckpt" in model_args.model_name_or_path),
            config=config,
            cache_dir=model_args.cache_dir,
            revision=model_args.model_revision,
            use_auth_token=True if model_args.use_auth_token else None,
        )

    # Tokenizer check: this script requires a fast tokenizer.
    if not isinstance(tokenizer, PreTrainedTokenizerFast):
        raise ValueError(
            "This example script only works for models that have a fast tokenizer. Checkout the big table of models "
            "at https://huggingface.co/transformers/index.html#bigtable to find the model types that meet this "
            "requirement"
        )

    # Preprocessing the dataset
    # Padding strategy
    padding = "max_length" if data_args.pad_to_max_length else False

    if data_args.visual_embed:
        imagenet_default_mean_and_std = data_args.imagenet_default_mean_and_std
        mean = IMAGENET_INCEPTION_MEAN if not imagenet_default_mean_and_std else IMAGENET_DEFAULT_MEAN
        std = IMAGENET_INCEPTION_STD if not imagenet_default_mean_and_std else IMAGENET_DEFAULT_STD
        common_transform = Compose([
            # transforms.ColorJitter(0.4, 0.4, 0.4),
            # transforms.RandomHorizontalFlip(p=0.5),
            RandomResizedCropAndInterpolationWithTwoPic(
                size=data_args.input_size, interpolation=data_args.train_interpolation),
        ])
        patch_transform = transforms.Compose([
            transforms.ToTensor(),
            transforms.Normalize(
                mean=torch.tensor(mean),
                std=torch.tensor(std))
        ])

    # Tokenize all texts and align the labels with them.
    def tokenize_and_align_labels(
        examples,
        augmentation=False,
        segment_predictions_dir=None,
    ):
        tokenized_inputs = tokenizer(
            examples[text_column_name],
            padding=False,
            truncation=True,
            return_overflowing_tokens=True,
            is_split_into_words=True,
        )

        labels = []
        bboxes = []
        images = []
        seg_ids = []
        line_ids_all = []    # NEW
        block_ids_all = []   # NEW
        column_ids_all = []
        entity_ids_all = []

        # Thêm vào tokenize_and_align_labels, cùng chỗ tính label_ids
        def compute_entity_ids(label_ids_aligned, label_list):
            """Gán 1 ID duy nhất cho mỗi entity liên tục, dựa trên chuỗi nhãn thật
            (không suy luận theo số chẵn/lẻ) -> tổng quát cho mọi dataset/label order."""
            entity_ids = []
            current_id = -1
            prev_type = None  # None nghĩa là đang ở "O" hoặc đầu chuỗi
            for lid in label_ids_aligned:
                if lid == -100:
                    entity_ids.append(-1)
                    continue
                label_str = label_list[lid]
                if label_str == "O":
                    entity_ids.append(-1)
                    prev_type = None
                    continue
                prefix, etype = label_str.split("-", 1)  # "B"/"I", "QUESTION"/...
                if prefix == "B" or etype != prev_type:
                    current_id += 1
                entity_ids.append(current_id)
                prev_type = etype
            return entity_ids
        
        # Helper function để tính line_ids từ bbox
        def compute_line_ids(bboxes, y_threshold=10):
            """Gom các token có y_center gần nhau thành cùng 1 dòng"""
            if not bboxes:
                return []
            # Tính y_center của mỗi bbox
            y_centers = [(box[1] + box[3]) / 2 for box in bboxes]
            # Sắp xếp và gom cụm
            lines = []
            current_line = 0
            lines.append(current_line)
            for i in range(1, len(y_centers)):
                if abs(y_centers[i] - y_centers[i-1]) > y_threshold:
                    current_line += 1
                lines.append(current_line)
            return lines
        
        # Helper function để tính block_ids từ bbox
        def compute_block_ids(bboxes, x_threshold=50, y_threshold=30):
            """Gom các token gần nhau thành cùng 1 block (dựa trên khoảng cách XY)"""
            if not bboxes:
                return []
            # Tính center của mỗi bbox
            centers = [((box[0] + box[2]) / 2, (box[1] + box[3]) / 2) for box in bboxes]
            # Gán block ID đơn giản: các token có khoảng cách <= threshold
            blocks = []
            current_block = 0
            blocks.append(current_block)
            for i in range(1, len(centers)):
                # Tính khoảng cách từ token hiện tại đến token trước
                dx = centers[i][0] - centers[i-1][0]
                dy = centers[i][1] - centers[i-1][1]
                if abs(dx) > x_threshold or abs(dy) > y_threshold:
                    current_block += 1
                blocks.append(current_block)
            return blocks
        def compute_column_ids(bboxes, x_threshold=50):
            """Gom các token theo cột dựa trên x_center"""
            if not bboxes:
                return []
            # Tính x_center của mỗi token
            x_centers = [(box[0] + box[2]) / 2 for box in bboxes]
            
            # Sắp xếp các token theo x_center
            columns = []
            current_col = 0
            columns.append(current_col)
            
            for i in range(1, len(x_centers)):
                # Nếu khoảng cách x lớn hơn ngưỡng → cột mới
                if abs(x_centers[i] - x_centers[i-1]) > x_threshold:
                    current_col += 1
                columns.append(current_col)
            return columns
        
        for batch_index in range(len(tokenized_inputs["input_ids"])):
            word_ids = tokenized_inputs.word_ids(batch_index=batch_index)
            org_batch_index = tokenized_inputs["overflow_to_sample_mapping"][batch_index]

            label = examples[label_column_name][org_batch_index]
            bbox = examples["bboxes"][org_batch_index]

            # NEW: Tính line_ids và block_ids cho các token gốc
            line_ids_orig = compute_line_ids(bbox)
            block_ids_orig = compute_block_ids(bbox)
            column_ids_orig = compute_column_ids(bbox, x_threshold=50)

            # -----------------------------------------------------------------
            # V5 segment IDs
            #
            # IMPORTANT: both TRAIN and EVAL/TEST use predicted segments.
            # There is intentionally NO gold form.id path here.
            # The bbox remains word-level and segment membership is an
            # independent input produced by the external segment predictor.
            # -----------------------------------------------------------------
            word_seg_id = None

            if getattr(data_args, "use_segment_head", False):
                if not segment_predictions_dir:
                    raise ValueError(
                        "segment_predictions_dir is required when --use_segment_head "
                        "is enabled. V5 never uses gold FUNSD form.id segments."
                    )

                image_path = examples["image_path"][org_batch_index]
                stem = os.path.splitext(os.path.basename(image_path))[0]
                segment_json = os.path.join(
                    segment_predictions_dir,
                    stem,
                    "segments.json",
                )

                if not os.path.isfile(segment_json):
                    raise FileNotFoundError(
                        "Predicted segment file not found: {}".format(segment_json)
                    )

                with open(segment_json, "r", encoding="utf-8") as f:
                    seg_data = json.load(f)

                word_seg_id = [-1] * len(bbox)
                raw_to_local = {}
                next_local_sid = 0

                for seg in seg_data.get("segments", []):
                    if "segment_id" not in seg:
                        raise ValueError(
                            "Missing segment_id in {}".format(segment_json)
                        )

                    raw_sid = int(seg["segment_id"])
                    if raw_sid not in raw_to_local:
                        raw_to_local[raw_sid] = next_local_sid
                        next_local_sid += 1
                    local_sid = raw_to_local[raw_sid]

                    for wid in seg.get("word_ids", []):
                        wid = int(wid)
                        if not 0 <= wid < len(word_seg_id):
                            raise ValueError(
                                "Invalid word_id={} for {} ({} words)".format(
                                    wid, segment_json, len(word_seg_id)
                                )
                            )
                        if word_seg_id[wid] >= 0 and word_seg_id[wid] != local_sid:
                            raise ValueError(
                                "Word {} is assigned to multiple predicted segments in {}".format(
                                    wid, segment_json
                                )
                            )
                        word_seg_id[wid] = local_sid

                missing = [
                    i for i, sid in enumerate(word_seg_id) if sid < 0
                ]
                if missing:
                    raise ValueError(
                        "Predicted segmentation leaves {} words without segment ID "
                        "for {}. First missing indices: {}".format(
                            len(missing),
                            stem,
                            missing[:20],
                        )
                    )

                if next_local_sid <= 0:
                    raise ValueError(
                        "No valid segments found in {}".format(segment_json)
                    )

            previous_word_idx = None
            label_ids = []
            bbox_inputs = []
            seg_id_inputs = []
            line_ids_aligned = []    # NEW
            block_ids_aligned = []   # NEW
            column_ids_aligned = []
            
            for word_idx in word_ids:
                if word_idx is None:
                    # Special tokens
                    label_ids.append(-100)
                    bbox_inputs.append([0, 0, 0, 0])
                    if word_seg_id is not None:
                        seg_id_inputs.append(-1)
                    line_ids_aligned.append(-1)     # NEW
                    block_ids_aligned.append(-1)    # NEW
                    column_ids_aligned.append(-1)
                elif word_idx != previous_word_idx:
                    # First token of a word
                    label_ids.append(label_to_id[label[word_idx]])
                    bbox_inputs.append(bbox[word_idx])
                    if word_seg_id is not None:
                        seg_id_inputs.append(word_seg_id[word_idx])
                    line_ids_aligned.append(line_ids_orig[word_idx])     # NEW
                    block_ids_aligned.append(block_ids_orig[word_idx])   # NEW
                    column_ids_aligned.append(column_ids_orig[word_idx])
                else:
                    # Subsequent tokens of the same word
                    label_ids.append(label_to_id[label[word_idx]] if data_args.label_all_tokens else -100)
                    bbox_inputs.append(bbox[word_idx])
                    if word_seg_id is not None:
                        seg_id_inputs.append(word_seg_id[word_idx])
                    line_ids_aligned.append(line_ids_orig[word_idx])     # NEW
                    block_ids_aligned.append(block_ids_orig[word_idx])   # NEW
                    column_ids_aligned.append(column_ids_orig[word_idx])
                previous_word_idx = word_idx
                
            labels.append(label_ids)
            bboxes.append(bbox_inputs)
            if word_seg_id is not None:
                seg_ids.append(seg_id_inputs)
            line_ids_all.append(line_ids_aligned)     # NEW
            block_ids_all.append(block_ids_aligned)   # NEW
            column_ids_all.append(column_ids_aligned)

            entity_ids_aligned = compute_entity_ids(label_ids, label_list)  # NEW
            entity_ids_all.append(entity_ids_aligned)

            if data_args.visual_embed:
                ipath = examples["image_path"][org_batch_index]
                img = pil_loader(ipath)
                for_patches, _ = common_transform(img, augmentation=augmentation)
                patch = patch_transform(for_patches)
                images.append(patch)

        tokenized_inputs["labels"] = labels
        tokenized_inputs["bbox"] = bboxes
        tokenized_inputs["line_ids"] = line_ids_all    # NEW
        tokenized_inputs["block_ids"] = block_ids_all  # NEW
        tokenized_inputs["column_ids"] = column_ids_all
        tokenized_inputs["entity_ids"] = entity_ids_all  # NEW

        if getattr(data_args, "use_segment_head", False):
            tokenized_inputs["seg_id"] = seg_ids
        if data_args.visual_embed:
            tokenized_inputs["images"] = images

        return tokenized_inputs

    if training_args.do_train:
        if "train" not in datasets:
            raise ValueError("--do_train requires a train dataset")
        train_dataset = datasets["train"]
        if data_args.max_train_samples is not None:
            train_dataset = train_dataset.select(range(data_args.max_train_samples))
        train_dataset = train_dataset.map(
            tokenize_and_align_labels,
            batched=True,
            remove_columns=remove_columns,
            num_proc=data_args.preprocessing_num_workers,
            # Segment IDs come from external predicted segmentation; never use gold form.id.
            load_from_cache_file=False if data_args.use_segment_head else not data_args.overwrite_cache,
            fn_kwargs={
                "segment_predictions_dir": data_args.segment_train_predictions_dir
                if data_args.use_segment_head else None,
            },
        )
        

    if training_args.do_eval:
        validation_name = "test"
        if validation_name not in datasets:
            raise ValueError("--do_eval requires a validation dataset")
        eval_dataset = datasets[validation_name]
        if data_args.max_val_samples is not None:
            eval_dataset = eval_dataset.select(range(data_args.max_val_samples))
        eval_dataset = eval_dataset.map(
            tokenize_and_align_labels,
            batched=True,
            remove_columns=remove_columns,
            num_proc=data_args.preprocessing_num_workers,
            load_from_cache_file=False if data_args.use_segment_head else not data_args.overwrite_cache,
            fn_kwargs={
                "segment_predictions_dir": data_args.segment_eval_predictions_dir
                if data_args.use_segment_head else None,
            },
        )

    if training_args.do_predict:
        if "test" not in datasets:
            raise ValueError("--do_predict requires a test dataset")
        test_dataset = datasets["test"]
        if data_args.max_test_samples is not None:
            test_dataset = test_dataset.select(range(data_args.max_test_samples))
        test_dataset = test_dataset.map(
            tokenize_and_align_labels,
            batched=True,
            remove_columns=remove_columns,
            num_proc=data_args.preprocessing_num_workers,
            load_from_cache_file=False if data_args.use_segment_head else not data_args.overwrite_cache,
            fn_kwargs={
                "segment_predictions_dir": data_args.segment_eval_predictions_dir
                if data_args.use_segment_head else None,
            },
        )

    # Data collator
    data_collator = DataCollatorForKeyValueExtraction(
        tokenizer,
        pad_to_multiple_of=8 if training_args.fp16 else None,
        padding=padding,
        max_length=512,
    )

    # Metrics
    metric = load_metric("seqeval")

    def compute_metrics(p):
        predictions, labels = p
        predictions = np.argmax(predictions, axis=2)

        # Remove ignored index (special tokens)
        true_predictions = [
            [label_list[p] for (p, l) in zip(prediction, label) if l != -100]
            for prediction, label in zip(predictions, labels)
        ]
        true_labels = [
            [label_list[l] for (p, l) in zip(prediction, label) if l != -100]
            for prediction, label in zip(predictions, labels)
        ]

        results = metric.compute(predictions=true_predictions, references=true_labels)
        if data_args.return_entity_level_metrics:
            # Unpack nested dictionaries
            final_results = {}
            for key, value in results.items():
                if isinstance(value, dict):
                    for n, v in value.items():
                        final_results[f"{key}_{n}"] = v
                else:
                    final_results[key] = value
            return final_results
        else:
            return {
                "precision": results["overall_precision"],
                "recall": results["overall_recall"],
                "f1": results["overall_f1"],
                "accuracy": results["overall_accuracy"],
            }
    # ------------------------------------------------------------------
    # V5 optimizer: avoid the previous 5e-4 classifier LR.
    #
    # Backbone + original token classifier use the normal fine-tuning LR.
    # Only the new segment modules use a moderately larger LR.
    # ------------------------------------------------------------------
    class CustomTrainer(Trainer):
        def create_optimizer(self):
            if self.optimizer is None:
                backbone_params = []
                classifier_params = []
                segment_params = []

                for name, param in self.model.named_parameters():
                    if not param.requires_grad:
                        continue
                    if name.startswith("layoutlmv3."):
                        backbone_params.append(param)
                    elif name.startswith("classifier.") or name.startswith("dropout."):
                        classifier_params.append(param)
                    elif (
                        name.startswith("segment_context.")
                        or name.startswith("segment_position_embedding.")
                        or name.startswith("segment_fusion_gate.")
                        or name.startswith("segment_residual.")
                    ):
                        segment_params.append(param)
                    else:
                        # Keep any future non-segment model parameter at the
                        # normal fine-tuning LR rather than silently applying
                        # the old 5e-4 LR.
                        classifier_params.append(param)

                optimizer_grouped_parameters = []

                if backbone_params:
                    optimizer_grouped_parameters.append(
                        {"params": backbone_params, "lr": self.args.learning_rate}
                    )
                if classifier_params:
                    optimizer_grouped_parameters.append(
                        {
                            "params": classifier_params,
                            "lr": self.args.learning_rate,
                        }
                    )
                if segment_params:
                    optimizer_grouped_parameters.append(
                        {
                            "params": segment_params,
                            "lr": self.args.learning_rate * 5.0,
                        }
                    )

                self.optimizer = torch.optim.AdamW(
                    optimizer_grouped_parameters,
                    betas=(self.args.adam_beta1, self.args.adam_beta2),
                    eps=self.args.adam_epsilon,
                )
            return self.optimizer

    # Khởi tạo Trainer bằng CustomTrainer vừa tạo thay vì Trainer mặc định
    trainer = CustomTrainer(
        model=model,
        args=training_args,
        train_dataset=train_dataset if training_args.do_train else None,
        eval_dataset=eval_dataset if training_args.do_eval else None,
        tokenizer=tokenizer,
        data_collator=data_collator,
        compute_metrics=compute_metrics,
    )
    # Initialize our Trainer
    # trainer = Trainer(
    #     model=model,
    #     args=training_args,
    #     train_dataset=train_dataset if training_args.do_train else None,
    #     eval_dataset=eval_dataset if training_args.do_eval else None,
    #     tokenizer=tokenizer,
    #     data_collator=data_collator,
    #     compute_metrics=compute_metrics,
    # )

    # Training
    if training_args.do_train:
        checkpoint = last_checkpoint if last_checkpoint else None
        train_result = trainer.train(resume_from_checkpoint=checkpoint)
        metrics = train_result.metrics
        trainer.save_model()  # Saves the tokenizer too for easy upload

        max_train_samples = (
            data_args.max_train_samples if data_args.max_train_samples is not None else len(train_dataset)
        )
        metrics["train_samples"] = min(max_train_samples, len(train_dataset))

        trainer.log_metrics("train", metrics)
        trainer.save_metrics("train", metrics)
        trainer.save_state()

    # Evaluation
    if training_args.do_eval:
        logger.info("*** Evaluate ***")

        metrics = trainer.evaluate()

        max_val_samples = data_args.max_val_samples if data_args.max_val_samples is not None else len(eval_dataset)
        metrics["eval_samples"] = min(max_val_samples, len(eval_dataset))

        trainer.log_metrics("eval", metrics)
        trainer.save_metrics("eval", metrics)

    # Predict
    if training_args.do_predict:
        logger.info("*** Predict ***")

        predictions, labels, metrics = trainer.predict(test_dataset)
        predictions = np.argmax(predictions, axis=2)

        # Remove ignored index (special tokens)
        true_predictions = [
            [label_list[p] for (p, l) in zip(prediction, label) if l != -100]
            for prediction, label in zip(predictions, labels)
        ]

        trainer.log_metrics("test", metrics)
        trainer.save_metrics("test", metrics)

        # Save predictions
        output_test_predictions_file = os.path.join(training_args.output_dir, "test_predictions.txt")
        if trainer.is_world_process_zero():
            with open(output_test_predictions_file, "w") as writer:
                for prediction in true_predictions:
                    writer.write(" ".join(prediction) + "\n")


def _mp_fn(index):
    # For xla_spawn (TPUs)
    main()


if __name__ == "__main__":
    main()
