# Evaluation

After training, open the [outputs folder](../outputs/) to find:

- `model_comparison.csv`
- `metrics.json`
- `dataset_profile.json`
- `test_predictions.csv`
- `model_comparison.png`
- `precision_recall_curves.png`
- `confusion_matrix.png`
- `prediction_distribution.png`

Run `python evaluation/evaluate.py` to print the held-out results in the terminal.

## Current real-data run

Random forest was selected by validation PR-AUC. On the 50,000-row held-out test sample it achieved
PR-AUC 0.3069, ROC-AUC 0.8529, precision 0.8297, and recall 0.2257.

### Confusion matrix

![PaySim confusion matrix](../outputs/confusion_matrix.png)

### Model comparison

![PaySim model comparison](../outputs/model_comparison.png)

### Precision-recall curves

![PaySim precision-recall curves](../outputs/precision_recall_curves.png)

### Prediction distribution

![PaySim prediction distribution](../outputs/prediction_distribution.png)
