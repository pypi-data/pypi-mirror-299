import logging
import sys
import uuid
from collections import defaultdict
from contextlib import contextmanager
from dataclasses import dataclass, replace
from statistics import mean
from typing import Callable, Type, cast

import numpy as np
import plotly.graph_objects as go
import torch
import torch.nn as nn
from PIL import Image
from plotly.subplots import make_subplots
from safetensors import safe_open
from safetensors.torch import load_file, save_file
from tqdm.auto import tqdm

from orcalib.curate._tracking import (
    FeedbackKind,
    RunId,
    generate_run_ids,
    record_memory_weights,
    record_model_feedback,
    record_model_input_output,
)
from orcalib.rac.common import (
    DatasetLike,
    EvalResult,
    InputType,
    LabeledMemoryLookup,
    LabeledMemoryLookupResult,
    PredictionResult,
)
from orcalib.rac.embedding_models import EmbeddingModel
from orcalib.rac.head_models import RACHeadInitConfig, RACHeadProtocol, SimpleMMOEHead
from orcalib.rac.memoryset import LabeledMemoryset
from orcalib.rac.metrics import (
    AnalyzeResult,
    aggregate_memory_stats,
    analyze_result,
    compute_prediction_metrics,
)
from orcalib.rac.util import format_dataset
from orcalib.rac.visualization import print_memories_table, visualize_explain


@dataclass(frozen=True)
class TrainingConfig:
    lr: float = 1e-4
    epochs: int = 1
    batch_size: int = 32


class RACModel(nn.Module):
    def __init__(
        self,
        num_classes: int,
        *,
        embedding_model: EmbeddingModel = EmbeddingModel.CLIP_BASE,
        head: Type[RACHeadProtocol] = SimpleMMOEHead,
        memory_width_override: int | None = None,
        memoryset: LabeledMemoryset | None = None,
        cross_encoder_model: str | None = None,
    ):
        # TODO: Support model run configuration like dtype and device (automagic with overrides)
        super(RACModel, self).__init__()
        if memory_width_override is None:
            self.mmoe_width = min(num_classes * 2, 50)
        else:
            self.mmoe_width = memory_width_override

        self.memoryset = memoryset
        self.base_model = embedding_model
        # Set up the logger
        logging.basicConfig(level=logging.INFO)
        self.logger = logging.getLogger(__name__)
        self.orca_model = head(
            RACHeadInitConfig(
                embedding_dim=embedding_model.embedding_dim,
                num_classes=num_classes,
                cross_encoder_model=cross_encoder_model,
            )
        )
        if not isinstance(self.orca_model, nn.Module):
            raise ValueError("Head model must be an instance of nn.Module")

    def forward(
        self,
        input_embeddings: torch.Tensor,
        memory_embeddings: list[list[torch.Tensor]],
        memory_labels: list[list[int]],
        original_input: list[InputType],
        original_memories: list[list[InputType]],
    ) -> torch.Tensor:
        assert isinstance(self.orca_model, nn.Module)
        return self.orca_model.forward(
            input_embeddings=torch.Tensor(input_embeddings),
            memory_embeddings=memory_embeddings,
            memory_labels=memory_labels,
            original_input=original_input,
            original_memories=original_memories,
        )

    def _record_curate_data(
        self,
        inpts: list[InputType],
        expected_labels: list[int],
        run_ids: list[RunId],
        memory_ids: list[list[int]],
        predicted_labels: list[int],
        logits,
        feedback_callback,
    ):
        assert self.memoryset
        # record memory weights
        if self.orca_model.last_memory_weights is not None:
            mem_ids = [m_id for memory_ids_list in memory_ids for m_id in memory_ids_list]

            record_memory_weights(
                self.memoryset.database_name,
                "rac_lookup",
                run_ids=[run_id for run_id in run_ids for _ in range(len(memory_ids[0]))],
                memory_ids=mem_ids,  # type: ignore -- we assert all None not in list
                memory_weights=self.orca_model.last_memory_weights.flatten().tolist(),
            )

        # record input-output and feedback
        record_model_input_output(
            self.memoryset.database_name,
            run_ids,
            [
                {
                    "example": "IMAGE" if isinstance(txt, Image.Image) else txt,
                    "label": lbl,
                }  # TODO: figure out how to save images in JSON
                for txt, lbl in zip(inpts, expected_labels)
            ],
            [{"label": lbl, "logits": lgts} for lbl, lgts in zip(predicted_labels, logits.tolist())],
        )

        # record feedback
        record_model_feedback(
            self.memoryset.database_name,
            run_ids,
            [
                (e == p) if feedback_callback is None else feedback_callback(e, p)
                for e, p in zip(expected_labels, predicted_labels)
            ],
            "correct",
            FeedbackKind.BINARY,
        )

    def predict(
        self,
        inpt: InputType,
        expected_label: int | None = None,
        log: bool = False,
        curate: bool = False,
        feedback_callback: Callable[[int, int], float | int | bool] | None = None,
    ) -> PredictionResult:
        return self.predict_batch(
            [inpt],
            [expected_label] if expected_label else None,
            log=log,
            curate=curate,
            feedback_callback=feedback_callback,
        )[0]

    def predict_batch(
        self,
        inpts: list[InputType],
        expected_labels: list[int] | None = None,
        log: bool = False,
        curate: bool = True,
        feedback_callback: Callable[[int, int], float | int | bool] | None = None,
    ) -> list[PredictionResult]:
        if self.memoryset is None:
            raise ValueError("No memoryset attached to the model (use `attach` method)")
        if self.memoryset.model != self.base_model:
            raise ValueError(
                f"Model mismatch between RAC and LabeledMemoryset: {self.base_model.value} != {self.memoryset.model.value}"
            )

        # compute input embedding
        input_embeddings = self.base_model._get_embedding(inpts, show_progress_bar=log)

        # lookup memories
        if self.orca_model.model_properties.needs_memories:
            run_ids = (
                generate_run_ids(
                    self.memoryset.database_name,
                    len(inpts),
                    model_id=self.base_model.name,
                    tags=set(),
                    metadata=dict(),
                )
                if curate and expected_labels and self.memoryset.mode == "hosted"
                else None
            )

            lookup_results = self.memoryset.lookup(input_embeddings, k=self.mmoe_width, run_ids=run_ids)

            memory_embeddings = [
                [torch.Tensor(memory.embedding) for memory in lookup_result] for lookup_result in lookup_results
            ]
            memory_labels = [[memory.label for memory in lookup_result] for lookup_result in lookup_results]
            memory_ids = [[memory.memory_id for memory in lookup_result] for lookup_result in lookup_results]
        else:
            run_ids = None
            # TODO: reconsider if using None might be better than using empty lists here
            lookup_results = []
            memory_embeddings = []
            memory_labels = []

        if self.orca_model.model_properties.needs_original_data:
            original_input = inpts
        else:
            original_input = []

        if self.orca_model.model_properties.needs_original_data and self.orca_model.model_properties.needs_memories:
            original_memories = [[memory.value for memory in lookup_result] for lookup_result in lookup_results]
        else:
            original_memories = []

        logits = self.forward(
            input_embeddings=torch.Tensor(input_embeddings),
            memory_embeddings=memory_embeddings,
            memory_labels=memory_labels,
            original_input=original_input,
            original_memories=original_memories,
        )

        predicted_labels = logits.argmax(dim=-1).tolist()

        if run_ids:
            self._record_curate_data(
                inpts, expected_labels, run_ids, memory_ids, predicted_labels, logits, feedback_callback  # type: ignore -- expected_labels is not None b/c run_ids would be None if it was
            )

        # build prediction results from the logits
        prediction_results = []
        for i, logit in enumerate(logits):
            prediction_results.append(
                PredictionResult(
                    label=int(torch.argmax(logit).item()),
                    confidence=torch.max(logit).item(),  # TODO: normalize this for easier interpretability
                    memories=(lookup_results[i] if self.orca_model.model_properties.needs_memories else []),
                    feedback=feedback_callback,
                    logits=logit,
                )
            )
        return prediction_results

    def attach(self, memoryset: LabeledMemoryset):
        # TODO(p2): support separate/different retrieval and predict models
        if memoryset.model.value != self.base_model.value:
            raise ValueError(
                f"Model mismatch between RAC and LabeledMemoryset: {self.base_model.value} != {memoryset.model.value}"
            )
        self.memoryset = memoryset

    def evaluate(
        self,
        dataset: DatasetLike | LabeledMemoryset,
        log: bool = False,
        batch_size: int = 64,
        curate: bool = True,
    ) -> EvalResult:
        """
        Benchmarks the model on the given dataset returning a bunch of different metrics.

        For dict-like or list of dict-like datasets, there must be a `label` key and one of the following keys: `text`, `image`, or `value`.
        If there are only two keys and one is `label`, the other will be inferred to be `value`.

        For list-like datasets, the first element of each tuple must be the value and the second must be the label.
        """
        if isinstance(dataset, LabeledMemoryset):
            dataset = dataset.get_all_memories()
        # This enforces that all dataset have at least value and label columns
        formatted_dataset = format_dataset(dataset, log)

        self.logger.info("Evaluating model") if log else None

        examples = [data[0] for data in formatted_dataset]
        expected_labels = [data[1] for data in formatted_dataset]

        # run batch prediction with batch_size
        predictions: list[tuple[int, torch.Tensor]] = []
        with torch.no_grad():
            for i in tqdm(range(0, len(formatted_dataset), batch_size), desc="Batch Predictions", disable=not log):
                predictions.extend(
                    [
                        (pred.label, pred.logits)
                        for pred in self.predict_batch(
                            examples[i : i + batch_size], expected_labels[i : i + batch_size], log=False, curate=curate
                        )
                    ]
                )

        self.logger.info("Computing Metrics") if log else None

        # Calculate metrics
        metrics = compute_prediction_metrics(predictions, expected_labels)
        return metrics

    def evaluate_and_explain(
        self,
        dataset: DatasetLike | LabeledMemoryset,
        log: bool = False,
        plot: bool = False,
        curate: bool = True,
    ) -> tuple[EvalResult, dict[int, LabeledMemoryLookupResult]]:
        """
        Benchmarks the model on the given dataset returning a bunch of different metrics.

        For dict-like or list of dict-like datasets, there must be a `label` key and one of the following keys: `text`, `image`, or `value`.
        If there are only two keys and one is `label`, the other will be inferred to be `value`.

        For list-like datasets, the first element of each tuple must be the value and the second must be the label.
        """

        if isinstance(dataset, LabeledMemoryset):
            dataset = dataset.get_all_memories()
        formatted_dataset = format_dataset(dataset, log)

        # Batch create predictions from the formatted dataset
        self.logger.info("Evaluating model") if log else None

        predictions: list[PredictionResult] = []
        predictions = self.predict_batch(
            [data[0] for data in formatted_dataset], [data[1] for data in formatted_dataset], log=log, curate=curate
        )
        explanations = []
        for prediction in predictions:
            explanations.append(self.explain(prediction))

        # map through a list of stats and aggregate memory stats
        memory_stats = []
        label_stats = []
        for explanation in explanations:
            if explanation is not None:
                for memory_stat in explanation.memory_stats:
                    memory_stats.append(memory_stat)
                for label_stat in explanation.label_stats:
                    label_stats.append(label_stat)

        # Initialize dict to hold lists of scores by label
        memory_scores_by_label = defaultdict(lambda: {"lookup_scores": [], "attention_weights": []})

        for stat in memory_stats:
            # Check if stat is a dictionary and process accordingly
            if isinstance(stat, dict):
                label = stat.get("label")
                if label is not None:
                    memory_scores_by_label[label]["lookup_scores"].append(stat.get("lookup_score", 0))
                    memory_scores_by_label[label]["attention_weights"].append(stat.get("attention_weight", 0))

        # Function to calculate min, max, and median
        def calculate_stats(values):
            return {"min": min(values), "max": max(values), "median": np.median(values)}

        # Calculate stats for each label
        stats_by_label = {}
        for label, scores in memory_scores_by_label.items():
            stats_by_label[label] = {
                "count": len(scores["lookup_scores"]),
                "lookup_scores": calculate_stats(scores["lookup_scores"]),
                "attention_weights": calculate_stats(scores["attention_weights"]),
            }
        mem_stats = aggregate_memory_stats(predictions, formatted_dataset, plot)

        correct_labels = [data[1] for data in formatted_dataset]
        prediction_tuples = [(pred.label, pred.logits) for pred in predictions]
        self.logger.info("Computing Metrics") if log else None
        metrics = compute_prediction_metrics(prediction_tuples, correct_labels)
        self.logger.info("metrics: %s", metrics) if log else None
        return (metrics, mem_stats)

    def inspect_last_run(
        self,
    ):
        """Displays information about the memories accessed during the last run (incl weights etc.)"""
        raise NotImplementedError()

    def explain(
        self,
        prediction_result: PredictionResult | None = None,
        inpt: InputType | None = None,
        interactive: bool = False,
        plot: bool = False,
        pretty_print: bool = False,
    ) -> AnalyzeResult | None:
        """Like `predict` but instead of the prediction result, returns an explanation of the prediction (accessed memories etc.)

        :param inpt: The input to explain
        :param plot: If True, will display graphs via matplotlib
        :param pretty_print: If True, will return a pretty printed string of the explanation. If False, will return a dictionary
        :param interactive: DISABLED - ~~If True, will display the explanation in an interactive way (e.g. with a GUI)~~
        """
        if inpt is None and prediction_result is None:
            raise ValueError("Either result or inpt must be provided")
        if prediction_result is None and inpt is not None:
            result = self.predict(inpt, curate=False)
        else:
            result = prediction_result

        if result is None:
            raise ValueError("No result to analyze")
        analysis = analyze_result(result)
        visualize_explain(analysis) if plot else None
        if pretty_print:
            self.logger.info(print_memories_table(analysis))
        elif not plot:
            return analysis

    def finetune(
        self,
        dataset: DatasetLike,
        log: bool = True,
        config: TrainingConfig = TrainingConfig(),
        plot: bool = True,
        show_running_mean: bool = False,
        validation_dataset: DatasetLike | None = None,
        **kwargs,
    ):
        """Fine-tunes the model on a given dataset."""
        self.logger.info("Starting fine-tuning") if log else None
        assert isinstance(self.orca_model, nn.Module)
        # Generate a new UUID at the start of finetune
        current_finetune_uuid = str(uuid.uuid4())

        config = replace(config, **kwargs)

        # Initialize lists to store batch numbers and loss values
        fractional_epochs = []
        loss_values = []
        mean_loss_values = []
        total_loss_values = []
        batch_count = 0
        validation_scores = []
        stop_early = False

        if plot:
            fig = make_subplots(specs=[[{"secondary_y": False}]])

            # Add traces
            # loss_trace
            fig.add_trace(
                go.Scatter(
                    name="Loss",
                    mode="markers",
                    marker={
                        "size": 5,
                        "color": "rgba( 0,0, 255,0.5)",
                    },
                ),
            )
            # mean_loss_trace
            fig.add_trace(
                go.Scatter(
                    mode="lines",
                    name="Mean Loss" if show_running_mean else "Trailing Mean Loss",
                    line=dict(
                        color="blue",
                        width=2,
                    ),
                ),
            )
            # validation_loss_trace
            fig.add_trace(
                go.Scatter(
                    mode="lines",
                    name="Validation Loss",
                    line=dict(
                        color="green",
                        width=2,
                    ),
                ),
            )

            # Update layout
            fig.update_layout(
                height=600,
                xaxis=dict(title="Epoch"),
                yaxis=dict(title="Loss"),
                title="Training Loss per Epoch",
                legend=dict(x=0.01, y=0.99),
            )

            # Display the figure
            fig_widget = go.FigureWidget(fig)
            if "ipykernel" in sys.modules:
                from IPython.display import display

                display(fig_widget)
        else:
            fig_widget = None

        # Set up optimizer and loss function
        optimizer = torch.optim.Adam(self.orca_model.parameters(), lr=config.lr)  # type: ignore
        loss_function = nn.CrossEntropyLoss()

        # Format dataset for training
        formatted_dataset = format_dataset(dataset, log)
        num_batches = len(formatted_dataset) // config.batch_size

        inferred_device = next(self.orca_model.parameters()).device
        # Training loop
        for epoch in range(config.epochs):
            total_loss = 0.0
            self.logger.info(f"Epoch {epoch + 1}/{config.epochs}") if log else None
            if stop_early:
                self.logger.info("Stopping Early") if log else None
                break
            for i in tqdm(range(num_batches), desc=f"Finetuning Epoch:{epoch + 1}", disable=not log):
                # Batch preparation
                batch_data = formatted_dataset[i * config.batch_size : (i + 1) * config.batch_size]
                labels = torch.LongTensor([data[1] for data in batch_data])

                # Move tensors to the appropriate device
                inputs = [data[0] for data in batch_data]
                labels = labels.to(inferred_device)

                # Reset gradients
                optimizer.zero_grad()

                # Forward pass: get predictions
                predictions = self.predict_batch(inputs, log=False, curate=False)

                # Extract logits from PredictionResult and stack them
                logits = torch.stack([torch.Tensor(pred.logits).to(inferred_device) for pred in predictions])

                # Compute loss
                loss = loss_function(logits, labels)
                total_loss += loss.item()

                if plot:
                    # Update data lists
                    fractional_epochs.append((batch_count + 1) / num_batches)
                    loss_values.append(loss.item())
                    total_loss_values.append(total_loss)
                    if show_running_mean:
                        mean_loss_values.append(mean(loss_values))
                    else:
                        mean_loss_values.append(mean(loss_values[-10:]))

                    # Update the data in the plot
                    if fig_widget:
                        # Add vertical line to indicate the start of a new epoch
                        if (batch_count + 1) % num_batches == 0 and batch_count != 0:
                            fig_widget.add_vline(
                                x=int((batch_count + 1) / num_batches),
                                line_color="rgba(0,0,0,0.25)",
                            )
                        with fig_widget.batch_update():
                            fig_widget.data[0].x = fractional_epochs  # type: ignore - fig_widget.data[0] is a Scatter object. It has an 'x' attribute
                            fig_widget.data[0].y = loss_values  # type: ignore
                            fig_widget.data[1].x = fractional_epochs  # type: ignore
                            fig_widget.data[1].y = mean_loss_values  # type: ignore
                            fig_widget.data[2].x = list(range(1, len(validation_scores) + 1))  # type: ignore
                            fig_widget.data[2].y = validation_scores  # type: ignore
                            fig_widget.update_layout(xaxis=dict(title=f"Epoch: {epoch + 1}/{config.epochs}"))

                # Backward pass and optimization
                loss.backward()

                optimizer.step()
                batch_count += 1

            avg_loss = total_loss / num_batches
            self.logger.info(f"Epoch {epoch + 1}, Loss: {avg_loss:.4f}") if log else None
            # run eval on validation set (when present) & record results
            if validation_dataset is not None:
                eval_result = self.evaluate(validation_dataset, log=log, curate=False)
                if validation_scores and eval_result.loss > validation_scores[-1]:
                    stop_early = True
                    self.logger.info(f"Stopping Early: {eval_result.loss} > {validation_scores[-1]}") if log else None
                    validation_scores.append(eval_result.loss)
                    # Update the plot before breaking
                    if fig_widget:
                        with fig_widget.batch_update():
                            fig_widget.data[2].x = list(range(1, len(validation_scores) + 1))  # type: ignore
                            fig_widget.data[2].y = validation_scores  # type: ignore
                        fig_widget.add_vline(
                            x=int((batch_count + 1) / num_batches),
                            line_color="rgba(255,0,0,0.25)",
                        )
                    self.load(f"finetune-{current_finetune_uuid}.pth")
                else:
                    validation_scores.append(eval_result.loss)
                    self.save(f"finetune-{current_finetune_uuid}.pth")

        self.logger.info("Fine-tuning completed") if log else None

    def save(self, path: str):
        """Saves the model to a file using safetensors"""
        assert isinstance(self.orca_model, nn.Module)

        # Prepare the state dict
        state_dict = self.orca_model.state_dict()
        # Convert non-contiguous tensors to contiguous tensors in the state dict
        contiguous_state_dict = {k: v.contiguous() if not v.is_contiguous() else v for k, v in state_dict.items()}

        # Prepare metadata
        metadata = {
            "head_model": self.orca_model.model_properties.name,
            "embedding_model": self.base_model.value,
            "head_model_version": self.orca_model.model_properties.version,
            "embedding_model_version": self.base_model.version,
        }

        # Convert all metadata values to strings
        metadata = {k: str(v) for k, v in metadata.items()}

        # Save using safetensors
        save_file(contiguous_state_dict, path, metadata=metadata)

        self.logger.info("Model saved successfully using safetensors")

    def load(self, path: str):
        """Loads a model from a safetensors file, verifying that the model is compatible with the current instance"""
        # Load the state dict and metadata using safetensors
        state_dict = load_file(path)
        metadata = safe_open(path, framework="pt").metadata()  # type: ignore - metadata is present

        # Verify model compatibility
        if metadata["head_model"] != self.orca_model.model_properties.name:
            raise ValueError(
                f"Head Model mismatch: {metadata['head_model']} != {self.orca_model.model_properties.name}"
            )
        if metadata["embedding_model"] != self.base_model.value:
            raise ValueError(f"Embedding Model mismatch: {metadata['embedding_model']} != {self.base_model.value}")
        if metadata["head_model_version"] != str(self.orca_model.model_properties.version):
            raise ValueError(
                f"Head Model version mismatch: {metadata['head_model_version']} != {self.orca_model.model_properties.version}"
            )
        if metadata["embedding_model_version"] != str(self.base_model.version):
            raise ValueError(
                f"Embedding Model version mismatch: {metadata['embedding_model_version']} != {self.base_model.version}"
            )

        # Load the state dict into the model
        assert isinstance(self.orca_model, nn.Module)
        self.orca_model.load_state_dict(state_dict)
        self.logger.info("Model loaded successfully from safetensors file")

    def use(self, memoryset: LabeledMemoryset):
        @contextmanager
        def ctx_manager():
            previous_memoryset = self.memoryset
            try:
                self.attach(memoryset)
                yield
            finally:
                if previous_memoryset:
                    self.attach(previous_memoryset)

        return ctx_manager()
