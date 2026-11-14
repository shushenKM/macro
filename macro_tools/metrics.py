"""Classification metrics and terminal reports with a fixed class ordering.

Reports display scores as percentages and confusion-matrix entries as counts.
Confusion-matrix rows are true gestures; columns are predicted gestures.
"""

import math
import operator
from statistics import mean, pstdev
from macro_tools.tasks import split_joint_label

def _label(value):
    if not isinstance(value, str) or not value.strip():
        raise ValueError("Every gesture label must be a nonempty string.")
    return value.strip()


def validate_label_mapping(mapping):
    """Require canonical names and unique contiguous integer indices from zero."""
    if not isinstance(mapping, dict) or not mapping:
        raise ValueError("The label mapping must be a nonempty dictionary.")
    for name, index in mapping.items():
        if _label(name) != name:
            raise ValueError("Mapping keys must have no surrounding whitespace.")
        if type(index) is not int:
            raise ValueError("Class indices must be integers, excluding booleans.")
    if sorted(mapping.values()) != list(range(len(mapping))):
        raise ValueError("Class indices must be unique and contiguous from zero.")
    return mapping



def _indices(values, class_count, name):
    output = []
    for value in values:
        if isinstance(value, bool):
            raise ValueError("{} must contain integer class indices, excluding booleans.".format(name))
        try:
            index = operator.index(value)
        except TypeError as exc:
            raise ValueError("{} must contain integer class indices.".format(name)) from exc
        if not 0 <= index < class_count:
            raise ValueError("Unknown class index {} in {}.".format(index, name))
        output.append(int(index))
    return output


def classification_metrics(y_true, y_pred, label_mapping, *, _components=True):
    """Calculate accuracy/F1 and a confusion matrix over every mapped class.

    Rows in the confusion matrix are true labels; columns are predicted labels.
    An absent class receives zero precision, recall, and F1 and still contributes
    to macro-F1. This keeps comparisons consistent across folds and modalities.
    """
    validate_label_mapping(label_mapping)
    names = [name for name, _ in sorted(label_mapping.items(), key=lambda item: item[1])]
    size = len(names)
    actual = _indices(y_true, size, "y_true")
    predicted = _indices(y_pred, size, "y_pred")
    if not actual or len(actual) != len(predicted):
        raise ValueError("y_true and y_pred must be nonempty and have the same length.")
    confusion = [[0] * size for _ in range(size)]
    for truth, prediction in zip(actual, predicted):
        confusion[truth][prediction] += 1
    per_class = {}
    for index, name in enumerate(names):
        true_positive = confusion[index][index]
        support = sum(confusion[index])
        predicted_count = sum(row[index] for row in confusion)
        precision = true_positive / predicted_count if predicted_count else 0.0
        recall = true_positive / support if support else 0.0
        f1 = 2 * precision * recall / (precision + recall) if precision + recall else 0.0
        per_class[name] = {
            "index": index, "precision": precision, "recall": recall,
            "f1": f1, "support": support,
        }
    total = len(actual)
    result = {
        "accuracy": sum(confusion[index][index] for index in range(size)) / total,
        "macro_f1": sum(values["f1"] for values in per_class.values()) / size,
        "weighted_f1": sum(values["f1"] * values["support"] for values in per_class.values()) / total,
        "per_class": per_class, "confusion_matrix": confusion,
        "class_names": names, "sample_count": total,
    }
    if _components and all("::object=" in name for name in names):
        pairs = [split_joint_label(name) for name in names]
        result["task"] = "gesture_object"
        result["component_metrics"] = {}
        for column, component in enumerate(("gesture", "object")):
            vocabulary = sorted({pair[column] for pair in pairs})
            mapping = {name: index for index, name in enumerate(vocabulary)}
            remap = [mapping[pair[column]] for pair in pairs]
            result["component_metrics"][component] = classification_metrics(
                [remap[index] for index in actual], [remap[index] for index in predicted],
                mapping, _components=False)
    return result


def aggregate_fold_metrics(fold_metrics):
    """Return unweighted mean/population SD across completed fold metrics.

    Every participant fold has equal weight. Pooled predictions, when needed,
    should be supplied separately to ``classification_metrics``.
    """
    folds = list(fold_metrics)
    if not folds:
        raise ValueError("Cannot aggregate an empty collection of fold metrics.")
    summary = {"fold_count": len(folds)}
    for metric in ("accuracy", "macro_f1", "weighted_f1"):
        values = [fold[metric] for fold in folds]
        if any(isinstance(value, bool) or not isinstance(value, (int, float)) or not math.isfinite(value) for value in values):
            raise ValueError("Fold {} values must be finite numbers.".format(metric))
        summary[metric] = {"mean": mean(values), "std": pstdev(values)}
    if all("component_metrics" in fold for fold in folds):
        summary["component_metrics"] = {
            key: aggregate_fold_metrics(fold["component_metrics"][key] for fold in folds)
            for key in ("gesture", "object")
        }
    return summary


def format_fold_summary(results, aggregate=None):
    """Show final test scores for each independently trained fold and their mean.

Each fold has equal weight. In leave-one-subject-out evaluation this is also an
equal-participant average. SD is the population standard deviation across folds,
not a confidence interval; a fixed multi-subject test group is only one fold.
    """
    results = list(results)
    aggregate = aggregate_fold_metrics(r["test_metrics"] for r in results) if aggregate is None else aggregate
    if not results or aggregate["fold_count"] != len(results):
        raise ValueError("Fold summary needs matching nonempty results and aggregate")
    width = max(len("Fold"), *(len(r["name"]) for r in results))
    row = "{:<" + str(width) + "}  {:>8}  {:>12}  {:>12}  {:>12}"
    lines = ["", "Final summary: {} completed training fold(s)".format(len(results)),
             row.format("Fold", "Examples", "Accuracy %", "Macro F1 %", "Weighted F1 %")]
    for result in results:
        metric = result["test_metrics"]
        lines.append(row.format(result["name"], metric["sample_count"],
            *("{:.2f}".format(100 * metric[key]) for key in ("accuracy", "macro_f1", "weighted_f1"))))
    from macro_tools.result_summary import format_overall_summary
    lines.append(format_overall_summary(aggregate))
    return "\n".join(lines)


def format_test_report(result):
    """Format a completed fold's saved test results without evaluating again.

    The selected checkpoint may come from an earlier epoch than the last one.
    Macro F1 weights each gesture equally; weighted F1 weights by test support.
    """
    metrics = result["test_metrics"]
    names = metrics["class_names"]
    confusion = metrics["confusion_matrix"]
    correct = sum(confusion[index][index] for index in range(len(names)))
    lines = [
        "",
        "Final test results: {}".format(result["name"]),
        "Checkpoint: {} | selected epoch {} | epochs completed {}".format(
            result["selected_checkpoint"], result["selected_epoch"], result["epochs_completed"]),
        "Test examples: {}".format(metrics["sample_count"]),
        "Test loss: {:.4f}".format(metrics["loss"]),
        "Test accuracy: {:.2%} ({}/{} correct)".format(
            metrics["accuracy"], correct, metrics["sample_count"]),
        "Test macro F1: {:.2%}".format(metrics["macro_f1"]),
        "Test weighted F1: {:.2%}".format(metrics["weighted_f1"]),
        "Training and evaluation time: {:.1f} s".format(result["elapsed_s"]),
        "",
        "Per-gesture test metrics (scores in %; support = test examples):",
    ]
    components = metrics.get("component_metrics")
    if components:
        lines[-1] = "Per gesture-object pair test metrics (scores in %; support = test examples):"
        lines.insert(2, "Task: gesture_object | test accuracy/F1 require the exact gesture-object pair")
        for key in ("gesture", "object"):
            scores = components[key]
            lines.insert(-2, "{} component: accuracy {:.2%}, macro F1 {:.2%}".format(
                key.capitalize(), scores["accuracy"], scores["macro_f1"]))
    class_title = "Gesture-object" if components else "Gesture"
    name_width = max(len(class_title), max(map(len, names)))
    row_format = "{:<" + str(name_width) + "}  {:>9}  {:>9}  {:>9}  {:>7}"
    lines.append(row_format.format(class_title, "Precision", "Recall", "F1", "Support"))
    for name in names:
        values = metrics["per_class"][name]
        lines.append(row_format.format(
            name, "{:.2f}".format(100 * values["precision"]),
            "{:.2f}".format(100 * values["recall"]),
            "{:.2f}".format(100 * values["f1"]), values["support"]))

    lines.extend(["", "Confusion matrix (counts): rows = true, columns = predicted.",
                  "Column indices match the class indices shown on the rows."])
    row_labels = ["{}: {}".format(index, name) for index, name in enumerate(names)]
    label_width = max(len("True / Pred"), max(map(len, row_labels)))
    cell_width = max(4, len(str(len(names) - 1)),
                     max(len(str(value)) for row in confusion for value in row))
    cell_format = "{:>" + str(cell_width) + "}"
    lines.append("{:<{}}  {}".format(
        "True / Pred", label_width,
        " ".join(cell_format.format(index) for index in range(len(names)))))
    for label, row in zip(row_labels, confusion):
        lines.append("{:<{}}  {}".format(
            label, label_width, " ".join(cell_format.format(value) for value in row)))
    return "\n".join(lines)
